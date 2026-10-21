/***************************************************************************************************
 * Copyright (c) 2026 Hygon Information Technology Co., Ltd. All rights reserved.
 * Copyright (c) 2023 - 2023 NVIDIA CORPORATION & AFFILIATES. All rights reserved.
 * Copyright (c) 2023 - 2024 NVIDIA CORPORATION & AFFILIATES. All rights reserved.
 * SPDX-License-Identifier: BSD-3-Clause
 *
 * Redistribution and use in source and binary forms, with or without
 * modification, are permitted provided that the following conditions are met:
 *
 * 1. Redistributions of source code must retain the above copyright notice, this
 * list of conditions and the following disclaimer.
 *
 * 2. Redistributions in binary form must reproduce the above copyright notice,
 * this list of conditions and the following disclaimer in the documentation
 * and/or other materials provided with the distribution.
 *
 * 3. Neither the name of the copyright holder nor the names of its
 * contributors may be used to endorse or promote products derived from
 * this software without specific prior written permission.
 *
 * THIS SOFTWARE IS PROVIDED BY THE COPYRIGHT HOLDERS AND CONTRIBUTORS "AS IS"
 * AND ANY EXPRESS OR IMPLIED WARRANTIES, INCLUDING, BUT NOT LIMITED TO, THE
 * IMPLIED WARRANTIES OF MERCHANTABILITY AND FITNESS FOR A PARTICULAR PURPOSE ARE
 * DISCLAIMED. IN NO EVENT SHALL THE COPYRIGHT HOLDER OR CONTRIBUTORS BE LIABLE
 * FOR ANY DIRECT, INDIRECT, INCIDENTAL, SPECIAL, EXEMPLARY, OR CONSEQUENTIAL
 * DAMAGES (INCLUDING, BUT NOT LIMITED TO, PROCUREMENT OF SUBSTITUTE GOODS OR
 * SERVICES; LOSS OF USE, DATA, OR PROFITS; OR BUSINESS INTERRUPTION) HOWEVER
 * CAUSED AND ON ANY THEORY OF LIABILITY, WHETHER IN CONTRACT, STRICT LIABILITY,
 * OR TORT (INCLUDING NEGLIGENCE OR OTHERWISE) ARISING IN ANY WAY OUT OF THE USE
 * OF THIS SOFTWARE, EVEN IF ADVISED OF THE POSSIBILITY OF SUCH DAMAGE.
 *
 **************************************************************************************************/
#pragma once

#include <hute/tensor.hpp>

// Preserve FlashMLA's register packing without changing HYTLASS's global traits.
namespace flash_mla::hytlass_ext {
using namespace hute;

struct GFX928_16x16x16_F32F16F16F32_NT : hute::GFX928_16x16x16_F32F16F16F32_NT {};

struct GFX928_16x16x16_F32BF16BF16F32_NT : hute::GFX928_16x16x16_F32BF16BF16F32_NT {};

struct GFX928_16x16x32_F32F16F16F32_NT : hute::GFX928_16x16x32_F32F16F16F32_NT {};

struct GFX928_16x16x64_F32F16uint8F32_NT
  {
    using DRegisters = float[4];
    using ARegisters = half_t[16];
    using BRegisters = uint8_t[16];
    using CRegisters = float[4];
  };

struct GFX928_16x16x64_F32BF16int8F32_NT
  {
    using DRegisters = float[4];
    using ARegisters = bfloat16_t[16];
    using BRegisters = uint8_t[16];
    using CRegisters = float[4];
  };

struct GFX928_16x16x64_F32F16F16F32_NT
  {
    using DRegisters = float[4];
    using ARegisters = half_t[16];
    using BRegisters = half_t[16];
    using CRegisters = float[4];
    // Register asm fma
    HUTE_HOST_DEVICE static void
    fma(float      & d0, float      & d1, float      & d2, float      & d3,
        half_t const& a0, half_t const& a1, half_t const& a2, half_t const& a3,
        half_t const& a4, half_t const& a5, half_t const& a6, half_t const& a7,
        half_t const& a8, half_t const& a9, half_t const& a10, half_t const& a11,
        half_t const& a12, half_t const& a13, half_t const& a14, half_t const& a15,
        half_t const& b0, half_t const& b1, half_t const& b2, half_t const& b3,
        half_t const& b4, half_t const& b5, half_t const& b6, half_t const& b7,
        half_t const& b8, half_t const& b9, half_t const& b10, half_t const& b11,
        half_t const& b12, half_t const& b13, half_t const& b14, half_t const& b15,
        float const& c0, float const& c1, float const& c2, float const& c3)
    {
      #if (defined(__gfx928__) || defined(__gfx936__)) && defined(__HIPCC__)
          v4f c;
          v4f d;
          c.x = c0;
          c.y = c1;
          c.z = c2;
          c.w = c3;

          __fp16x4_t A0, A1, A2, A3, B0, B1, B2, B3;
          A0.x = a0; A0.y = a1; A0.z = a2; A0.w = a3;
          A1.x = a4; A1.y = a5; A1.z = a6; A1.w = a7;

          A2.x = a8; A2.y = a9; A2.z = a10; A2.w = a11;
          A3.x = a12; A3.y = a13; A3.z = a14; A3.w = a15;

          B0.x = b0; B0.y = b1; B0.z = b2; B0.w = b3;
          B1.x = b4; B1.y = b5; B1.z = b6; B1.w = b7;
          B2.x = b8; B2.y = b9; B2.z = b10; B2.w = b11;
          B3.x = b12; B3.y = b13; B3.z = b14; B3.w = b15;

          #ifdef HG_ROCM
          // d = __builtin_amdgcn_mmac_f32_16x16x16_f16(A,B,c);
          #else
          d = hytlass::arch::detail::mmac_f32_16x16x16_f16(A0,B0,c);
          d = hytlass::arch::detail::mmac_f32_16x16x16_f16(A1,B1,d);
          d = hytlass::arch::detail::mmac_f32_16x16x16_f16(A2,B2,d);
          d = hytlass::arch::detail::mmac_f32_16x16x16_f16(A3,B3,d);
          #endif

          d0 = d.x;
          d1 = d.y;
          d2 = d.z;
          d3 = d.w;
      #elif (defined(__gfx938__)||defined(__gfx92a__))  && defined(__HIPCC__)
          v4f c;
          v4f d;
          c.x = c0;
          c.y = c1;
          c.z = c2;
          c.w = c3;

          __fp16x4_t A0, A1, A2, A3, B0, B1, B2, B3;
          A0.x = a0; A0.y = a1; A0.z = a2; A0.w = a3;
          A1.x = a4; A1.y = a5; A1.z = a6; A1.w = a7;

          A2.x = a8; A2.y = a9; A2.z = a10; A2.w = a11;
          A3.x = a12; A3.y = a13; A3.z = a14; A3.w = a15;

          B0.x = b0; B0.y = b1; B0.z = b2; B0.w = b3;
          B1.x = b4; B1.y = b5; B1.z = b6; B1.w = b7;
          B2.x = b8; B2.y = b9; B2.z = b10; B2.w = b11;
          B3.x = b12; B3.y = b13; B3.z = b14; B3.w = b15;

          #if defined(__gfx92a__)
          d = hytlass::arch::detail::mmac_f32_16x16x16_f16(A0,B0,c);
          d = hytlass::arch::detail::mmac_f32_16x16x16_f16(A1,B1,d);
          d = hytlass::arch::detail::mmac_f32_16x16x16_f16(A2,B2,d);
          d = hytlass::arch::detail::mmac_f32_16x16x16_f16(A3,B3,d);
          #else
          d = hytlass::arch::detail::mmac_f32_16x16x16_f16(A0,B0,c);
          d = hytlass::arch::detail::mmac_f32_16x16x16_f16(A1,B1,d);
          d = hytlass::arch::detail::mmac_f32_16x16x16_f16(A2,B2,d);
          d = hytlass::arch::detail::mmac_f32_16x16x16_f16(A3,B3,d);
          #endif


          d0 = d.x;
          d1 = d.y;
          d2 = d.z;
          d3 = d.w;




      #endif
    }

  };

struct GFX928_16x16x64_F32BF16BF16F32_NT
  {
    using DRegisters = float[4];
    using ARegisters = bfloat16_t[16];
    using BRegisters = bfloat16_t[16];
    using CRegisters = float[4];

    // Register asm fma
    HUTE_HOST_DEVICE static void
    fma(float      & d0, float      & d1, float      & d2, float      & d3,
        bfloat16_t const& a0, bfloat16_t const& a1, bfloat16_t const& a2, bfloat16_t const& a3,
        bfloat16_t const& a4, bfloat16_t const& a5, bfloat16_t const& a6, bfloat16_t const& a7,
        bfloat16_t const& a8, bfloat16_t const& a9, bfloat16_t const& a10, bfloat16_t const& a11,
        bfloat16_t const& a12, bfloat16_t const& a13, bfloat16_t const& a14, bfloat16_t const& a15,
        bfloat16_t const& b0, bfloat16_t const& b1, bfloat16_t const& b2, bfloat16_t const& b3,
        bfloat16_t const& b4, bfloat16_t const& b5, bfloat16_t const& b6, bfloat16_t const& b7,
        bfloat16_t const& b8, bfloat16_t const& b9, bfloat16_t const& b10, bfloat16_t const& b11,
        bfloat16_t const& b12, bfloat16_t const& b13, bfloat16_t const& b14, bfloat16_t const& b15,
        float const& c0, float const& c1, float const& c2, float const& c3)
    {
     #if (defined(__gfx928__) || defined(__gfx936__)) && defined(__HIPCC__)
          v4f c;
          v4f d;
          c.x = c0;
          c.y = c1;
          c.z = c2;
          c.w = c3;
          hytlass::Array<bfloat16_t,4> a_0, a_1, a_2, a_3;
          a_0[0] = a0;
          a_0[1] = a1;
          a_0[2] = a2;
          a_0[3] = a3;

          a_1[0] = a4;
          a_1[1] = a5;
          a_1[2] = a6;
          a_1[3] = a7;

          a_2[0] = a8;
          a_2[1] = a9;
          a_2[2] = a10;
          a_2[3] = a11;

          a_3[0] = a12;
          a_3[1] = a13;
          a_3[2] = a14;
          a_3[3] = a15;

          hytlass::Array<bfloat16_t,4> b_0, b_1, b_2, b_3;
          b_0[0] = b0;
          b_0[1] = b1;
          b_0[2] = b2;
          b_0[3] = b3;

          b_1[0] = b4;
          b_1[1] = b5;
          b_1[2] = b6;
          b_1[3] = b7;

          b_2[0] = b8;
          b_2[1] = b9;
          b_2[2] = b10;
          b_2[3] = b11;

          b_3[0] = b12;
          b_3[1] = b13;
          b_3[2] = b14;
          b_3[3] = b15;
          // asm volatile("v_mmac_f32_16x16x16_bf16 %0, %1, %2, %3\n\t"
          //                   : "+v"(d)
          //                   : "v"(a), "v"(b), "v"(c));
          __bf16x4_t A0, A1, A2, A3, B0, B1, B2, B3;
          A0 = *(reinterpret_cast<__bf16x4_t *>(&a_0));
          A1 = *(reinterpret_cast<__bf16x4_t *>(&a_1));
          A2 = *(reinterpret_cast<__bf16x4_t *>(&a_2));
          A3 = *(reinterpret_cast<__bf16x4_t *>(&a_3));

          B0 = *(reinterpret_cast<__bf16x4_t *>(&b_0));
          B1 = *(reinterpret_cast<__bf16x4_t *>(&b_1));
          B2 = *(reinterpret_cast<__bf16x4_t *>(&b_2));
          B3 = *(reinterpret_cast<__bf16x4_t *>(&b_3));

          #ifdef HG_ROCM
          // d = __builtin_amdgcn_mmac_f32_16x16x16_bf16(A, B, c);
          #else
          d = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A0, B0, c);
          d = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A1, B1, d);
          d = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A2, B2, d);
          d = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A3, B3, d);
          #endif

          d0 = d.x;
          d1 = d.y;
          d2 = d.z;
          d3 = d.w;
      #elif (defined(__gfx938__)||defined(__gfx92a__))  && defined(__HIPCC__)
           v4f c;
          v4f d;
          c.x = c0;
          c.y = c1;
          c.z = c2;
          c.w = c3;
          hytlass::Array<bfloat16_t,4> a_0, a_1, a_2, a_3;
          a_0[0] = a0;
          a_0[1] = a1;
          a_0[2] = a2;
          a_0[3] = a3;

          a_1[0] = a4;
          a_1[1] = a5;
          a_1[2] = a6;
          a_1[3] = a7;

          a_2[0] = a8;
          a_2[1] = a9;
          a_2[2] = a10;
          a_2[3] = a11;

          a_3[0] = a12;
          a_3[1] = a13;
          a_3[2] = a14;
          a_3[3] = a15;

          hytlass::Array<bfloat16_t,4> b_0, b_1, b_2, b_3;
          b_0[0] = b0;
          b_0[1] = b1;
          b_0[2] = b2;
          b_0[3] = b3;

          b_1[0] = b4;
          b_1[1] = b5;
          b_1[2] = b6;
          b_1[3] = b7;

          b_2[0] = b8;
          b_2[1] = b9;
          b_2[2] = b10;
          b_2[3] = b11;

          b_3[0] = b12;
          b_3[1] = b13;
          b_3[2] = b14;
          b_3[3] = b15;
          // asm volatile("v_mmac_f32_16x16x16_bf16 %0, %1, %2, %3\n\t"
          //                   : "+v"(d)
          //                   : "v"(a), "v"(b), "v"(c));
          __bf16x4_t A0, A1, A2, A3, B0, B1, B2, B3;
          A0 = *(reinterpret_cast<__bf16x4_t *>(&a_0));
          A1 = *(reinterpret_cast<__bf16x4_t *>(&a_1));
          A2 = *(reinterpret_cast<__bf16x4_t *>(&a_2));
          A3 = *(reinterpret_cast<__bf16x4_t *>(&a_3));

          B0 = *(reinterpret_cast<__bf16x4_t *>(&b_0));
          B1 = *(reinterpret_cast<__bf16x4_t *>(&b_1));
          B2 = *(reinterpret_cast<__bf16x4_t *>(&b_2));
          B3 = *(reinterpret_cast<__bf16x4_t *>(&b_3));

          #if defined(__gfx92a__)
          d = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A0, B0, c);
          d = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A1, B1, d);
          d = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A2, B2, d);
          d = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A3, B3, d);
          #else
          d = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A0, B0, c);
          d = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A1, B1, d);
          d = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A2, B2, d);
          d = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A3, B3, d);
          #endif


          d0 = d.x;
          d1 = d.y;
          d2 = d.z;
          d3 = d.w;






      #endif
    }
  };

struct GFX928_16x16x32_F32BF16BF16F32_NT : hute::GFX928_16x16x32_F32BF16BF16F32_NT {};

struct GFX928_16x32x16_F32F16F16F32_NT : hute::GFX928_16x32x16_F32F16F16F32_NT {};

struct GFX928_16x32x16_F32BF16BF16F32_NT : hute::GFX928_16x32x16_F32BF16BF16F32_NT {};

struct GFX928_16x64x16_FP8_F32F16F16F32_NT
  {
    using DRegisters = float[16];
    using ARegisters = half_t[4];
    using BRegisters = half_t[16];
    using CRegisters = float[16];

    // Register asm fma
    HUTE_HOST_DEVICE static void
    fma(float      & d0, float      & d1, float      & d2, float      & d3,
        float      & d4, float      & d5, float      & d6, float      & d7,
        float& d8, float& d9, float& d10, float& d11,
        float& d12, float& d13, float& d14, float& d15,
        half_t const& a0, half_t const& a1,half_t const& a2, half_t const& a3,
        half_t const& b0, half_t const& b1,half_t const& b2, half_t const& b3,
        half_t const& b4, half_t const& b5,half_t const& b6, half_t const& b7,
        half_t const& b8, half_t const& b9,half_t const& b10, half_t const& b11,
        half_t const& b12, half_t const& b13,half_t const& b14, half_t const& b15,
        float const& c0, float const& c1, float const& c2, float const& c3,
        float const& c4, float const& c5, float const& c6, float const& c7,
        float const& c8, float const& c9, float const& c10, float const& c11,
        float const& c12, float const& c13, float const& c14, float const& c15)
    {

     #if (defined(__gfx928__) || defined(__gfx936__)) && defined(__HIPCC__)
        v4f C0,C1, C2, C3;
        v4f D0,D1, D2, D3;

        C0.x = c0;  C0.y = c2;  C0.z = c4;  C0.w = c6;
        C1.x = c1;  C1.y = c3;  C1.z = c5;  C1.w = c7;

        C2.x = c8;  C2.y = c10;  C2.z = c12;  C2.w = c14;
        C3.x = c9;  C3.y = c11;  C3.z = c13;  C3.w = c15;

        __fp16x4_t A, B0, B1, B2, B3;
        A.x  = a0; A.y  = a1; A.z  = a2; A.w  = a3;
        B0.x = b0; B0.y = b2; B0.z = b4; B0.w = b6;
        B1.x = b1; B1.y = b3; B1.z = b5; B1.w = b7;
        B2.x = b8; B2.y = b10; B2.z = b12; B2.w = b14;
        B3.x = b9; B3.y = b11; B3.z = b13; B3.w = b15;

        D0 = hytlass::arch::detail::mmac_f32_16x16x16_f16(A, B0, C0);
        D1 = hytlass::arch::detail::mmac_f32_16x16x16_f16(A, B1, C1);
        D2 = hytlass::arch::detail::mmac_f32_16x16x16_f16(A, B2, C2);
        D3 = hytlass::arch::detail::mmac_f32_16x16x16_f16(A, B3, C3);

        d0 = D0.x; d1 = D1.x; d2 = D0.y; d3 = D1.y;
        d4 = D0.z; d5 = D1.z; d6 = D0.w; d7 = D1.w;

        d8 = D2.x; d9 = D3.x; d10 = D2.y; d11 = D3.y;

        d12 = D2.z; d13 = D3.z; d14 = D2.w; d15 = D3.w;

      #elif (defined(__gfx938__)||defined(__gfx92a__))  && defined(__HIPCC__)
        v4f C0,C1, C2, C3;
        v4f D0,D1, D2, D3;

        C0.x = c0;  C0.y = c2;  C0.z = c4;  C0.w = c6;
        C1.x = c1;  C1.y = c3;  C1.z = c5;  C1.w = c7;

        C2.x = c8;  C2.y = c10;  C2.z = c12;  C2.w = c14;
        C3.x = c9;  C3.y = c11;  C3.z = c13;  C3.w = c15;

        __fp16x4_t A, B0, B1, B2, B3;
        A.x  = a0; A.y  = a1; A.z  = a2; A.w  = a3;
        B0.x = b0; B0.y = b2; B0.z = b4; B0.w = b6;
        B1.x = b1; B1.y = b3; B1.z = b5; B1.w = b7;
        B2.x = b8; B2.y = b10; B2.z = b12; B2.w = b14;
        B3.x = b9; B3.y = b11; B3.z = b13; B3.w = b15;

        #if defined(__gfx92a__)
        D0 = hytlass::arch::detail::mmac_f32_16x16x16_f16(A, B0, C0);
        D1 = hytlass::arch::detail::mmac_f32_16x16x16_f16(A, B1, C1);
        D2 = hytlass::arch::detail::mmac_f32_16x16x16_f16(A, B2, C2);
        D3 = hytlass::arch::detail::mmac_f32_16x16x16_f16(A, B3, C3);
        #else
        D0 = hytlass::arch::detail::mmac_f32_16x16x16_f16(A, B0, C0);
        D1 = hytlass::arch::detail::mmac_f32_16x16x16_f16(A, B1, C1);
        D2 = hytlass::arch::detail::mmac_f32_16x16x16_f16(A, B2, C2);
        D3 = hytlass::arch::detail::mmac_f32_16x16x16_f16(A, B3, C3);
        #endif

        d0 = D0.x; d1 = D1.x; d2 = D0.y; d3 = D1.y;
        d4 = D0.z; d5 = D1.z; d6 = D0.w; d7 = D1.w;

        d8 = D2.x; d9 = D3.x; d10 = D2.y; d11 = D3.y;

        d12 = D2.z; d13 = D3.z; d14 = D2.w; d15 = D3.w;


      #endif
    }
  };

struct GFX928_16x64x16_FP8_F32BF16BF16F32_NT
  {
    using DRegisters = float[16];
    using ARegisters = bfloat16_t[4];
    using BRegisters = bfloat16_t[16];
    using CRegisters = float[16];

    // Register asm fma
    HUTE_HOST_DEVICE static void
    fma(float      & d0, float      & d1, float      & d2, float      & d3,
        float      & d4, float      & d5, float      & d6, float      & d7,
        float& d8, float& d9, float& d10, float& d11,
        float& d12, float& d13, float& d14, float& d15,
        bfloat16_t const& a0, bfloat16_t const& a1,bfloat16_t const& a2, bfloat16_t const& a3,
        bfloat16_t const& b0, bfloat16_t const& b1,bfloat16_t const& b2, bfloat16_t const& b3,
        bfloat16_t const& b4, bfloat16_t const& b5,bfloat16_t const& b6, bfloat16_t const& b7,
        bfloat16_t const& b8, bfloat16_t const& b9,bfloat16_t const& b10, bfloat16_t const& b11,
        bfloat16_t const& b12, bfloat16_t const& b13,bfloat16_t const& b14, bfloat16_t const& b15,
        float const& c0, float const& c1, float const& c2, float const& c3,
        float const& c4, float const& c5, float const& c6, float const& c7,
        float const& c8, float const& c9, float const& c10, float const& c11,
        float const& c12, float const& c13, float const& c14, float const& c15
      )
    {

      #if (defined(__gfx928__) || defined(__gfx936__)) && defined(__HIPCC__)
        v4f C0,C1, C2, C3;
        v4f D0,D1, D2, D3;

        C0.x = c0;  C0.y = c2;  C0.z = c4;  C0.w = c6;
        C1.x = c1;  C1.y = c3;  C1.z = c5;  C1.w = c7;

        C2.x = c8;  C2.y = c10;  C2.z = c12;  C2.w = c14;
        C3.x = c9;  C3.y = c11;  C3.z = c13;  C3.w = c15;

        hytlass::Array<bfloat16_t, 4> array_a0;
        hytlass::Array<bfloat16_t, 4> array_b0, array_b1, array_b2, array_b3;

        array_a0[0] = a0; array_a0[1] = a1; array_a0[2] = a2; array_a0[3] = a3;
        // array_a0[0] = 1.0; array_a0[1] = 1.0; array_a0[2] = 1.0; array_a0[3] = 1.0;

        array_b0[0] = b0; array_b0[1] = b2; array_b0[2] = b4; array_b0[3] = b6;
        array_b1[0] = b1; array_b1[1] = b3; array_b1[2] = b5; array_b1[3] = b7;

        array_b2[0] = b8; array_b2[1] = b10; array_b2[2] = b12; array_b2[3] = b14;
        array_b3[0] = b9; array_b3[1] = b11; array_b3[2] = b13; array_b3[3] = b15;

        __bf16x4_t A, B0, B1, B2, B3;
        A = *reinterpret_cast<__bf16x4_t*>(&array_a0);
        B0 = *reinterpret_cast<__bf16x4_t*>(&array_b0);
        B1 = *reinterpret_cast<__bf16x4_t*>(&array_b1);
        B2 = *reinterpret_cast<__bf16x4_t*>(&array_b2);
        B3 = *reinterpret_cast<__bf16x4_t*>(&array_b3);

        #ifdef HG_ROCM
        // D0 = __builtin_amdgcn_mmac_f32_16x16x16_bf16(A, B0, C0);
        // D1 = __builtin_amdgcn_mmac_f32_16x16x16_bf16(A, B1, C1);
        #else
        D0 = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A, B0, C0);
        D1 = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A, B1, C1);
        D2 = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A, B2, C2);
        D3 = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A, B3, C3);
        #endif

        d0 = D0.x; d1 = D1.x; d2 = D0.y; d3 = D1.y;
        d4 = D0.z; d5 = D1.z; d6 = D0.w; d7 = D1.w;

        d8 = D2.x; d9 = D3.x; d10 = D2.y; d11 = D3.y;

        d12 = D2.z; d13 = D3.z; d14 = D2.w; d15 = D3.w;

      #elif (defined(__gfx938__)||defined(__gfx92a__))  && defined(__HIPCC__)

        v4f C0,C1, C2, C3;
        v4f D0,D1, D2, D3;

        C0.x = c0;  C0.y = c2;  C0.z = c4;  C0.w = c6;
        C1.x = c1;  C1.y = c3;  C1.z = c5;  C1.w = c7;

        C2.x = c8;  C2.y = c10;  C2.z = c12;  C2.w = c14;
        C3.x = c9;  C3.y = c11;  C3.z = c13;  C3.w = c15;

        hytlass::Array<bfloat16_t, 4> array_a0;
        hytlass::Array<bfloat16_t, 4> array_b0, array_b1, array_b2, array_b3;

        array_a0[0] = a0; array_a0[1] = a1; array_a0[2] = a2; array_a0[3] = a3;
        // array_a0[0] = 1.0; array_a0[1] = 1.0; array_a0[2] = 1.0; array_a0[3] = 1.0;

        array_b0[0] = b0; array_b0[1] = b2; array_b0[2] = b4; array_b0[3] = b6;
        array_b1[0] = b1; array_b1[1] = b3; array_b1[2] = b5; array_b1[3] = b7;

        array_b2[0] = b8; array_b2[1] = b10; array_b2[2] = b12; array_b2[3] = b14;
        array_b3[0] = b9; array_b3[1] = b11; array_b3[2] = b13; array_b3[3] = b15;

        __bf16x4_t A, B0, B1, B2, B3;
        A = *reinterpret_cast<__bf16x4_t*>(&array_a0);
        B0 = *reinterpret_cast<__bf16x4_t*>(&array_b0);
        B1 = *reinterpret_cast<__bf16x4_t*>(&array_b1);
        B2 = *reinterpret_cast<__bf16x4_t*>(&array_b2);
        B3 = *reinterpret_cast<__bf16x4_t*>(&array_b3);

        #if defined(__gfx92a__)
        D0 = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A, B0, C0);
        D1 = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A, B1, C1);
        D2 = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A, B2, C2);
        D3 = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A, B3, C3);
        #else
        D0 = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A, B0, C0);
        D1 = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A, B1, C1);
        D2 = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A, B2, C2);
        D3 = hytlass::arch::detail::mmac_f32_16x16x16_bf16(A, B3, C3);
        #endif


        d0 = D0.x; d1 = D1.x; d2 = D0.y; d3 = D1.y;
        d4 = D0.z; d5 = D1.z; d6 = D0.w; d7 = D1.w;

        d8 = D2.x; d9 = D3.x; d10 = D2.y; d11 = D3.y;

        d12 = D2.z; d13 = D3.z; d14 = D2.w; d15 = D3.w;

      #endif

    }
  };

struct GFX928_16x16x32_F32F16F16F32_NN : GFX928_16x16x32_F32F16F16F32_NT {};

struct GFX928_16x16x32_F32BF16BF16F32_NN : GFX928_16x16x32_F32BF16BF16F32_NT {};

struct GFX938_16x64x16_F32F8F8F32E4M3E4M3_NT
  {
    using DRegisters = float[16];
    using ARegisters = float_e4m3_t[4];
    using BRegisters = float_e4m3_t[16];
    using CRegisters = float[16];
  };

struct GFX938_16x16x64_F32F8F8F32E4M3E4M3_NT_LIT
  {
    using DRegisters = float[4];
    using ARegisters = float_e4m3_t[16];
    using BRegisters = float_e4m3_t[16];
    using CRegisters = float[4];

    // Register asm fma
    HUTE_HOST_DEVICE static void
    fma(float      & d0, float      & d1, float      & d2, float      & d3,
        float_e4m3_t const& a0, float_e4m3_t const& a1,float_e4m3_t const& a2, float_e4m3_t const& a3,
        float_e4m3_t const& a4, float_e4m3_t const& a5,float_e4m3_t const& a6, float_e4m3_t const& a7,
        float_e4m3_t const& a8, float_e4m3_t const& a9,float_e4m3_t const& a10, float_e4m3_t const& a11,
        float_e4m3_t const& a12, float_e4m3_t const& a13,float_e4m3_t const& a14, float_e4m3_t const& a15,
        float_e4m3_t const& b0, float_e4m3_t const& b1,float_e4m3_t const& b2, float_e4m3_t const& b3,
        float_e4m3_t const& b4, float_e4m3_t const& b5,float_e4m3_t const& b6, float_e4m3_t const& b7,
        float_e4m3_t const& b8, float_e4m3_t const& b9,float_e4m3_t const& b10, float_e4m3_t const& b11,
        float_e4m3_t const& b12, float_e4m3_t const& b13,float_e4m3_t const& b14, float_e4m3_t const& b15,
        float const& c0, float const& c1, float const& c2, float const& c3)
    {
      #if (defined(__gfx938__))  && defined(__HIPCC__)
        v4f c;
        v4f d;
        c.x = c0;
        c.y = c1;
        c.z = c2;
        c.w = c3;
        hytlass::Array<float_e4m3_t,8> a_0;
        a_0[0] = a0; a_0[1] = a1; a_0[2] = a2; a_0[3] = a3;
        a_0[4] = a4; a_0[5] = a5; a_0[6] = a6; a_0[7] = a7;

        hytlass::Array<float_e4m3_t,8> a_1;
        a_1[0] = a8; a_1[1] = a9; a_1[2] = a10; a_1[3] = a11;
        a_1[4] = a12; a_1[5] = a13; a_1[6] = a14; a_1[7] = a15;

        hytlass::Array<float_e4m3_t,8> b_0;
        b_0[0] = b0;b_0[1] = b1;b_0[2] = b2;b_0[3] = b3;
        b_0[4] = b4;b_0[5] = b5;b_0[6] = b6;b_0[7] = b7;

        hytlass::Array<float_e4m3_t,8> b_1;
        b_1[0] = b8;b_1[1] = b9;b_1[2] = b10;b_1[3] = b11;
        b_1[4] = b12;b_1[5] = b13;b_1[6] = b14;b_1[7] = b15;

        intx2_t A, B,A1,B1;
        A = *(reinterpret_cast<intx2_t *>(&a_0));
        B = *(reinterpret_cast<intx2_t *>(&b_0));
        A1 = *(reinterpret_cast<intx2_t *>(&a_1));
        B1 = *(reinterpret_cast<intx2_t *>(&b_1));

        // #ifndef HG_ROCM
        d = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A, B, c, true, false);
        d = __builtin_hcu_mmac_f32_16x16x32_fp8_fp8_lit_lts(A1, B1, d, true, false);
        // if(thread0()) {
        //   printf("A0: %f %f %f %f %f %f %f %f\n"
        //     "A1: %f %f %f %f %f %f %f %f\n"
        //     "B0: %f %f %f %f %f %f %f %f \n"
        //     "B1: %f %f %f %f %f %f %f %f \n"
        //     "C0: %f %f %f %f \n"
        //     "D1: %f %f %f %f \n",
        //     float(a0), float(a1), float(a2), float(a3),
        //     float(a4), float(a5), float(a6), float(a7),
        //     float(a8), float(a9), float(a10), float(a11),
        //     float(a12), float(a13), float(a14), float(a15),
        //     float(b0), float(b1), float(b2), float(b3),
        //     float(b4), float(b5), float(b6), float(b7),
        //     float(b8), float(b9), float(b10), float(b11),
        //     float(b12), float(b13), float(b14), float(b15),
        //     c.x, c.y, c.z, c.w, d.x, d.y, d.z, d.w
        //   );
        // }
        // #endif
        d0 = d.x;
        d1 = d.y;
        d2 = d.z;
        d3 = d.w;
      #elif defined(__gfx92a__) && defined(__HIPCC__)
        HUTE_INVALID_CONTROL_PATH("GFX938 LIT MMAC requires gfx938");
      #endif
    }

  };

struct GFX938_16x32x32_F32F8F8F32E4M3E4M3_NT_LIT : hute::GFX938_16x32x32_F32F8F8F32E4M3E4M3_NT_LIT {};

struct GFX938_16x16x64_F32F8F8F32E4M3E4M3_NN_LIT : GFX938_16x16x64_F32F8F8F32E4M3E4M3_NT_LIT {};

struct GFX928_DS_READ_DS_M32x16_B16
{
  //源共享内存数据是两个64位共享内存
  using SRegisters = uint64_t[2];
  using DRegisters = uint16_t[8];

  HUTE_HOST_DEVICE static void
  copy(uint64_t & smem_src1,
       uint64_t const& smem_src2,
       uint16_t& dst0, uint16_t& dst1, uint16_t& dst2, uint16_t& dst3,
       uint16_t& dst4, uint16_t& dst5, uint16_t& dst6, uint16_t& dst7)
  {

    #if (defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)||defined(__gfx92a__)) && defined(__HIPCC__)
      #if 0
      uint32x4_t d;
      int lds_offset = reinterpret_cast<const char *>(&smem_src1) - (char *)(0x1000000000000);
      if (thread0() || thread(64, 0)) {
        printf("lds_offset:%d\n", lds_offset);
      }
      // __builtin_amdgcn_ds_read_m32x16f16_alt(lds,offset)
      asm volatile("DS_READ_M32x16_B16 %0, %1, offset:0x00 \n\t"
                    "s_waitcnt lgkmcnt(0) \n\t"
                    : "+v"(d)
                    : "v"(lds_offset));

      uint16_t * dst = reinterpret_cast<uint16_t *>(&d);
      #else
      __fp16 * lds = reinterpret_cast<__fp16 *>(&smem_src1);
      const short offset = 0;
      #ifdef HG_ROCM
      auto d = __builtin_hygon_ds_read_m32x16_f16(lds);
      #else
      auto d = __builtin_hcu_ds_read_m32x16f16(lds, offset);
      #endif
      uint16_t * dst = reinterpret_cast<uint16_t*>(&d);
      #endif
      dst0 = dst[0];
      dst1 = dst[1];
      dst2 = dst[2];
      dst3 = dst[3];
      dst4 = dst[4];
      dst5 = dst[5];
      dst6 = dst[6];
      dst7 = dst[7];

    #endif

  }

};

struct GFX928_DS_READ_DS_M32x32_B8
{
  using SRegisters = uint128_t[1];
  using DRegisters = uint128_t[1];

  HUTE_HOST_DEVICE static void
  copy(uint128_t const& smem_src,
       uint128_t& dst)
  {
    #if (defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)||defined(__gfx92a__)) && defined(__HIPCC__)
      v4i d;
      d = __builtin_hcu_ds_read_m32x32u8( (int*)(&smem_src), short(0));
      uint128_t* d_ptr = reinterpret_cast<uint128_t *>(&d);

      dst= *d_ptr;

    #endif
  }
};

struct GFX928_DS_READ_DS_M64x16_B8
{
  using SRegisters = uint128_t[1];
  using DRegisters = uint8_t[16];

  HUTE_HOST_DEVICE static void
  copy(uint128_t const& smem_src,
       uint8_t& dst00, uint8_t& dst01, uint8_t& dst02, uint8_t& dst03,
       uint8_t& dst04, uint8_t& dst05, uint8_t& dst06, uint8_t& dst07,
       uint8_t& dst08, uint8_t& dst09, uint8_t& dst10, uint8_t& dst11,
       uint8_t& dst12, uint8_t& dst13, uint8_t& dst14, uint8_t& dst15)
  {
    // #if (defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)) && defined(__HIPCC__)
    // v4i d;
    // int lds_offset = reinterpret_cast<const char *>(&smem_src) - (char *)(0x1000000000000);
    // asm volatile("DS_READ_M32x32_B8 %0, %1, offset:0x00 \n\t"
    //               "s_waitcnt lgkmcnt(0) \n\t"
    //               : "+v"(d)
    //               : "v"(lds_offset));
    // uint8_t * dst = reinterpret_cast<uint8_t *>(&d);
    // dst00 = dst[0];
    // dst01 = dst[1];
    // dst02 = dst[2];
    // dst03 = dst[3];
    // dst04 = dst[4];
    // dst05 = dst[5];
    // dst06 = dst[6];
    // dst07 = dst[7];
    // dst08 = dst[8];
    // dst09 = dst[9];
    // dst10 = dst[10];
    // dst11 = dst[11];
    // dst12 = dst[12];
    // dst13 = dst[13];
    // dst14 = dst[14];
    // dst15 = dst[15];
    // #endif
  }
};

} // namespace flash_mla::hytlass_ext

namespace hute {

template <>
struct MMA_Traits<flash_mla::hytlass_ext::GFX928_16x16x16_F32F16F16F32_NT>
{
  using ValTypeD = float;
  using ValTypeA = half_t;
  using ValTypeB = half_t;
  using ValTypeC = float;


  using Shape_MNK = Shape<_16,_16,_16>;
  using ThrID   = Layout<_64>;
  using ALayout = Layout<Shape<Shape<_16, _4>,_4>,
                          Stride<Stride<_1,_64>,_16>>;

  using BLayout = Layout<Shape <Shape <_16, _4>,_4>,
                         Stride<Stride< _1,_64>,_16>>;
  using CLayout = Layout<Shape <Shape <_16, _4>, _4>,
                         Stride<Stride< _1,_16>,_64>>;
};

template <>
struct MMA_Traits<flash_mla::hytlass_ext::GFX928_16x16x16_F32BF16BF16F32_NT>
      : MMA_Traits<flash_mla::hytlass_ext::GFX928_16x16x16_F32F16F16F32_NT>
{
  using ValTypeD = float;
  using ValTypeA = bfloat16_t;
  using ValTypeB = bfloat16_t;
  using ValTypeC = float;
};

template <>
 struct MMA_Traits<flash_mla::hytlass_ext::GFX928_16x16x32_F32F16F16F32_NT>
 {
   using ValTypeD = float;
   using ValTypeA = half_t;
   using ValTypeB = half_t;
   using ValTypeC = float;


   using Shape_MNK = Shape<_16,_16,_32>;
   using ThrID   = Layout<_64>;
   using ALayout = Layout<Shape<Shape<_16, _4>,_8>,
                           Stride<Stride<_1,_128>,_16>>;

   using BLayout = Layout<Shape <Shape <_16, _4>,_8>,
                          Stride<Stride< _1,_128>,_16>>;
   using CLayout = Layout<Shape <Shape <_16, _4>, _4>,
                          Stride<Stride< _1,_16>,_64>>;
 };

template <>
 struct MMA_Traits<flash_mla::hytlass_ext::GFX928_16x16x32_F32BF16BF16F32_NT>
       : MMA_Traits<flash_mla::hytlass_ext::GFX928_16x16x32_F32F16F16F32_NT>
 {
   using ValTypeD = float;
   using ValTypeA = bfloat16_t;
   using ValTypeB = bfloat16_t;
   using ValTypeC = float;
 };

template <>
 struct MMA_Traits<flash_mla::hytlass_ext::GFX928_16x16x32_F32F16F16F32_NN>
  : MMA_Traits<flash_mla::hytlass_ext::GFX928_16x16x32_F32F16F16F32_NT>
 {
  using ALayout = Layout<Shape<Shape<_4, _16>,_8>,
                            Stride<Stride<_128,_1>,_16>>;
 };

template <>
 struct MMA_Traits<flash_mla::hytlass_ext::GFX928_16x16x32_F32BF16BF16F32_NN>
  :  MMA_Traits<flash_mla::hytlass_ext::GFX928_16x16x32_F32BF16BF16F32_NT>
 {
  using ALayout = Layout<Shape<Shape<_4, _16>,_8>,
                            Stride<Stride<_128,_1>,_16>>;
 };

template <>
 struct MMA_Traits<flash_mla::hytlass_ext::GFX928_16x16x64_F32F16F16F32_NT>
 {
   using ValTypeD = float;
   using ValTypeA = half_t;
   using ValTypeB = half_t;
   using ValTypeC = float;


   using Shape_MNK = Shape<_16,_16,_64>;
   using ThrID   = Layout<_64>;
   using ALayout = Layout<Shape<Shape<_16, _4>,_16>,
                           Stride<Stride<_1,_256>,_16>>;

   using BLayout = Layout<Shape <Shape <_16, _4>,_16>,
                          Stride<Stride< _1,_256>,_16>>;
   using CLayout = Layout<Shape <Shape <_16, _4>, _4>,
                          Stride<Stride< _1,_16>,_64>>;
 };

template <>
 struct MMA_Traits<flash_mla::hytlass_ext::GFX928_16x16x64_F32BF16BF16F32_NT>
       : MMA_Traits<flash_mla::hytlass_ext::GFX928_16x16x64_F32F16F16F32_NT>
 {
   using ValTypeD = float;
   using ValTypeA = bfloat16_t;
   using ValTypeB = bfloat16_t;
   using ValTypeC = float;
 };

template <>
 struct MMA_Traits<flash_mla::hytlass_ext::GFX928_16x16x64_F32F16uint8F32_NT>
 {
   using ValTypeD = float;
   using ValTypeA = half_t;
   using ValTypeB = uint8_t;
   using ValTypeC = float;


   using Shape_MNK = Shape<_16,_16,_64>;
   using ThrID   = Layout<_64>;
   using ALayout = Layout<Shape<Shape<_16, _4>,_16>,
                           Stride<Stride<_1,_256>,_16>>;

   using BLayout = Layout<Shape <Shape <_16, _4>,_16>,
                          Stride<Stride< _1,_256>,_16>>;
   using CLayout = Layout<Shape <Shape <_16, _4>, _4>,
                          Stride<Stride< _1,_16>,_64>>;
 };

template <>
 struct MMA_Traits<flash_mla::hytlass_ext::GFX928_16x16x64_F32BF16int8F32_NT>
       : MMA_Traits<flash_mla::hytlass_ext::GFX928_16x16x64_F32F16uint8F32_NT>
 {
   using ValTypeD = float;
   using ValTypeA = bfloat16_t;
   using ValTypeB = uint8_t;
   using ValTypeC = float;
 };

template <>
struct MMA_Traits<flash_mla::hytlass_ext::GFX928_16x32x16_F32F16F16F32_NT>
{
  using ValTypeD = float;
  using ValTypeA = half_t;
  using ValTypeB = half_t;
  using ValTypeC = float;


  using Shape_MNK = Shape<_16, _32, _16>;
  using ThrID = Layout<_64>;
  using ALayout = Layout<Shape<Shape<_16, _4>, _4>,
                          Stride<Stride<_1, _64>, _16>>;
  using BLayout = Layout<Shape<Shape<_16, _4>, Shape<_2, _4>>,
                          Stride<Stride<_1, _128>, Stride<_16, _32>>>;

  using CLayout = Layout<Shape<Shape<_16, _4>, Shape<_8>>,
                         Stride<Stride<_1, _16>, Stride<_64>>>;

};

template <>
struct MMA_Traits<flash_mla::hytlass_ext::GFX928_16x32x16_F32BF16BF16F32_NT>
      : MMA_Traits<flash_mla::hytlass_ext::GFX928_16x32x16_F32F16F16F32_NT>
{
  using ValTypeD = float;
  using ValTypeA = bfloat16_t;
  using ValTypeB = bfloat16_t;
  using ValTypeC = float;
};

template <>
struct MMA_Traits<flash_mla::hytlass_ext::GFX928_16x64x16_FP8_F32F16F16F32_NT>
{
  using ValTypeD = float;
  using ValTypeA = half_t;
  using ValTypeB = half_t;
  using ValTypeC = float;


  using Shape_MNK = Shape<_16, _64, _16>;
  using ThrID = Layout<_64>;
  using ALayout = Layout<Shape<Shape<_16, _4>, _4>,
                          Stride<Stride<_1, _64>, _16>>;
  using BLayout = Layout<Shape<Shape<_16, _4>, Shape<Shape<_2, _2>, _4>>,
                          Stride<Stride<_1, _128>, Stride<Stride<_1, _32>, _64>>>;

  using CLayout = Layout<Shape<Shape<_16, _4>, Shape<_2, _8>>,
                         Stride<Stride<_1, _16>, Stride<_16, _128>>>;

};

template <>
struct MMA_Traits<flash_mla::hytlass_ext::GFX928_16x64x16_FP8_F32BF16BF16F32_NT>
      : MMA_Traits<flash_mla::hytlass_ext::GFX928_16x64x16_FP8_F32F16F16F32_NT>
{
  using ValTypeD = float;
  using ValTypeA = bfloat16_t;
  using ValTypeB = bfloat16_t;
  using ValTypeC = float;
};

template <>
struct MMA_Traits<flash_mla::hytlass_ext::GFX938_16x16x64_F32F8F8F32E4M3E4M3_NT_LIT>
{
  using ValTypeD = float;
  using ValTypeA = float_e4m3_t;
  using ValTypeB = float_e4m3_t;
  using ValTypeC = float;
  using Shape_MNK = Shape<_16,_16,_64>;
  using ThrID   = Layout<_64>;

  using ALayout = Layout<Shape<Shape<_16, _4>,_16>, //_1表示to到t1  _64表示to到t16 _16表示t0内部之间
                          Stride<Stride<_1,_256>,_16>>; //Stride<Stride<_1,_128>,_16>>;
  using BLayout = Layout<Shape <Shape <_16, _4>,_16>,
                         Stride<Stride<_1,_256>,_16>>; //Stride<Stride< _1,_128>,_16>>;

  using CLayout = Layout<Shape <Shape <_16, _4>, _4>,
                         Stride<Stride< _1, _64>, _16>>;
};

template <>
 struct MMA_Traits<flash_mla::hytlass_ext::GFX938_16x16x64_F32F8F8F32E4M3E4M3_NN_LIT>
  : MMA_Traits<flash_mla::hytlass_ext::GFX938_16x16x64_F32F8F8F32E4M3E4M3_NT_LIT>
 {
  using ALayout = Layout<Shape<Shape<_4, _16>,_16>,
                            Stride<Stride<_256,_1>,_16>>;
 };

template <>
struct MMA_Traits<flash_mla::hytlass_ext::GFX938_16x32x32_F32F8F8F32E4M3E4M3_NT_LIT> {
  using ValTypeD = float;
  using ValTypeA = float_e4m3_t;
  using ValTypeB = float_e4m3_t;
  using ValTypeC = float;

  using Shape_MNK = Shape<_16, _32, _32>;
  using ThrID = Layout<_64>;

  using ALayout = Layout<Shape<Shape<_16, _4>, _8>,   // (16 * 4) *8  16*4个线程 每个拷8个
                         Stride<Stride<_1, _128>, _16>>;
  using BLayout = Layout<Shape<Shape<_16, _4>, Shape<_2, _8>>,
                         Stride<Stride<_1, _256>, Stride<_16, _32>>>;//_1表示to到t1  _256表示to到t16 _16表示t0内部之间
  using CLayout = Layout<Shape<Shape<_16, _4>, Shape<_4,_2>>,
                         Stride<Stride<_1, _64>, Stride<_16,_256>>>;
};

template <>
struct MMA_Traits<flash_mla::hytlass_ext::GFX938_16x64x16_F32F8F8F32E4M3E4M3_NT> {
  using ValTypeD = float;
  using ValTypeA = float_e4m3_t;
  using ValTypeB = float_e4m3_t;
  using ValTypeC = float;

  using Shape_MNK = Shape<_16, _64, _16>;
  using ThrID = Layout<_64>;

  using ALayout = Layout<Shape<Shape<_16, _4>, _4>,   // (16 * 4) *8  16*4个线程 每个拷8个
                         Stride<Stride<_1, _64>, _16>>;
  using BLayout = Layout<Shape<Shape<_16, _4>, Shape<_4, _4>>,
                         Stride<Stride<_1, _256>, Stride<_16, _64>>>;//_1表示to到t1  _256表示to到t16 _16表示t0内部之间
  using CLayout = Layout<Shape<Shape<_16, _4>, Shape<_16>>,
                         Stride<Stride<_1, _16>, Stride<_64>>>;
};

template <>
struct Copy_Traits<flash_mla::hytlass_ext::GFX928_DS_READ_DS_M32x16_B16>
{
  // Logical thread id to thread idx (warp)

  using ThrID = Layout<_64>;

  // Map from (src-thr,src-val) to bit
  using SrcLayout = Layout<Shape< Shape<_4,_16>,_128>,
                           Stride< Stride<_128,_512>,_1>>;
  // using SrcLayout = Layout<Shape<Shape <_4,_16>,Shape<Shape<_64,_2>,_1>>,
  //                          Stride<Stride<_64,_512>,Stride<Stride<_1,_256>,_0>>>;
  // Map from (dst-thr,dst-val) to bit
  using DstLayout =  Layout<Shape <Shape <_16, _4>,Shape<_16,_2,_4>>,
                              Stride<Stride<_16,_2048>,Stride<_1,_256,_512>>>;


  // Reference map from (thr,val) to bit
  using RefLayout = DstLayout;

  // bool using_lds_offset = true;
};

template <>
struct Copy_Traits<flash_mla::hytlass_ext::GFX928_DS_READ_DS_M32x32_B8>
{
  // Logical thread id to thread idx (warp)

  using ThrID = Layout<_64>;

  // Map from (src-thr,src-val) to bit
  using SrcLayout = Layout<Shape<Shape<_2, _32>, _128>,
                           Stride<Stride<_128, _256>, _1>>;
  // Map from (dst-thr,dst-val) to bit
  using DstLayout = Layout<Shape<Shape<_16, _4>, Shape<_8, _2, _8>>,
                           Stride<Stride<_8, _2048>, Stride<_1, _128, _256>>>;

  // Reference map from (thr,val) to bit
  using RefLayout = DstLayout;
};

template <>
struct Copy_Traits<flash_mla::hytlass_ext::GFX928_DS_READ_DS_M64x16_B8>
{
  // Logical thread id to thread idx (warp)

  using ThrID = Layout<_64>;

  // Map from (src-thr,src-val) to bit
  using SrcLayout = Layout<Shape<Shape<_4, _16>, _128>,
                           Stride<Stride<_128, _512>, _1>>;
  // // Map from (dst-thr,dst-val) to bit
  using DstLayout = Layout<Shape<Shape<_16, _4>, Shape<_8, _2, _8>>,
                           Stride<Stride<_8, _2048>, Stride<_1, _128, _256>>>;

  // Reference map from (thr,val) to bit
  using RefLayout = DstLayout;
};

} // namespace hute
