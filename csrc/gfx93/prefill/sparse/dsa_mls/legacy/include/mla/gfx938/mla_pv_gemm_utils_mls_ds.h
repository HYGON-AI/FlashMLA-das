// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
// SPDX-License-Identifier: MIT

#pragma once // prepare for prefetch V in qk gemm
#include "intrinsic_mls_ds.h"



template<int kHeadDim, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, typename Element, bool Is_even_MN>
__forceinline__ __device__ void prefetch_v_to_lds_mls_ds_576_512(
        vec4_uint v_ptr,
        Element* v_lds,
        int warp_id,
        int seqlen_v_stride,
        int max_seq_kv_offset=0) {

    constexpr int ELEMENT_BYTES = sizeof(Element);
    constexpr int WARP_NUM = kBlockM * kBlockN / (WARP_M * WARP_N);
    constexpr int WARP_K   = 32;
    constexpr int kHeadDim_OPT = 256;   // 32x32 x WARP_NUM x 2B x stage == 32K

    // MLS
    int n_load = 0;
    vec4_uint v_srsrc;
    *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_load * WARP_NUM * 32 + warp_id * 32) * ELEMENT_BYTES);
    v_srsrc[2] = seqlen_v_stride;
    if constexpr (true) {
        int nm_filter = inline_min_max<0, 32>(0 * WARP_K + 32 - max_seq_kv_offset);
        v_srsrc[3] = max_seq_kv_offset % kBlockK == 0 ? 0: nm_filter << 8;
    }
    int lds_stage_id = 0;
    int lds_offset = (lds_stage_id * WARP_K * kHeadDim_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;

    flash::wait_all_warp_arrived(); // 防止写 v lds 和读 q lds k lds 冲突, qk 可能有的 warp 没结束
    inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);
    __builtin_amdgcn_sched_barrier(0);
}

template<int kHeadDim, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, typename Element, bool Is_even_MN>
__forceinline__ __device__ void prefetch_v_to_lds_mls_ds_576_512_buffer_load(
        vec4_uint v_ptr,
        Element* v_lds,
        int warp_id,
        int seqlen_v_stride,
        int* index_ptr,
        int* block_table,
        int batch_stride,
        int n_loop,
        int max_seq_kv_offset=0) {

    constexpr int ELEMENT_BYTES = sizeof(Element);
    constexpr int WARP_NUM = kBlockM * kBlockN / (WARP_M * WARP_N);
    constexpr int WARP_K   = 32;
    constexpr int kHeadDim_OPT = 256;   // 32x32 x WARP_NUM x 2B x stage == 32K

    // MLS
    // int n_load = 0;
    // vec4_uint v_srsrc;
    // *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_load * WARP_NUM * 32 + warp_id * 32) * ELEMENT_BYTES);
    // v_srsrc[2] = seqlen_v_stride;
    // if constexpr (true) {
    //     int nm_filter = inline_min_max<0, 32>(0 * WARP_K + 32 - max_seq_kv_offset);
    //     v_srsrc[3] = max_seq_kv_offset % kBlockK == 0 ? 0: nm_filter << 8;
    // }
    // int lds_stage_id = 0;
    // int lds_offset = (lds_stage_id * WARP_K * kHeadDim_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;

    // flash::wait_all_warp_arrived(); // 防止写 v lds 和读 q lds k lds 冲突, qk 可能有的 warp 没结束
    // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);
    int tid = threadIdx.x % 64;

    int index_topk_1 = index_ptr[n_loop * 64 + (tid / 4)];
    int index_topk_2 = index_ptr[n_loop * 64 + (tid / 4) + 16];
    int lds_offset = __builtin_amdgcn_readfirstlane((warp_id * 32 * 32) * ELEMENT_BYTES / 4);
    int g_offset_v = warp_id * 16 + tid % 4 * 4 + block_table[index_topk_1/128] * batch_stride * ELEMENT_BYTES / 4 + (index_topk_1 % 128) * seqlen_v_stride * ELEMENT_BYTES / 4;
    int lds_offset_add = __builtin_amdgcn_readfirstlane((32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
    int g_offset_v_add = warp_id * 16 + tid % 4 * 4 + block_table[index_topk_2/128] * batch_stride * ELEMENT_BYTES / 4 + (index_topk_2 % 128) * seqlen_v_stride * ELEMENT_BYTES / 4;
    flash::wait_all_warp_arrived();
    inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
    inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
    __builtin_amdgcn_sched_barrier(0);
}

template<int kHeadDim, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, typename Element, bool Is_even_MN>
__forceinline__ __device__ void prefetch_v_to_lds_mls_ds_576_512_buffer_load_nopage(
        vec4_uint v_ptr,
        Element* v_lds,
        int warp_id,
        int seqlen_v_stride,
        int* index_ptr,
        int batch_stride,
        int n_loop,
        int max_seq_kv_offset=0) {

    constexpr int ELEMENT_BYTES = sizeof(Element);
    constexpr int WARP_NUM = kBlockM * kBlockN / (WARP_M * WARP_N);
    constexpr int WARP_K   = 32;
    constexpr int kHeadDim_OPT = 256;   // 32x32 x WARP_NUM x 2B x stage == 32K

    // MLS
    // int n_load = 0;
    // vec4_uint v_srsrc;
    // *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_load * WARP_NUM * 32 + warp_id * 32) * ELEMENT_BYTES);
    // v_srsrc[2] = seqlen_v_stride;
    // if constexpr (true) {
    //     int nm_filter = inline_min_max<0, 32>(0 * WARP_K + 32 - max_seq_kv_offset);
    //     v_srsrc[3] = max_seq_kv_offset % kBlockK == 0 ? 0: nm_filter << 8;
    // }
    // int lds_stage_id = 0;
    // int lds_offset = (lds_stage_id * WARP_K * kHeadDim_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;

    // flash::wait_all_warp_arrived(); // 防止写 v lds 和读 q lds k lds 冲突, qk 可能有的 warp 没结束
    // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);
    int tid = threadIdx.x % 64;
    int index_topk_1 = index_ptr[n_loop * 64 + (tid / 4)];
    int index_topk_2 = index_ptr[n_loop * 64 + (tid / 4) + 16];
    int lds_offset = __builtin_amdgcn_readfirstlane((warp_id * 32 * 32) * ELEMENT_BYTES / 4);
    int g_offset_v = warp_id * 16 + tid % 4 * 4 + index_topk_1 * seqlen_v_stride * ELEMENT_BYTES / 4;
    int lds_offset_add = __builtin_amdgcn_readfirstlane((32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
    int g_offset_v_add = warp_id * 16 + tid % 4 * 4 + index_topk_2 * seqlen_v_stride * ELEMENT_BYTES / 4;
    flash::wait_all_warp_arrived();
    inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
    inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
    __builtin_amdgcn_sched_barrier(0);
}

template<int kHeadDim, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, typename Element, bool Is_even_MN>
__forceinline__ __device__ void prefetch_v_to_lds_mla_dsa_h64_legacy_contiguous_d576(
        vec4_uint v_ptr,
        Element* v_lds,
        int warp_id,
        int seqlen_v_stride,
        int* index_ptr,
        int batch_stride,
        int n_loop,
        int max_seq_kv_offset=0) {

    constexpr int ELEMENT_BYTES = sizeof(Element);
    constexpr int WARP_NUM = kBlockM * kBlockN / (WARP_M * WARP_N);
    constexpr int WARP_K   = 32;
    constexpr int kHeadDim_OPT = 256;   // 32x32 x WARP_NUM x 2B x stage == 32K

    // MLS
    // int n_load = 0;
    // vec4_uint v_srsrc;
    // *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_load * WARP_NUM * 32 + warp_id * 32) * ELEMENT_BYTES);
    // v_srsrc[2] = seqlen_v_stride;
    // if constexpr (true) {
    //     int nm_filter = inline_min_max<0, 32>(0 * WARP_K + 32 - max_seq_kv_offset);
    //     v_srsrc[3] = max_seq_kv_offset % kBlockK == 0 ? 0: nm_filter << 8;
    // }
    // int lds_stage_id = 0;
    // int lds_offset = (lds_stage_id * WARP_K * kHeadDim_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;

    // flash::wait_all_warp_arrived(); // 防止写 v lds 和读 q lds k lds 冲突, qk 可能有的 warp 没结束
    // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);
    int tid = threadIdx.x % 64;
    int index_topk_1 = index_ptr[((n_loop * 64)) + (tid / 4)];
    int index_topk_2 = index_ptr[((n_loop * 64)) + (tid / 4) + 16];
    int lds_offset = __builtin_amdgcn_readfirstlane((warp_id * 32 * 32) * ELEMENT_BYTES / 4);
    int g_offset_v = warp_id * 16 + tid % 4 * 4 + index_topk_1 * seqlen_v_stride * ELEMENT_BYTES / 4;
    int lds_offset_add = __builtin_amdgcn_readfirstlane((32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
    int g_offset_v_add = warp_id * 16 + tid % 4 * 4 + index_topk_2 * seqlen_v_stride * ELEMENT_BYTES / 4;
    flash::wait_all_warp_arrived();
    inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
    inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
    // g_offset_v += WARP_NUM * 32 * ELEMENT_BYTES / 4;
    // g_offset_v_add += WARP_NUM * 32 * ELEMENT_BYTES / 4;
    // lds_offset = __builtin_amdgcn_readfirstlane(((warp_id + WARP_NUM) * 32 * 32) * ELEMENT_BYTES / 4);
    // lds_offset_add = __builtin_amdgcn_readfirstlane((32 * 16 + (warp_id + WARP_NUM) * 32 * 32) * ELEMENT_BYTES / 4);
    // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
    // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
    __builtin_amdgcn_sched_barrier(0);
}
