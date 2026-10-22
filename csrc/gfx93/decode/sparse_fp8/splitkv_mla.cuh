#pragma once

#include "hytlass_ext.h"

#include "splitkv_mla.h"

#include <kerutils/kerutils.cuh>

#include "utils.h"
#include "components/dequant.h"
#include "components/helpers.h"
#include "config.h"
#include "softmax.h"
using namespace hute;

namespace gfx93::decode::sparse_fp8 {
#define CUDART_L2E_F            1.442695041F

// ---- KernelTemplate 的 V32 辅助函数（static，可直接内联，不依赖 this）----

template<ModelType MODEL_TYPE, int NUM_HEADS, bool HAVE_TOPK_LENGTH>
__device__ __forceinline__ auto
KernelTemplate<MODEL_TYPE, NUM_HEADS, HAVE_TOPK_LENGTH>::dequant_fp8_to_bf16(const Fp8_storage& data0, float kv_scale, int idx)
    -> std::tuple<Element, Element, Element, Element> {
    #if defined(__gfx938__)
    auto res1 = __builtin_amdgcn_cvt_pk_f32_fp8(data0.fp8_array[idx / 4], false);
    auto res2 = __builtin_amdgcn_cvt_pk_f32_fp8(data0.fp8_array[idx / 4], true);
    auto f1 = res1[0];
    auto f2 = res1[1];
    auto f3 = res2[0];
    auto f4 = res2[1];
    #else
    const auto fp8x2_low = *reinterpret_cast<const __hip_fp8x2_storage_t*>(&data0.fp8_array[idx / 4]);
    const auto fp8x2_high = *(reinterpret_cast<const __hip_fp8x2_storage_t*>(&(data0.fp8_array[idx / 4])) + 1);
    auto f1 = flash::fp8e4m3_to_fp32(static_cast<__hip_fp8_storage_t>((fp8x2_low << 8) >> 8));
    auto f2 = flash::fp8e4m3_to_fp32(static_cast<__hip_fp8_storage_t>((fp8x2_low >> 8)));
    auto f3 = flash::fp8e4m3_to_fp32(static_cast<__hip_fp8_storage_t>((fp8x2_high << 8) >> 8));
    auto f4 = flash::fp8e4m3_to_fp32(static_cast<__hip_fp8_storage_t>((fp8x2_high) >> 8));
    #endif
    f1 *= kv_scale;
    f2 *= kv_scale;
    f3 *= kv_scale;
    f4 *= kv_scale;
    hytlass::NumericConverter<Element, float, hytlass::FloatRoundStyle::round_toward_zero> convert_;
    return {convert_(f1), convert_(f2), convert_(f3), convert_(f4)};
}

template<ModelType MODEL_TYPE, int NUM_HEADS, bool HAVE_TOPK_LENGTH>
__device__ __forceinline__ auto
KernelTemplate<MODEL_TYPE, NUM_HEADS, HAVE_TOPK_LENGTH>::issue_kv_loads(const SparseAttnDecodeParams& params, int token_index, int col_idx, bool is_extra)
    -> PfKV {
    PfKV pf;
    uint8_t* k_ptr = is_extra ? (uint8_t*)params.extra_kv : (uint8_t*)params.kv;
    int page_block_size = is_extra ? params.extra_page_block_size : params.page_block_size;
    int64_t k_block_stride = is_extra ? params.stride_extra_kv_block : params.stride_kv_block;
    int64_t k_row_stride = is_extra ? params.stride_extra_kv_row : params.stride_kv_row;
    int block_index = token_index == -1 ? 0 : (int)((uint32_t)token_index / (uint32_t)page_block_size);
    int rel_idx_in_block = (uint32_t)token_index % (uint32_t)page_block_size;
    const int64_t offset_k = (int64_t)(block_index) * k_block_stride;
    uint8_t* gK_base;
    if constexpr (MODEL_TYPE == ModelType::V32) {
        // V32: K = 512 fp8 (4 个 128 段 scale) + 64 bf16 rope，scale 为 fp32 紧跟在 fp8 之后
        gK_base = k_ptr + offset_k + rel_idx_in_block * k_row_stride;
        float* scale_ptr = (float*)(gK_base + HEAD_DIM_NOPE);
        if (token_index == -1) {
            for (int i = 0; i < NUM_SCALES; i++) pf.scales[i] = 0.0f;
            for (int i = 0; i < 4; i++) {
                pf.kA[i].data_128 = {0};
                pf.kB[i].data_128 = {0};
            }
        } else {
            for (int i = 0; i < NUM_SCALES; i++) pf.scales[i] = scale_ptr[i];
            for (int i = 0; i < 4; i++) pf.kA[i].data_128 = *((__fp16x8_t*)(gK_base + col_idx * 16 + (4 + i) * 64));
            for (int i = 0; i < 4; i++) pf.kB[i].data_128 = *((__fp16x8_t*)(gK_base + col_idx * 16 + i * 64));
        }
        pf.rope0.data_128 = *((uint32x4_t*)(gK_base + col_idx * 16 * 2 + HEAD_DIM_NOPE + 16));
        pf.rope1.data_128 = *((uint32x4_t*)(gK_base + col_idx * 16 * 2 + 8 * 2 + HEAD_DIM_NOPE + 16));
    } else {
        // MODEL1: K = 448 fp8 (每 64 一段 scale, 共 7 段) + 64 bf16 rope；scale 为 e8m0，存放在 block 末尾
        gK_base = k_ptr + offset_k + rel_idx_in_block * (HEAD_DIM_NOPE + HEAD_DIM_ROPE * 2);
        uint8_t* scale_ptr = k_ptr + offset_k + page_block_size * (HEAD_DIM_NOPE + HEAD_DIM_ROPE * 2) + rel_idx_in_block * NUM_SCALES;
        if (token_index == -1) {
            for (int i = 0; i < NUM_SCALES; i++) pf.scales[i] = 0.0f;
            for (int i = 0; i < 4; i++) {
                pf.kA[i].data_128 = {0};
                pf.kB[i].data_128 = {0};
            }
            pf.rope0.data_128 = {0};
            pf.rope1.data_128 = {0};
        } else {
            union Scale_e8m0 {
                __fp16x4_t tmp;
                __hip_fp8_storage_t fp8_e8m0[NUM_SCALES];
            };
            Scale_e8m0 scale_e8m0;
            scale_e8m0.tmp = *(__fp16x4_t*)(scale_ptr);
            union Fp32 {
                uint32_t as_bits;
                float as_value;
            };
            Fp32 fp32;
            for (int i = 0; i < NUM_SCALES - 1; i++) {
                fp32.as_bits = (scale_e8m0.fp8_e8m0[i] << 23);
                pf.scales[i] = fp32.as_value;
            }
            for (int i = 0; i < 3; i++) pf.kA[i].data_128 = *((__fp16x8_t*)(gK_base + col_idx * 16 + (4 + i) * 64));
            for (int i = 0; i < 4; i++) pf.kB[i].data_128 = *((__fp16x8_t*)(gK_base + col_idx * 16 + i * 64));
            pf.rope0.data_128 = *((uint32x4_t*)(gK_base + col_idx * 16 * 2 + HEAD_DIM_NOPE));
            pf.rope1.data_128 = *((uint32x4_t*)(gK_base + col_idx * 16 * 2 + 8 * 2 + HEAD_DIM_NOPE));
        }
    }
    return pf;
}

template<ModelType MODEL_TYPE, int NUM_HEADS, bool HAVE_TOPK_LENGTH>
__device__ __forceinline__ void
KernelTemplate<MODEL_TYPE, NUM_HEADS, HAVE_TOPK_LENGTH>::lds_direct_copy_q(const Element* q_ptr, const SparseAttnDecodeParams& params, Element* s_q,
                                                                          int head_block_idx, int lane_idx, int warp_idx, int k_idx, int offset_k) {
    struct PtrWrapper {
        uint32_t former;
        uint32_t latter;
    };
    PtrWrapper glob_ptr;
    *(uint64_t*)&glob_ptr = reinterpret_cast<uint64_t>(q_ptr);
    uint32x4_t global_addr = {0};
    global_addr[0] = (glob_ptr.former);
    global_addr[1] = (glob_ptr.latter);
    global_addr[2] = 0x80000000;
    global_addr[3] = 0x00020000;
    constexpr int bytes_per_warp = 64 * 8 * 2;
    constexpr int bytes_per_block = bytes_per_warp * 4;
    const int row_idx = lane_idx % 16;
    const int col_idx = lane_idx / 16;
    const int row_offset = row_idx;
    if constexpr (MODEL_TYPE == ModelType::V32) {
        int col_offset;
        if (k_idx == 2) {
            col_offset = k_idx * 256 + warp_idx * 8 + col_idx * 16;
        } else {
            col_offset = k_idx * 256 + warp_idx * 64 + col_idx * 16 + offset_k * 8;
        }
        int offset_v = (row_offset * params.stride_q_h_q + col_offset) * 2;
        if (head_block_idx * BLOCK_M + row_idx >= params.h_q) {
            offset_v = -1;
        }
        if (k_idx == 2 && warp_idx >= 2) {
            offset_v = -1;
        }
        const int offset_s = 0;
        int ldsAddrPerWave = reinterpret_cast<size_t>(s_q) + warp_idx * bytes_per_warp + k_idx * bytes_per_block
            + offset_k * 3 * bytes_per_block;
        __builtin_amdgcn_sched_barrier(0);
        asm volatile(
            "s_mov_b32 m0, %1 \n\t"
            "s_nop 0 \n\t"
            "buffer_load_dwordx4 %0, %2, %3 ,offen  offset:0, lds \n" ::"v"(offset_v),
            "s"(ldsAddrPerWave), "s"(global_addr), "s"(offset_s)
        :);
        __builtin_amdgcn_sched_barrier(0);
    } else {
        const int col_offset = k_idx * 256 + warp_idx * 64 + col_idx * 16 + offset_k * 8;
        int offset_v = (row_offset * params.stride_q_h_q + col_offset) * 2;
        if (head_block_idx * BLOCK_M + row_idx >= params.h_q) {
            offset_v = -1;
        }
        const int offset_s = 0;
        int ldsAddrPerWave = reinterpret_cast<size_t>(s_q) + warp_idx * bytes_per_warp + k_idx * bytes_per_block
            + offset_k * 2 * bytes_per_block;
        __builtin_amdgcn_sched_barrier(0);
        asm volatile(
            "s_mov_b32 m0, %1 \n\t"
            "s_nop 0 \n\t"
            "buffer_load_dwordx4 %0, %2, %3 ,offen  offset:0, lds \n" ::"v"(offset_v),
            "s"(ldsAddrPerWave), "s"(global_addr), "s"(offset_s)
        :);
        __builtin_amdgcn_sched_barrier(0);
    }
}

// 解析本次请求的调度信息（block 范围、是否 no-split、topk_length 等）
template<ModelType MODEL_TYPE, int NUM_HEADS, bool HAVE_TOPK_LENGTH>
__device__ __forceinline__ auto
KernelTemplate<MODEL_TYPE, NUM_HEADS, HAVE_TOPK_LENGTH>::get_cur_req_info(const SparseAttnDecodeParams& params, const DecodingSchedMeta& sched_meta, int batch_idx)
    -> MainloopArgs {
    MainloopArgs args;
    int total_topk_padded;
    if constexpr (HAVE_TOPK_LENGTH) {
        // 动态 topk_length 截断，V32 与 MODEL1 共用；<true> 实例保证 topk_length 非空
        int topk_length = __ldg(params.topk_length + batch_idx);
        total_topk_padded = max(ku::ceil(topk_length, (int)TOPK_BLOCK_SIZE), (int)TOPK_BLOCK_SIZE);
        args.topk_length = topk_length;
        args.num_orig_kv_blocks = total_topk_padded / TOPK_BLOCK_SIZE;
    } else {
        // 静态 topk：编译期不生成 topk_length 相关代码，与基线等价（V32 与 MODEL1 共用）
        total_topk_padded = params.topk;
        args.num_orig_kv_blocks = params.topk / TOPK_BLOCK_SIZE;
    }
    if constexpr (MODEL_TYPE == ModelType::MODEL1) {
        // extra_kv 仅 MODEL1，与 topk_length 相互独立，静态/动态都需截断 extra_topk_length
        int extra_topk_length = params.extra_topk_length ? __ldg(params.extra_topk_length + batch_idx) : params.extra_topk;
        total_topk_padded += ku::ceil(extra_topk_length, (int)TOPK_BLOCK_SIZE);
        args.extra_topk_length = extra_topk_length;
    }

    args.start_block_idx = batch_idx == sched_meta.begin_req_idx ? sched_meta.begin_block_idx : 0;
    args.end_block_idx = batch_idx == sched_meta.end_req_idx ? sched_meta.end_block_idx : total_topk_padded / TOPK_BLOCK_SIZE;
    args.is_no_split = batch_idx == sched_meta.begin_req_idx ? !sched_meta.is_first_req_splitted : (batch_idx == sched_meta.end_req_idx ? !sched_meta.is_last_req_splitted : true);

    return args;
}

template<ModelType MODEL_TYPE, int NUM_HEADS, bool HAVE_TOPK_LENGTH>
__device__ __forceinline__ uint16_t
KernelTemplate<MODEL_TYPE, NUM_HEADS, HAVE_TOPK_LENGTH>::float2bf16(float s) {
    uint32_t x32 = reinterpret_cast<uint32_t const &>(s);
    #ifndef FLASH_MLA_BF16_TYPE
    #define FLASH_MLA_BF16_TYPE 0
    #endif
    #if FLASH_MLA_BF16_TYPE == 1
    x32 += 0x8000u;
    #endif
    return uint16_t(x32 >> 16);
}

template<ModelType MODEL_TYPE, int NUM_HEADS, bool HAVE_TOPK_LENGTH>
__device__ void KernelTemplate<MODEL_TYPE, NUM_HEADS, HAVE_TOPK_LENGTH>::compute_attn_1rowblock_splitkv_sparse_mla_fp8(const SparseAttnDecodeParams &params, const DecodingSchedMeta& sched_meta, int batch_idx) {
    using Element = hytlass::bfloat16_t;
    using index_t = int64_t;
    const int tidx = threadIdx.x;
    const int lane_idx = tidx % 64;
    const int warp_idx = __builtin_amdgcn_readfirstlane(tidx / 64);
    const int head_block_idx = NUM_M_BLOCKS == 1 ? 0 : blockIdx.x;
    const int s_q_idx = blockIdx.y;
    extern __shared__ char shared_memory[];
    SharedMemoryPlan &plan = *reinterpret_cast<SharedMemoryPlan*>(shared_memory);

    const index_t row_offset_q = batch_idx * params.stride_q_b + head_block_idx * BLOCK_M * params.stride_q_h_q + s_q_idx * params.stride_q_s_q;
    Tensor gQ = make_tensor(make_gmem_ptr(reinterpret_cast<Element *>(params.q) + row_offset_q),
                            Shape<Int<BLOCK_M>, Int<HEAD_DIM_K>>{},
                            make_stride(params.stride_q_h_q, _1{}));
    TiledMMA tiled_mma = TiledMma{};
    auto thr_mma = tiled_mma.get_thread_slice(tidx);
    Tensor tSrQ = thr_mma.partition_fragment_A(gQ);
    // 需要的最大空间为 16 * 576 * 2
    Element* s_q = reinterpret_cast<Element *>(shared_memory);

    if constexpr (MODEL_TYPE == ModelType::V32) {
        const auto q_ptr = gQ.data().get();
        lds_direct_copy_q(q_ptr, params, s_q, head_block_idx, lane_idx, warp_idx, 0, 0);
        lds_direct_copy_q(q_ptr, params, s_q, head_block_idx, lane_idx, warp_idx, 1, 0);
        lds_direct_copy_q(q_ptr, params, s_q, head_block_idx, lane_idx, warp_idx, 0, 1);
        lds_direct_copy_q(q_ptr, params, s_q, head_block_idx, lane_idx, warp_idx, 1, 1);
        lds_direct_copy_q(q_ptr, params, s_q, head_block_idx, lane_idx, warp_idx, 2, 0);
        Element* s_q_read_ptr = s_q + lane_idx * 8;
        __builtin_amdgcn_sched_barrier(0);
        asm volatile("s_waitcnt vmcnt(4) \n s_barrier"); 
        __builtin_amdgcn_sched_barrier(0);
        for (int k = 0; k < 4; k++) {
            for (int i = 0; i < 8; i++) {
                tSrQ(i, 0, k) = s_q_read_ptr[i];
            }
            s_q_read_ptr += 16 * 32;
        }
        __builtin_amdgcn_sched_barrier(0);
        asm volatile("s_waitcnt vmcnt(3) \n s_barrier"); 
        __builtin_amdgcn_sched_barrier(0);
        for (int k = 4; k < 8; k++) {
            for (int i = 0; i < 8; i++) {
                tSrQ(i, 0, k) = s_q_read_ptr[i];
            }
            s_q_read_ptr += 16 * 32;
        }
        __builtin_amdgcn_sched_barrier(0);
        asm volatile("s_waitcnt vmcnt(2) \n s_barrier"); 
        __builtin_amdgcn_sched_barrier(0);
        s_q_read_ptr = s_q + lane_idx * 8 + 3 * 4 * 16 * 4 * 8;
        for (int k = 0; k < 4; k++) {
            for (int i = 8; i < 16; i++) {
                tSrQ(i, 0, k) = s_q_read_ptr[i - 8];
            }
            s_q_read_ptr += 16 * 32;
        }
        __builtin_amdgcn_sched_barrier(0);
        asm volatile("s_waitcnt vmcnt(1) \n s_barrier"); 
        __builtin_amdgcn_sched_barrier(0);
        for (int k = 4; k < 8; k++) {
            for (int i = 8; i < 16; i++) {
                tSrQ(i, 0, k) = s_q_read_ptr[i - 8];
            }
            s_q_read_ptr += 16 * 32;
        }
        __builtin_amdgcn_sched_barrier(0);
        asm volatile("s_waitcnt vmcnt(0) \n s_barrier"); 
        __builtin_amdgcn_sched_barrier(0);
        s_q_read_ptr = s_q + lane_idx * 8 + 2 * 4 * 16 * 4 * 8;
        for (int k = 8; k < 9; k++) {
            for (int i = 0; i < 8; i++) {
                tSrQ(i, 0, k) = s_q_read_ptr[i];
            }
            s_q_read_ptr += 16 * 32;
        }
        for (int k = 8; k < 9; k++) {
            for (int i = 8; i < 16; i++) {
                tSrQ(i, 0, k) = s_q_read_ptr[i-8];
            }
            s_q_read_ptr += 16 * 32;
        }
        __builtin_amdgcn_sched_barrier(0);
        asm volatile("s_waitcnt lgkmcnt(0) \n s_barrier"); 
        __builtin_amdgcn_sched_barrier(0);

    } else {
        const auto q_ptr = gQ.data().get();
        lds_direct_copy_q(q_ptr, params, s_q, head_block_idx, lane_idx, warp_idx, 0, 0);
        lds_direct_copy_q(q_ptr, params, s_q, head_block_idx, lane_idx, warp_idx, 1, 0);
        lds_direct_copy_q(q_ptr, params, s_q, head_block_idx, lane_idx, warp_idx, 0, 1);
        lds_direct_copy_q(q_ptr, params, s_q, head_block_idx, lane_idx, warp_idx, 1, 1);

        Element* s_q_read_ptr = s_q + lane_idx * 8;
        __builtin_amdgcn_sched_barrier(0);
        asm volatile("s_waitcnt vmcnt(3) \n s_barrier"); 
        __builtin_amdgcn_sched_barrier(0);
        for (int k = 0; k < 4; k++) {
            for (int i = 0; i < 8; i++) {
                tSrQ(i, 0, k) = s_q_read_ptr[i];
            }
            s_q_read_ptr += 16 * 32;
        }
        __builtin_amdgcn_sched_barrier(0);
        asm volatile("s_waitcnt vmcnt(2) \n s_barrier"); 
        __builtin_amdgcn_sched_barrier(0);
        for (int k = 4; k < 8; k++) {
            for (int i = 0; i < 8; i++) {
                tSrQ(i, 0, k) = s_q_read_ptr[i];
            }
            s_q_read_ptr += 16 * 32;
        }
        __builtin_amdgcn_sched_barrier(0);
        asm volatile("s_waitcnt vmcnt(1) \n s_barrier"); 
        __builtin_amdgcn_sched_barrier(0);
        for (int k = 0; k < 4; k++) {
            for (int i = 8; i < 16; i++) {
                tSrQ(i, 0, k) = s_q_read_ptr[i - 8];
            }
            s_q_read_ptr += 16 * 32;
        }
        __builtin_amdgcn_sched_barrier(0);
        asm volatile("s_waitcnt vmcnt(0) \n s_barrier"); 
        __builtin_amdgcn_sched_barrier(0);
        for (int k = 4; k < 8; k++) {
            for (int i = 8; i < 16; i++) {
                tSrQ(i, 0, k) = s_q_read_ptr[i - 8];
            }
            s_q_read_ptr += 16 * 32;
        }
        __builtin_amdgcn_sched_barrier(0);
        asm volatile("s_waitcnt lgkmcnt(0) \n s_barrier"); 
        __builtin_amdgcn_sched_barrier(0);
    }
   
    Tensor gK = make_tensor(make_gmem_ptr(reinterpret_cast<uint8_t *>(params.kv)),
                            Shape<Int<TOPK_BLOCK_SIZE>, Int<HEAD_DIM_K>>{},
                            make_stride(params.stride_kv_row, _1{}));
    Tensor tSrK  = thr_mma.partition_fragment_B(gK); 
    TiledMMA tiled_mma_16x16x32 = TiledMma_16_16_32{};
    auto smem_tiled_copy_K = make_tiled_copy_B(Copy_Atom<DefaultCopy, Element>{}, tiled_mma_16x16x32);
    auto smem_thr_copy_K = smem_tiled_copy_K.get_thread_slice(tidx);
    Tensor sK = make_tensor(make_smem_ptr(plan.smem_v.data()), SmemLayoutK{});
    Tensor tOsV = smem_thr_copy_K.partition_S(sK);

    TiledMMA tiled_mma_o = TiledMma_O{};
    auto thr_mma_o = tiled_mma_o.get_thread_slice(tidx);
    auto smem_tiled_copy_V = make_tiled_copy_B(Copy_Atom<flash_mla::hytlass_ext::GFX928_DS_READ_DS_M32x16_B16, Element>{}, tiled_mma_o);
    auto smem_thr_copy_V = smem_tiled_copy_V.get_thread_slice(tidx);
    Tensor sV = make_tensor(make_smem_ptr(plan.smem_v.data()), SmemLayoutV{});
    Tensor sVt = make_tensor(sV.data(), SmemLayoutVtransposed{});
    Tensor tOsVt = smem_thr_copy_V.partition_S(sVt);
    Tensor tOrVt  = thr_mma_o.partition_fragment_B(sVt);
    Tensor tOrVt_copy_view = smem_thr_copy_V.retile_D(tOrVt);

    Tensor acc_o = partition_fragment_C(tiled_mma_o, Shape<Int<BLOCK_M>, Int<HEAD_DIM_V>>{});
    clear(acc_o);
    flash::Softmax<size<1>(acc_o)> softmax;
    MainloopArgs args = get_cur_req_info(params, sched_meta, batch_idx);

    // idx_of / consume_block_pf 依赖的上下文（indices 与 smem 视图）
    const index_t row_offset_topk =  batch_idx * params.stride_indices_b + s_q_idx * params.stride_indices_s_q;
    int* gIndices = reinterpret_cast<int *>(params.indices) + row_offset_topk;
    int* gExtraIndices = params.extra_indices + batch_idx*params.stride_extra_indices_b + s_q_idx*params.stride_extra_indices_s_q; // (extra_topk) : (1)
    Tensor sP = make_tensor(make_smem_ptr(plan.smem_p.data()), SmemLayoutP{});
    Tensor sRow_max_reduce_buffer = make_tensor(make_smem_ptr(plan.smem_row_max.data()), SmemLayoutRow{});
    Tensor sRow_sum_reduce_buffer = make_tensor(make_smem_ptr(plan.smem_row_sum.data()), SmemLayoutRow{});

    // 取 block_idx 对应 lane 的 token：超出 topk_length 的位置按 -1 处理，使 K/V 加载为 0
    // （避免 0 x NaN 在 PV 中传播出 NaN）。
    auto idx_of = [&](int block_idx, bool is_extra) -> int {
        const int off = (lane_idx % 16) + warp_idx * 16;
        int* indices_base = is_extra
            ? gExtraIndices + (block_idx - args.num_orig_kv_blocks) * TOPK_BLOCK_SIZE
            : gIndices + block_idx * TOPK_BLOCK_SIZE;
        [[maybe_unused]] int rel_block_idx = is_extra ? (block_idx - args.num_orig_kv_blocks) : block_idx;
        [[maybe_unused]] int topk_length = is_extra ? args.extra_topk_length : args.topk_length;
        int token = indices_base[off];
        if (is_extra || HAVE_TOPK_LENGTH) {
            if (rel_block_idx * TOPK_BLOCK_SIZE + off >= topk_length) token = -1;
        }
        return token;
    };

    struct IsOrigBlock {};
    struct IsExtraBlock {};

    // 消费一个已预取到寄存器的 block：QK -> mask -> softmax -> PV
    auto consume_block_pf = [&](int block_idx, const PfKV& pf, auto is_extra_block_t) {
        static constexpr bool IS_EXTRA_BLOCK = std::is_same_v<decltype(is_extra_block_t), IsExtraBlock>;
        Tensor acc_s = partition_fragment_C(tiled_mma, Shape<Int<BLOCK_M>, Int<TOPK_BLOCK_SIZE>>{});
        clear(acc_s);
        int* indices_base = IS_EXTRA_BLOCK
            ? gExtraIndices + (block_idx - args.num_orig_kv_blocks) * TOPK_BLOCK_SIZE
            : gIndices + block_idx * TOPK_BLOCK_SIZE;
        [[maybe_unused]] int topk_length = IS_EXTRA_BLOCK ? args.extra_topk_length : args.topk_length;
        [[maybe_unused]] int rel_block_idx = IS_EXTRA_BLOCK ? (block_idx - args.num_orig_kv_blocks) : block_idx;

        // QK A: V32 -> k_idx 4..7 (dims 256..511)；MODEL1 -> k_idx 4..6 (dims 256..447)
        constexpr int k_idx_a_end = MODEL_TYPE == ModelType::V32 ? 8 : 7;
        for (int k_idx = 4; k_idx < k_idx_a_end; k_idx++) {
            for (int j = 0; j < 16; j += 4) {
                auto [rst0, rst1, rst2, rst3] = dequant_fp8_to_bf16(pf.kA[k_idx - 4], pf.scales[MODEL_TYPE == ModelType::V32 ? k_idx / 2 : k_idx], j);
                tSrK(j, 0, k_idx) = rst0;
                tSrK(j + 1, 0, k_idx) = rst1;
                tSrK(j + 2, 0, k_idx) = rst2;
                tSrK(j + 3, 0, k_idx) = rst3;
            }
            #pragma unroll
            for (int j = 0; j < 8; j++) {
                tOsV(j, 0, (k_idx - 4) * 2) = tSrK(j, 0, k_idx);
            }
            #pragma unroll
            for (int j = 8; j < 16; j++) {
                tOsV(j - 8, 0, (k_idx - 4) * 2 + 1) = tSrK(j, 0, k_idx);
            }
            hute::gemm(tiled_mma, tSrQ(_, _, k_idx), tSrK(_, _, k_idx), acc_s);
        }
        if constexpr (MODEL_TYPE == ModelType::MODEL1) {
            // MODEL1: k_idx 7 = rope (dims 448..511)，且属于 V（写入 tOsV slot 6/7）
            for (int j = 0; j < 8; j++) {
                tSrK(j, 0, 7) = hytlass::bfloat16_t::bitcast(pf.rope0.data_array[j]);
            }
            for (int j = 8; j < 16; j++) {
                tSrK(j, 0, 7) = hytlass::bfloat16_t::bitcast(pf.rope1.data_array[j - 8]);
            }
            hute::gemm(tiled_mma, tSrQ(_, _, 7), tSrK(_, _, 7), acc_s);
            #pragma unroll
            for (int j = 0; j < 8; j++) {
                tOsV(j, 0, 6) = tSrK(j, 0, 7);
            }
            #pragma unroll
            for (int j = 8; j < 16; j++) {
                tOsV(j - 8, 0, 7) = tSrK(j, 0, 7);
            }
        }
        __syncthreads();
        __builtin_amdgcn_sched_barrier(0);
        flash::__ds_read_m32x16_row_col_rrow_alt<0, 0, 2>(tOsVt, tOrVt_copy_view);
        flash::__ds_read_m32x16_row_col_rrow_alt<0, 1, 2>(tOsVt, tOrVt_copy_view);
        flash::__ds_read_m32x16_row_col_rrow_alt<0, 2, 2>(tOsVt, tOrVt_copy_view);
        flash::__ds_read_m32x16_row_col_rrow_alt<0, 3, 2>(tOsVt, tOrVt_copy_view);
        flash::__ds_read_m32x16_row_col_rrow_alt<1, 0, 3>(tOsVt, tOrVt_copy_view);
        flash::__ds_read_m32x16_row_col_rrow_alt<1, 1, 3>(tOsVt, tOrVt_copy_view);
        flash::__ds_read_m32x16_row_col_rrow_alt<1, 2, 3>(tOsVt, tOrVt_copy_view);
        flash::__ds_read_m32x16_row_col_rrow_alt<1, 3, 3>(tOsVt, tOrVt_copy_view);
        __builtin_amdgcn_sched_barrier(0);
        __syncthreads();
        __builtin_amdgcn_sched_barrier(0);

        // QK B: k_idx 0..3 (dims 0..255)
        for (int k_idx = 0; k_idx < 4; k_idx++) {
            for (int j = 0; j < 16; j += 4) {
                auto [rst0, rst1, rst2, rst3] = dequant_fp8_to_bf16(pf.kB[k_idx], pf.scales[MODEL_TYPE == ModelType::V32 ? k_idx / 2 : k_idx], j);
                tSrK(j, 0, k_idx) = rst0;
                tSrK(j + 1, 0, k_idx) = rst1;
                tSrK(j + 2, 0, k_idx) = rst2;
                tSrK(j + 3, 0, k_idx) = rst3;
            }
            #pragma unroll
            for (int j = 0; j < 8; j++) {
                tOsV(j, 0, k_idx * 2) = tSrK(j, 0, k_idx);
            }
            #pragma unroll
            for (int j = 8; j < 16; j++) {
                tOsV(j - 8, 0, k_idx * 2 + 1) = tSrK(j, 0, k_idx);
            }
            hute::gemm(tiled_mma, tSrQ(_, _, k_idx), tSrK(_, _, k_idx), acc_s);
        }
        __syncthreads();
        __builtin_amdgcn_sched_barrier(0);
        flash::__ds_read_m32x16_row_col_rrow_alt<0, 0, 0>(tOsVt, tOrVt_copy_view);
        flash::__ds_read_m32x16_row_col_rrow_alt<0, 1, 0>(tOsVt, tOrVt_copy_view);
        flash::__ds_read_m32x16_row_col_rrow_alt<0, 2, 0>(tOsVt, tOrVt_copy_view);
        flash::__ds_read_m32x16_row_col_rrow_alt<0, 3, 0>(tOsVt, tOrVt_copy_view);
        __builtin_amdgcn_sched_barrier(0);
        if constexpr (MODEL_TYPE == ModelType::V32) {
            // V32: k_idx 8 = rope (dims 512..575)，不属于 V
            for (int j = 0; j < 8; j++) {
                tSrK(j, 0, 8) = hytlass::bfloat16_t::bitcast(pf.rope0.data_array[j]);
            }
            for (int j = 8; j < 16; j++) {
                tSrK(j, 0, 8) = hytlass::bfloat16_t::bitcast(pf.rope1.data_array[j - 8]);
            }
            hute::gemm(tiled_mma, tSrQ(_, _, 8), tSrK(_, _, 8), acc_s);
        }
        __builtin_amdgcn_sched_barrier(0);
        asm volatile("s_waitcnt lgkmcnt(0) \n\t s_barrier\n\t");
        __builtin_amdgcn_sched_barrier(0);

        // mask + softmax
        Tensor cS = make_identity_tensor(Shape<Int<BLOCK_M>, Int<TOPK_BLOCK_SIZE>>{});
        Tensor tScS = thr_mma.partition_C(cS);
        for (int i = 0; i < size(acc_s); ++i) {
            if constexpr (IS_EXTRA_BLOCK || HAVE_TOPK_LENGTH) {
                int col = int(get<1>(tScS(i)));
                if (indices_base[col] == -1 || (rel_block_idx * TOPK_BLOCK_SIZE + col >= topk_length)) acc_s(i) = -INFINITY;
            } else {
                if (indices_base[int(get<1>(tScS(i)))] == -1) acc_s(i) = -INFINITY;
            }
        }
        block_idx == args.start_block_idx
        ? softmax.template softmax_rescale_o_prefill</*Is_first=*/true,  /*Check_inf=*/Is_causal>(acc_s, acc_o, sRow_max_reduce_buffer, params.sm_scale_div_log2)
        :   softmax.template softmax_rescale_o_prefill</*Is_first=*/false, /*Check_inf=*/Is_causal>(acc_s, acc_o, sRow_max_reduce_buffer, params.sm_scale_div_log2);
        Tensor rP = flash::convert_type<Element>(acc_s);
        Tensor tOrP = flash::convert_layout_acc_Aregs(tiled_mma, tiled_mma_o, rP, sP);

        // PV
        {
            flash::__ds_read_m32x16_row_col_alt<1, 0>(tOsVt, tOrVt_copy_view);
            flash::__ds_read_m32x16_row_col_alt<1, 1>(tOsVt, tOrVt_copy_view);
            hute::gemm(tiled_mma_o, tOrP(_, _, 0), tOrVt(_, _, 0), acc_o);
            hute::gemm(tiled_mma_o, tOrP(_, _, 1), tOrVt(_, _, 1), acc_o);
            flash::__ds_read_m32x16_row_col_alt<1, 2>(tOsVt, tOrVt_copy_view);
            flash::__ds_read_m32x16_row_col_alt<1, 3>(tOsVt, tOrVt_copy_view);
            hute::gemm(tiled_mma_o, tOrP(_, _, 2), tOrVt(_, _, 2), acc_o);
            hute::gemm(tiled_mma_o, tOrP(_, _, 3), tOrVt(_, _, 3), acc_o);
        }
    };

    const int col_idx_pf = lane_idx / 16;
    if constexpr (MODEL_TYPE == ModelType::V32) {
        for (int block_idx = args.start_block_idx; block_idx < args.end_block_idx; ++block_idx) {
            PfKV pf = issue_kv_loads(params, idx_of(block_idx, false), col_idx_pf, false);
            consume_block_pf(block_idx, pf, IsOrigBlock{});
        }
    } else {
        for (int block_idx = args.start_block_idx; block_idx < min(args.num_orig_kv_blocks, args.end_block_idx); ++block_idx) {
            PfKV pf = issue_kv_loads(params, idx_of(block_idx, false), col_idx_pf, false);
            consume_block_pf(block_idx, pf, IsOrigBlock{});
        }
        for (int block_idx = max(args.start_block_idx, args.num_orig_kv_blocks); block_idx < args.end_block_idx; ++block_idx) {
            PfKV pf = issue_kv_loads(params, idx_of(block_idx, true), col_idx_pf, true);
            consume_block_pf(block_idx, pf, IsExtraBlock{});
        }
    }
    
    if (args.is_no_split) {
        int start_head_idx = head_block_idx*BLOCK_M;
        Tensor lse = softmax.template normalize_softmax_lse<false>(acc_o, sRow_sum_reduce_buffer, params.sm_scale);
        const index_t row_offset_o = batch_idx * params.stride_o_b + start_head_idx * params.stride_o_h_q + s_q_idx * params.stride_o_s_q ;
        Tensor gO = make_tensor(make_gmem_ptr(reinterpret_cast<Element *>(params.out) + row_offset_o),
                                        Shape<Int<BLOCK_M>, Int<HEAD_DIM_V>>{},
                                        make_stride(params.stride_o_h_q, _1{}));
        if (params.attn_sink != nullptr) {
            float rAttn_sink = __ldg((float*)params.attn_sink + start_head_idx + lane_idx % 16); 
            if (flash::is_positive_infinity(rAttn_sink)) {
                for (int i = 0; i < size(acc_o); i++) {
                    acc_o(i) = 0.0f;
                } 
            }
            else
            {
                if (!flash::is_positive_infinity(lse(0)))
                {
                    // Stable sigmoid(LSE - sink): never exponentiate a positive value.
                    float sink_delta = (lse[0] - rAttn_sink) * CUDART_L2E_F;
                    float sink_exp_neg_abs = __builtin_amdgcn_exp2f(-fabsf(sink_delta));
                    float o_scale = (sink_delta >= 0.0f ? 1.0f : sink_exp_neg_abs)
                        / (1.0f + sink_exp_neg_abs);
                    for (int i = 0; i < size(acc_o); i++)
                    {
                        acc_o(i) *= o_scale;
                    }
                }
            }

        }
        float* gSoftmaxLse = (float*)params.lse + batch_idx * params.stride_lse_b + start_head_idx + s_q_idx * params.stride_lse_s_q;	// (BLOCK_M) : (1)
        {
            using result_type = hytlass::Array<Element, 2>;
            int row, col;
            const int warpId = tidx / 64;
            const int laneId = tidx % 64;
            for (int mi = 0; mi < size<1>(acc_o); ++mi) {
                row = mi * BLOCK_M + laneId % 16;
                if (row < params.h_q) {
                    for (int ni = 0; ni < size<2>(acc_o); ++ni) {
                        // 为了使用global_loadx4指令, V矩阵吸入lds的时候 N方向发生了了交换
                        /*
                        ------------------- N 方向----------------------
                        |0 1 ... 7 16 ... 31 40 ... 47 56... 64 8 .. 15 32 ... 39
                        |
                        |
                        k
                        方向
                        |
                        |
                        |
                        */
                        col = (laneId / 16) * 2 + ni * 128 + (warpId % 2) * 8 + (warpId / 2) * 64;
                        for (int i = 0; i < 4; i ++) {

                            #if defined(__gfx938__)
                            auto d =  __builtin_hcu_cvt_pk_bf16_f32(0, acc_o(i, mi, ni), 0, acc_o(i + 4, mi, ni), 0);
                            auto res = reinterpret_cast<result_type const &>(d);
                            #else
                            result_type res;
                            Element e0, e1;
                            e0.storage = float2bf16(acc_o(i, mi, ni));
                            e1.storage = float2bf16(acc_o(i + 4, mi, ni));
                            res[0] = e0;
                            res[1] = e1;
                            #endif
                            *(result_type*)(&gO(row, col)) = res;
                            col += 16;    
                        }
                    }
                    if (tidx / 16 == 0)
                        gSoftmaxLse[row] = lse(mi);
                }
            }
        }
    } else {
        int start_head_idx = head_block_idx*BLOCK_M;
        Tensor lse = softmax.template normalize_softmax_lse<false, true>(acc_o, sRow_sum_reduce_buffer, params.sm_scale);
        int n_split_idx = batch_idx == sched_meta.begin_req_idx ? sched_meta.begin_split_idx : 0;
        int split_idx = params.use_fixed_split
            ? batch_idx * params.fixed_num_splits + n_split_idx
            : __ldg(params.num_splits_ptr + batch_idx) + n_split_idx;
        float* oaccum_ptr = (float*)params.o_accum + split_idx*params.stride_o_accum_split + s_q_idx*params.stride_o_accum_s_q + start_head_idx*params.stride_o_accum_h_q;	// (BLOCK_M, HEAD_DIM_V) : (params.stride_o_accum_h_q, 1)
        Tensor gOaccum = make_tensor(make_gmem_ptr(oaccum_ptr), make_layout(
            Shape<Int<BLOCK_M>, Int<HEAD_DIM_V>>{},
            make_stride(params.stride_o_accum_h_q, _1{})
        ));
        float* gSoftmaxLseAccum = (float*)params.lse_accum + split_idx*params.stride_lse_accum_split + s_q_idx*params.stride_lse_accum_s_q + start_head_idx;	// (BLOCK_M) : (1)
        {
            int row, col;
            const int warpId = tidx / 64;
            const int laneId = tidx % 64;
            for (int mi = 0; mi < size<1>(acc_o); ++mi) {
                row = mi * BLOCK_M + laneId % 16;
                if (row < params.h_q) {
                    for (int ni = 0; ni < size<2>(acc_o); ++ni) {
                        col = (laneId / 16) * 2 + ni * 128 + (warpId % 2) * 8 + (warpId / 2) * 64;
                        for (int i = 0; i < 4; i ++) {
                            gOaccum(row, col) = acc_o(i, mi, ni);
                            gOaccum(row, col + 1) = acc_o(i + 4, mi, ni);
                            col += 16;
                        }
                    }
                    if (tidx / 16 == 0)
                        gSoftmaxLseAccum[row] = lse(mi);
                }
            }
        }
    }

}


template<ModelType MODEL_TYPE, int NUM_HEADS, bool HAVE_TOPK_LENGTH>
__device__ void KernelTemplate<MODEL_TYPE, NUM_HEADS, HAVE_TOPK_LENGTH>::devfunc(const SparseAttnDecodeParams &params) {
    const int partition_idx = blockIdx.z;
    DecodingSchedMeta sched_meta = params.tile_scheduler_metadata_ptr[partition_idx];

    if (sched_meta.begin_req_idx >= params.b) return;
    for (int batch_idx = sched_meta.begin_req_idx; batch_idx <= sched_meta.end_req_idx; ++batch_idx) {
        if (batch_idx > sched_meta.begin_req_idx) {
            __syncthreads();  
        }
        compute_attn_1rowblock_splitkv_sparse_mla_fp8(params, sched_meta, batch_idx);
    }
}

template<ModelType MODEL_TYPE, int NUM_HEADS, bool HAVE_TOPK_LENGTH>
__device__ void KernelTemplate<MODEL_TYPE, NUM_HEADS, HAVE_TOPK_LENGTH>::devfunc_fixed_split(
    const SparseAttnDecodeParams &params) {
    const int split_linear_idx = blockIdx.z;
    const int split_idx = split_linear_idx % params.fixed_num_splits;
    const int batch_idx = split_linear_idx / params.fixed_num_splits;
    if (batch_idx >= params.b) return;

    // 逐请求有效 token 数：动态 topk 时按 topk_length 截断，否则回到全量 topk。
    // max(...,1) 保证零有效 token 也至少调度 1 个 block，由 lane 掩码产出 lse=+inf。
    int total_blocks;
    if constexpr (HAVE_TOPK_LENGTH) {
        const int req_topk = std::min((int)params.topk_length[batch_idx], params.topk);
        total_blocks = std::max(hute::ceil_div(req_topk, TOPK_BLOCK_SIZE), 1);
    } else {
        total_blocks = params.topk / TOPK_BLOCK_SIZE;
    }
    const int blocks_per_split = hute::ceil_div(total_blocks, params.fixed_num_splits);

    DecodingSchedMeta fixed_meta{};
    fixed_meta.begin_req_idx = batch_idx;
    fixed_meta.end_req_idx = batch_idx;
    fixed_meta.begin_block_idx = split_idx * blocks_per_split;
    fixed_meta.end_block_idx = min(total_blocks, fixed_meta.begin_block_idx + blocks_per_split);
    fixed_meta.begin_split_idx = split_idx;
    fixed_meta.is_first_req_splitted = params.fixed_num_splits > 1;
    fixed_meta.is_last_req_splitted = params.fixed_num_splits > 1;

    compute_attn_1rowblock_splitkv_sparse_mla_fp8(params, fixed_meta, batch_idx);
}

template<typename Kernel>
__global__ void __launch_bounds__(Kernel::NUM_THREADS, 1)
flash_fwd_splitkv_mla_fp8_sparse_kernel(const SparseAttnDecodeParams params) {
#if defined(__gfx936__) || defined(__gfx938__)
    Kernel::devfunc(params);
#endif
}

template<typename Kernel>
__global__ void __launch_bounds__(Kernel::NUM_THREADS, 1)
flash_fwd_fixed_splitkv_mla_fp8_sparse_kernel(const SparseAttnDecodeParams params) {
#if defined(__gfx936__) || defined(__gfx938__)
    Kernel::devfunc_fixed_split(params);
#endif
}

template<ModelType MODEL_TYPE, int NUM_HEADS, bool HAVE_TOPK_LENGTH>
void KernelTemplate<MODEL_TYPE, NUM_HEADS, HAVE_TOPK_LENGTH>::run(const SparseAttnDecodeParams &params) {
    KU_ASSERT(params.h_kv == 1);
    KU_ASSERT(params.topk % TOPK_BLOCK_SIZE == 0);
    KU_ASSERT(params.d_qk == HEAD_DIM_K);
    KU_ASSERT(params.d_v == HEAD_DIM_V);
    if constexpr (MODEL_TYPE == ModelType::MODEL1) {
        constexpr int BYTES_PER_TOKEN = HEAD_DIM_NOPE + 2*HEAD_DIM_ROPE + 8;
        KU_ASSERT(params.stride_kv_row == BYTES_PER_TOKEN, "Each page block in KV cache must be contiguous for head64 sparse fp8 decoding attention in MODEL1");
        if (params.extra_kv != nullptr) {
            KU_ASSERT(params.stride_extra_kv_row == BYTES_PER_TOKEN, "Each page block in extra KV cache must be contiguous for head64 sparse fp8 decoding attention in MODEL1");
        }
    } else {
        KU_ASSERT(params.extra_kv == nullptr, "V3.2 does not support extra KV cache");
        KU_ASSERT((params.topk_length != nullptr) == HAVE_TOPK_LENGTH, "V3.2 topk_length must match the HAVE_TOPK_LENGTH instantiation");
        KU_ASSERT(params.stride_kv_row == 656);
    }
    auto mla_kernel = &flash_fwd_splitkv_mla_fp8_sparse_kernel<KernelTemplate<MODEL_TYPE, NUM_HEADS, HAVE_TOPK_LENGTH>>;
    constexpr size_t smem_size = 32768; // lds复用
    mla_kernel<<<dim3(NUM_M_BLOCKS, params.s_q, params.num_sm_parts), NUM_THREADS, smem_size, params.stream>>>(params);
}

template<ModelType MODEL_TYPE, int NUM_HEADS, bool HAVE_TOPK_LENGTH>
void KernelTemplate<MODEL_TYPE, NUM_HEADS, HAVE_TOPK_LENGTH>::run_fixed_split(
    const SparseAttnDecodeParams &params) {
    KU_ASSERT(params.h_kv == 1);
    KU_ASSERT(params.topk % TOPK_BLOCK_SIZE == 0);
    KU_ASSERT(params.d_qk == HEAD_DIM_K);
    KU_ASSERT(params.d_v == HEAD_DIM_V);
    KU_ASSERT(params.use_fixed_split);
    KU_ASSERT(params.fixed_num_splits >= 1);
    KU_ASSERT(params.fixed_partition_size >= TOPK_BLOCK_SIZE);
    KU_ASSERT(params.fixed_partition_size % TOPK_BLOCK_SIZE == 0);

    if constexpr (MODEL_TYPE == ModelType::MODEL1) {
        constexpr int BYTES_PER_TOKEN = HEAD_DIM_NOPE + 2*HEAD_DIM_ROPE + 8;
        KU_ASSERT(params.stride_kv_row == BYTES_PER_TOKEN);
        KU_ASSERT(params.extra_kv == nullptr);
        KU_ASSERT(params.topk_length == nullptr);
    } else {
        KU_ASSERT(params.extra_kv == nullptr, "V3.2 does not support extra KV cache");
        KU_ASSERT((params.topk_length != nullptr) == HAVE_TOPK_LENGTH, "V3.2 topk_length must match the HAVE_TOPK_LENGTH instantiation");
        KU_ASSERT(params.stride_kv_row == 656);
    }

    auto mla_kernel =
        &flash_fwd_fixed_splitkv_mla_fp8_sparse_kernel<KernelTemplate<MODEL_TYPE, NUM_HEADS, HAVE_TOPK_LENGTH>>;
    constexpr size_t smem_size = 32768;
    mla_kernel<<<dim3(NUM_M_BLOCKS, params.s_q, params.b * params.fixed_num_splits),
                 NUM_THREADS, smem_size, params.stream>>>(params);
    CHECK_CUDA_KERNEL_LAUNCH();
}

template<ModelType MODEL_TYPE, int NUM_HEADS>
void run_flash_splitkv_mla_fp8_sparse_kernel(const SparseAttnDecodeParams &params) {
    // V32 与 MODEL1 统一：有 topk_length 走动态特化，否则走静态特化（与基线等价）
    if (params.topk_length != nullptr) {
        KernelTemplate<MODEL_TYPE, NUM_HEADS, true>::run(params);
    } else {
        KernelTemplate<MODEL_TYPE, NUM_HEADS, false>::run(params);
    }
}

template<ModelType MODEL_TYPE, int NUM_HEADS>
void run_flash_fixed_splitkv_mla_fp8_sparse_kernel(const SparseAttnDecodeParams &params) {
    if (params.topk_length != nullptr) {
        KernelTemplate<MODEL_TYPE, NUM_HEADS, true>::run_fixed_split(params);
    } else {
        KernelTemplate<MODEL_TYPE, NUM_HEADS, false>::run_fixed_split(params);
    }
}

}
