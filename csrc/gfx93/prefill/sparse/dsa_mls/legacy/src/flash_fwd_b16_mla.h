#pragma once
#include "block_info.h"
#include "kernel_traits.h"
#include "splitkv.h"
#include "params.h"
#include "wait.h"
#include "fwd/utils.h"

// DSA MLS h64 sparse prefill/decode implementation.
// This file intentionally keeps only the gfx938 h64 path used by dsa_mls/launch.h.

#include "mla/gfx938/mla_qk_gemm_prefetch_v_mls_ds.h"
#include "mla/gfx938/mla_qk_gemm_utils_mls_ds.h"
#include "mla/gfx938/mla_pv_gemm_prefetch_k_mls_ds.h"
#include "mla/gfx938/mla_pv_gemm_utils_mls_ds.h"
#include "mla/gfx938/mla_softmax_gfx938.h"
#include "mla/gfx938/mla_epilogue_tile16x32_lit.h"

namespace flash {

template<const int stride, typename T>
__device__ __forceinline__ vec4_uint tcp_cache_swizzle_func(const T* ptr) {
    vec4_uint res;
    *(uint64_t*)&res = reinterpret_cast<uint64_t>(ptr);
    if constexpr (stride == 256) {
        res[1] += 0x42000000;
    } else if constexpr (stride == 196) {
        res[1] += 0x41800000;
    } else if constexpr (stride == 128) {
        res[1] += 0x41000000;
    } else if constexpr (stride == 64) {
        res[1] += 0x40800000;
    }
    res[2] = 0x80000000;
    res[3] = 0x00020000;
    return res;
}

template<typename Kernel_traits, bool Is_training, bool Is_dropout, bool Is_prefix, bool Is_causal, bool Is_even_MN, bool Is_even_K, bool Return_softmax, bool Is_MTP, int Layout, bool Topk2048, typename Params>
__forceinline__ __device__ void flash_mla_dsa_prefill_h64_body(const Params params) {
#if defined(__gfx938__)
    using Element           = typename Kernel_traits::Element;
    using ElementAccum      = typename Kernel_traits::ElementAccum;
    using index_t           = typename Kernel_traits::index_t;
    constexpr int kBlockM   = Kernel_traits::kBlockM;
    constexpr int kBlockN   = Kernel_traits::kBlockN;
    constexpr int kBlockK   = Kernel_traits::kBlockK;
    constexpr int kHeadDim  = Kernel_traits::kHeadDim;
    constexpr int kHeadDimV = Kernel_traits::kHeadDimV;
    constexpr int kNWarps   = Kernel_traits::kNWarps;
    constexpr int WARP_M    = Kernel_traits::kWaveM;
    constexpr int WARP_N    = Kernel_traits::kWaveN;
    constexpr int STAGES    = Kernel_traits::STAGES;
    constexpr int WARP_NUM  = kBlockM / WARP_M;

    {
        const int bidh = blockIdx.y;
        const int bidb = blockIdx.z;
        int warp_id_vec = threadIdx.x / 64;
        const int warp_id = __builtin_amdgcn_readfirstlane(warp_id_vec);
        const int m_block = blockIdx.x;

        constexpr bool Is_FlashMLA = !Is_prefix;

        int actual_seqlen_q = params.seqlen_q;
        int actual_seqlen_k = params.partition_size;

        if (m_block * kBlockM >= actual_seqlen_q || actual_seqlen_k <= 0) return;
        const int warp_offset_in_seq_q = m_block * kBlockM + warp_id * WARP_M;
        const int warp_seqq_limit      = Is_even_MN ? 0: actual_seqlen_q - m_block * kBlockM;

        extern __shared__ Element smem[];
        Element* q_lds = (Element*)&(smem);                     // 16KB
        Element* k_lds = q_lds; // 16KB
        Element* v_lds = q_lds;
        int* index_lds = (int *)(q_lds + 8 * 1024);

        const int linear_q_start = m_block * kBlockM;
        const int query_idx = linear_q_start / params.ngroups;
        const int q_head_start = linear_q_start - query_idx * params.ngroups;
        int real_topk;
        if constexpr (Topk2048) {
            real_topk = 2048;
        } else {
            real_topk = params.topk_length ? params.topk_length[query_idx] : params.topk;
        }
        const int n_block_min = 0;
        int n_block_max;
        if constexpr (Topk2048) {
            n_block_max = 2048 / kBlockN;
        } else {
            n_block_max = ceil_div(real_topk, kBlockN);
        }
        int seqlen_q_stride = params.q_head_stride;
        int seqlen_k_stride = params.k_row_stride;
        int seqlen_v_stride = params.v_row_stride;
        int seqlen_o_stride = params.o_head_stride;
        int seqlen_qv_stride = params.qv_row_stride;

        int row_offset_q, row_offset_k, row_offset_v, row_offset_o, row_offset_lse, row_offset_qv;
        int headdim_split_id = 0;

        int *index_ptr;
        if constexpr (Topk2048) {
            index_ptr = params.sparse_indices
                + bidb * params.sparse_indices_batch_stride
                + query_idx * params.sparse_indices_row_stride
                + (q_head_start / params.ngroups) * params.sparse_indices_head_stride;
        } else {
            index_ptr = params.sparse_indices
                + bidb * params.sparse_indices_batch_stride
                + query_idx * params.sparse_indices_row_stride
                + (q_head_start / params.ngroups) * params.sparse_indices_head_stride;
        }
        row_offset_q   = bidb * int64_t(params.q_batch_stride) + query_idx * int64_t(params.q_token_stride) + q_head_start * int64_t(params.q_head_stride);
        row_offset_k   = 0;
        row_offset_v   = 0;
        row_offset_o   = bidb * int64_t(params.o_batch_stride) + query_idx * int64_t(params.o_row_stride) + q_head_start * int64_t(params.o_head_stride);
        row_offset_lse = bidb * params.seqlen_q + m_block * kBlockM;

        vec4_uint qv_ptr;
        auto q_ptr = prepare_for_matrix_load<kHeadDim>(reinterpret_cast<Element*>(params.q_ptr) + row_offset_q);
        if constexpr (!Is_FlashMLA)
            qv_ptr = prepare_for_matrix_load<kHeadDim>(reinterpret_cast<Element*>(params.qv_ptr) + row_offset_qv);
        auto k_ptr = prepare_for_matrix_load<kHeadDim>(reinterpret_cast<Element*>(params.k_ptr) + row_offset_k);
        auto k_ptr_buffer = tcp_cache_swizzle_func<64, Element>(reinterpret_cast<Element*>(params.k_ptr) + row_offset_k);
        auto v_ptr = prepare_for_matrix_load<kHeadDimV>(reinterpret_cast<Element*>(params.v_ptr) + row_offset_v);
        auto v_ptr_buffer = tcp_cache_swizzle_func<64, Element>(reinterpret_cast<Element*>(params.v_ptr) + row_offset_v);
        auto index_ptr_buffer = tcp_cache_swizzle_func<0, int>(reinterpret_cast<int*>(index_ptr));
        auto k_base_ptr = reinterpret_cast<Element*>(params.k_ptr) + row_offset_k;
        auto v_base_ptr = reinterpret_cast<Element*>(params.v_ptr) + row_offset_v;
        constexpr int n_masking_steps = 1;

        int tid = threadIdx.x % 64;
        if constexpr (Topk2048) {
            int lds_offset = __builtin_amdgcn_readfirstlane(warp_id * 4 * 64);
            int g_offset_v = tid * 4;
            int g_offset_s = warp_id * 256;
            inline_buffer_load_dwordx4_lds(index_lds, index_ptr_buffer, lds_offset, g_offset_s, g_offset_v);
        }

        constexpr bool PREFETCH_K = (Is_even_MN) and( ( kHeadDim == 512 and kHeadDimV == 512 ));
        constexpr bool ALLOW_PREFETCH = (STAGES > 1);
        if constexpr (PREFETCH_K and ALLOW_PREFETCH) {
            if (n_block_min < n_block_max - n_masking_steps) {
                prefetch_q_to_lds_mls_ds_576_512<kHeadDim, kBlockM, kBlockK, WARP_M, Element, Is_even_MN>(q_ptr, q_lds, warp_id, seqlen_q_stride, Is_even_MN ? 0: actual_seqlen_q - m_block * kBlockM);
                prefetch_k_to_lds_mls_ds_576_512<kHeadDim, kBlockN, kBlockK, WARP_NUM, WARP_N, Element, Is_even_MN>(k_ptr, k_lds, warp_id, seqlen_k_stride, Is_even_MN ? 0: actual_seqlen_k - n_block_min * kBlockN);
            }
        }

        vec_Accum<ElementAccum> scores_max[WARP_M / 16];
        vec_Accum<ElementAccum> scores_sum[WARP_M / 16];
        vec4_Accum<ElementAccum> acc_o[(kHeadDimV / kBlockK) * (WARP_M / 16) * (kBlockK / 32)][2];

        {
            constexpr int K_LOOP_COUNT = kHeadDimV / kBlockK;
            constexpr int M_WARP_COUNT = WARP_M / 16;
            constexpr int K_WARP_COUNT = kBlockK / 32;
            constexpr int M_MMAC_COUNT = 1;

            #pragma unroll
            for (int i = 0; i < M_WARP_COUNT; ++i) {
                scores_max[i].f32[0] = -INFINITY;
                scores_sum[i].f32[0] = 0;
            }

            #pragma unroll
            for (int i = 0; i < K_LOOP_COUNT * M_WARP_COUNT * K_WARP_COUNT; ++i) {
                #pragma unroll
                for (int min_tile_m = 0; min_tile_m < M_MMAC_COUNT; ++min_tile_m) {
                    #pragma unroll
                    for (int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                        acc_o[i][min_tile_n].f32[0] = 0;
                        acc_o[i][min_tile_n].f32[1] = 0;
                        acc_o[i][min_tile_n].f32[2] = 0;
                        acc_o[i][min_tile_n].f32[3] = 0;
                    }
                }
            }
        }

        union_vec4_f16x2<Element> q_reg[(WARP_M * 64) / (16 * 64) * (kHeadDim / kBlockK)];

        auto qk_load_q = &qk_mla_dsa_h64_load_q_d576<kHeadDim, kHeadDimV, kBlockM, kBlockN, 64, WARP_M, WARP_N, STAGES, Element, ElementAccum, Is_even_MN, Is_FlashMLA>;

        prefetch_q_to_lds_mls_ds_576_512<kHeadDim, kBlockM, 64, WARP_M, Element, Is_even_MN>(q_ptr, q_lds, warp_id, seqlen_q_stride, warp_seqq_limit);

        qk_load_q(q_ptr, q_ptr, k_ptr_buffer, v_ptr_buffer, q_lds, k_lds, v_lds, q_reg, warp_id, seqlen_qv_stride, seqlen_q_stride, seqlen_k_stride, seqlen_v_stride, index_ptr, params.k_batch_stride, params.v_batch_stride, warp_seqq_limit);

        auto qk_indexed = &qk_mla_dsa_h64_decode_indexed_d576<kHeadDim, kHeadDimV, kBlockM, kBlockN, 64, WARP_M, WARP_N, STAGES, Element, ElementAccum, Is_even_MN, Is_FlashMLA>;
        auto pv_gemm = &pv_gemm_prefetch_k_mls_ds_576_512<PREFETCH_K, kHeadDim, kHeadDimV, kBlockM, kBlockK, kBlockN, WARP_M, kBlockK, STAGES, Element, ElementAccum, Is_even_MN>;
        auto pv_indexed = &pv_mla_dsa_h64_indexed_d576<false, kHeadDim, kHeadDimV, kBlockM, 256, kBlockN, WARP_M, 256, STAGES, Element, ElementAccum, Is_even_MN>;

        constexpr int kIndexChunkSize = 1024;
        constexpr int kIndexBlocksPerChunk = kIndexChunkSize / kBlockN;

        for (int index_block_base = 0; index_block_base < n_block_max; index_block_base += kIndexBlocksPerChunk) {
            const int index_base = index_block_base * kBlockN;
            if constexpr (Topk2048) {
                flash::wait_all_warp_arrived();
                if (index_block_base == kIndexBlocksPerChunk) {
                    int lds_offset = __builtin_amdgcn_readfirstlane(warp_id * 4 * 64);
                    int g_offset_v = tid * 4;
                    int g_offset_s = 1024 + warp_id * 256;
                    inline_buffer_load_dwordx4_lds(index_lds, index_ptr_buffer, lds_offset, g_offset_s, g_offset_v);
                }
                flash::wait_buffer_data_arrived<true>(0);
            } else {
                int lds_offset = __builtin_amdgcn_readfirstlane(warp_id * 4 * 64);
                int g_offset_v = tid * 4;
                int g_offset_s = index_base + warp_id * 256;
                flash::wait_all_warp_arrived();
                inline_buffer_load_dwordx4_lds(index_lds, index_ptr_buffer, lds_offset, g_offset_s, g_offset_v);
                flash::wait_buffer_data_arrived<true>(0);
            }

            int index_offset = warp_id * 256 + tid * 4;
            #pragma unroll
            for (int i = 0; i < 4; ++i) {
                const int local_index = index_offset + i;
                const int global_index = index_base + local_index;
                int index_value = index_lds[local_index];
                index_lds[local_index] = (global_index >= real_topk || index_value < 0 || index_value >= params.seqlen_k) ? -1 : index_value;
            }
            flash::wait_all_warp_arrived();

            const int index_block_end = (n_block_max < index_block_base + kIndexBlocksPerChunk) ? n_block_max : index_block_base + kIndexBlocksPerChunk;

            for (int n_block_loop = index_block_base; n_block_loop < index_block_end; ++n_block_loop) {

                int warp_offset_in_seqkv = n_block_loop * kBlockN;
                int warp_seqkv_limit     = Is_even_MN ? 0: actual_seqlen_k - warp_offset_in_seqkv;
                int n_loop_real          = n_block_loop - index_block_base;

                vec4_Accum<ElementAccum> s_reg[(WARP_M / 16) * (kBlockN / 32)][2];

                if constexpr (Is_FlashMLA) {
                    if constexpr (kHeadDim == 576) {
                        qk_mla_dsa_h64_prefill_indexed_d576<kHeadDim, kHeadDimV, kBlockM, kBlockN, 64, WARP_M, WARP_N, STAGES, Element, ElementAccum, Is_even_MN, Is_FlashMLA>(
                            q_ptr /* q576 */, q_ptr /* q576 */, k_ptr_buffer /* k576 */, v_base_ptr /* v512 */, q_lds, k_lds, v_lds, q_reg, s_reg, warp_id, seqlen_qv_stride, seqlen_q_stride, seqlen_k_stride, seqlen_v_stride, index_lds, params.k_batch_stride, params.v_batch_stride, params.page_block_size, n_loop_real, warp_seqq_limit, warp_seqkv_limit);
                    } else {
                        qk_indexed(q_ptr /* q576 */, q_ptr /* q576 */, k_ptr_buffer /* k576 */, v_base_ptr /* v512 */, q_lds, k_lds, v_lds, q_reg, s_reg, warp_id, seqlen_qv_stride, seqlen_q_stride, seqlen_k_stride, seqlen_v_stride, index_lds, params.k_batch_stride, params.v_batch_stride, params.page_block_size, n_loop_real, warp_seqq_limit, warp_seqkv_limit);
                    }
                } else {
                }

            if constexpr (!Is_causal) {
                    prefill_dsa_apply_mask_gfx938<vec4_Accum<ElementAccum>, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, index_lds, warp_offset_in_seqkv, real_topk);
                } else {
                        if constexpr (Is_MTP) {
                            if constexpr (Is_FlashMLA) {
                                flashmla_apply_mtp_mask_causal_gfx938<vec4_Accum<ElementAccum>, kBlockN, WARP_M, WARP_NUM>(s_reg, warp_offset_in_seqkv/* n_block_loop * kBlockN */, actual_seqlen_k, warp_offset_in_seq_q/* m_block * kBlockM + warp_id_row * 16 */, actual_seqlen_q, params.ngroups, params.mtp);
                            } else {
                                prefill_mla_apply_mtp_mask_causal_gfx938<vec4_Accum<ElementAccum>, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, warp_offset_in_seqkv, actual_seqlen_k, warp_offset_in_seq_q, actual_seqlen_q);
                            }
                        } else {
                            prefill_mla_apply_mask_causal_gfx938<vec4_Accum<ElementAccum>, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, warp_offset_in_seqkv, actual_seqlen_k, warp_offset_in_seq_q, actual_seqlen_q);
                        }
                }

                prefill_mla_softmax_rescale_o<false, Is_causal, vec4_Accum<ElementAccum>, vec_Accum<ElementAccum>, kHeadDimV, kBlockK, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, scores_max, scores_sum, acc_o, params.scale_softmax_log2);

                union_vec2_f16x2<Element> p_reg[(WARP_M / 16) * (kBlockN / 32)][2];
                prefill_mla_convert_pk_type<WARP_M, kBlockN, Element, ElementAccum, 1/* M_MMAC_COUNT */>(p_reg, s_reg);

                pv_indexed(k_base_ptr, k_ptr, v_ptr_buffer, q_lds, k_lds, v_lds, p_reg, acc_o, warp_id, seqlen_q_stride, seqlen_k_stride, seqlen_v_stride, index_lds, params.v_batch_stride, params.page_block_size, n_loop_real, warp_seqq_limit, warp_seqkv_limit);

            }
        }

        vec_Accum<ElementAccum> lse[WARP_M / 16];
        if constexpr (Topk2048) {
            prefill_mla_epilugue_rescale_acco<WARP_M, kBlockK, kHeadDimV, Is_dropout && Is_training, ElementAccum, vec_Accum<ElementAccum>, 1/* M_MMAC_COUNT */>(acc_o, lse, scores_max, scores_sum, params.scale_softmax, 0/* params.rp_dropout */);
        } else {
            prefill_dsa_epilugue_rescale_acco<WARP_M, kBlockK, kHeadDimV, Is_dropout && Is_training, ElementAccum, vec_Accum<ElementAccum>, 1/* M_MMAC_COUNT */>(
                acc_o, lse, scores_max, scores_sum, params.scale_softmax, 0/* params.rp_dropout */,
                params.attn_sink == nullptr ? nullptr : params.attn_sink + q_head_start);
        }
        constexpr bool Is_Interleave = true;
        int lane_id = threadIdx.x & 63;
        if (params.softmax_lse_ptr != nullptr) {
            prefill_mla_epilogue_store_lse<WARP_M, Is_even_MN, false/*SplitD*/, Is_Interleave, ElementAccum, vec_Accum<ElementAccum>, 1/* M_MMAC_COUNT */>(lse, params.softmax_lse_ptr, row_offset_lse, warp_id, lane_id, 0, actual_seqlen_q - m_block * kBlockM);
        }
        Element* o_ptr = reinterpret_cast<Element *>(params.o_ptr) + row_offset_o;
        prefill_mla_epilogue_store_output<kHeadDimV, kBlockM, kBlockK, WARP_M, Is_even_MN, Is_Interleave, false/*TcpSwizzle*/, Element, ElementAccum, 1/* M_MMAC_COUNT */>(o_ptr, acc_o, m_block, warp_id, lane_id, seqlen_o_stride, actual_seqlen_q);
    }
#endif
}

template<typename Kernel_traits, bool Is_training, bool Is_dropout, bool Is_prefix, bool Is_causal, bool Is_even_MN, bool Is_even_K, bool Return_softmax, bool Is_MTP, int Layout, bool NeedIndexGuard, typename Params>
__global__ void __launch_bounds__(256, 1) flash_mla_dsa_prefill_h64_topk2048_fast_kernel(const Params params) {
#if defined(__gfx938__)
    using Element           = typename Kernel_traits::Element;
    using ElementAccum      = typename Kernel_traits::ElementAccum;
    using index_t           = typename Kernel_traits::index_t;
    constexpr int kBlockM   = Kernel_traits::kBlockM;
    constexpr int kBlockN   = Kernel_traits::kBlockN;
    constexpr int kBlockK   = Kernel_traits::kBlockK;
    constexpr int kHeadDim  = Kernel_traits::kHeadDim;
    constexpr int kHeadDimV = Kernel_traits::kHeadDimV;
    constexpr int kNWarps   = Kernel_traits::kNWarps;
    constexpr int WARP_M    = Kernel_traits::kWaveM;
    constexpr int WARP_N    = Kernel_traits::kWaveN;
    constexpr int STAGES    = Kernel_traits::STAGES;
    constexpr int WARP_NUM  = kBlockM / WARP_M;

    {
        const int bidh = blockIdx.y;
        const int bidb = blockIdx.z;
        int warp_id_vec = threadIdx.x / 64;
        const int warp_id = __builtin_amdgcn_readfirstlane(warp_id_vec);
        const int m_block = blockIdx.x;

        // Is_FlashMLA为true则无qv，为False则有qv，适配FA3和FlashMLA接口
        constexpr bool Is_FlashMLA = !Is_prefix;

        // 获取当前任务的长度
        int sum_s_q = Is_FlashMLA ? 0: params.max_seqlen;
        int actual_seqlen_q = params.seqlen_q;
        int actual_seqlen_k = 2048;

        // 处理边界
        if (m_block * kBlockM >= actual_seqlen_q) return;
        const int warp_offset_in_seq_q = m_block * kBlockM + warp_id * WARP_M;
        const int warp_seqq_limit      = Is_even_MN ? 0: actual_seqlen_q - m_block * kBlockM;

        extern __shared__ Element smem[];
        Element* q_lds = (Element*)&(smem);                     // 16KB
        Element* k_lds = q_lds; // 16KB
        Element* v_lds = q_lds;
        int* index_lds = (int *)(q_lds + 8 * 1024);
        const int linear_q_start = m_block * kBlockM;
        const int query_idx = linear_q_start / params.ngroups;
        const int q_head_start = linear_q_start - query_idx * params.ngroups;
        constexpr int real_topk = 2048;
        const int n_block_min = 0;
        int n_block_max = real_topk / kBlockN;

        // 计算数据跨度
        int seqlen_q_stride = params.q_head_stride;
        int seqlen_k_stride = params.k_row_stride;
        int seqlen_v_stride = params.v_row_stride;
        int seqlen_o_stride = params.o_head_stride;
        int seqlen_qv_stride = params.qv_row_stride;    // 当走FlashMLA接口时，不会使用

        int64_t row_offset_q, row_offset_k, row_offset_v, row_offset_o, row_offset_lse, row_offset_qv;
        int headdim_split_id = 0;

        int *index_ptr = params.sparse_indices
            + bidb * params.sparse_indices_batch_stride
            + query_idx * params.sparse_indices_row_stride
            + (q_head_start / params.ngroups) * params.sparse_indices_head_stride;

        row_offset_q   = bidb * int64_t(params.q_batch_stride) + query_idx * int64_t(params.q_token_stride) + q_head_start * int64_t(params.q_head_stride);
        row_offset_k   = 0;
        row_offset_v   = 0;
        row_offset_o   = bidb * int64_t(params.o_batch_stride) + query_idx * int64_t(params.o_row_stride) + q_head_start * int64_t(params.o_head_stride);
        row_offset_lse = bidb * params.seqlen_q + m_block * kBlockM;

        vec4_uint qv_ptr;
        auto q_ptr = prepare_for_matrix_load<kHeadDim>(reinterpret_cast<Element*>(params.q_ptr) + row_offset_q);
        if constexpr (!Is_FlashMLA)
            qv_ptr = prepare_for_matrix_load<kHeadDim>(reinterpret_cast<Element*>(params.qv_ptr) + row_offset_qv);
        auto k_ptr = prepare_for_matrix_load<kHeadDim>(reinterpret_cast<Element*>(params.k_ptr) + row_offset_k);
        auto k_ptr_buffer = tcp_cache_swizzle_func<64, Element>(reinterpret_cast<Element*>(params.k_ptr) + row_offset_k);
        auto v_ptr = prepare_for_matrix_load<kHeadDimV>(reinterpret_cast<Element*>(params.v_ptr) + row_offset_v);
        auto v_ptr_buffer = tcp_cache_swizzle_func<64, Element>(reinterpret_cast<Element*>(params.v_ptr) + row_offset_v);
        auto index_ptr_buffer = tcp_cache_swizzle_func<0, int>(reinterpret_cast<int*>(index_ptr));
        auto k_base_ptr = reinterpret_cast<Element*>(params.k_ptr) + row_offset_k;
        auto v_base_ptr = reinterpret_cast<Element*>(params.v_ptr) + row_offset_v;
        constexpr int n_masking_steps = 1;

        int tid = threadIdx.x % 64;
        int lds_offset = __builtin_amdgcn_readfirstlane(warp_id * 4 * 64);
        int g_offset_v = tid * 4;
        int g_offset_s = warp_id * 256;
        inline_buffer_load_dwordx4_lds(index_lds, index_ptr_buffer, lds_offset, g_offset_s, g_offset_v);
        int fallback_index = 0;
        if constexpr (NeedIndexGuard) {
            flash::wait_buffer_data_arrived<true>(0);
            int index_offset = warp_id * 256 + tid * 4;
            #pragma unroll
            for (int i = 0; i < 4; ++i) {
                const int local_index = index_offset + i;
                int index_value = index_lds[local_index];
                index_lds[local_index] = (index_value < 0 || index_value >= params.seqlen_k) ? -1 : index_value;
            }
            flash::wait_all_warp_arrived();

            int fallback_index_v = index_lds[0];
            fallback_index = __builtin_amdgcn_readfirstlane(fallback_index_v);

            if (fallback_index < 0 || fallback_index >= params.seqlen_k) {
                return;
            }
        }

        constexpr bool PREFETCH_K = (Is_even_MN) and( ( kHeadDim == 576 and kHeadDimV == 512 ));
        constexpr bool ALLOW_PREFETCH = (STAGES > 1);
        if constexpr (PREFETCH_K and ALLOW_PREFETCH) {
            if (n_block_min < n_block_max - n_masking_steps) {
                prefetch_q_to_lds_mls_ds_576_512<kHeadDim, kBlockM, kBlockK, WARP_M, Element, Is_even_MN>(q_ptr, q_lds, warp_id, seqlen_q_stride, Is_even_MN ? 0: actual_seqlen_q - m_block * kBlockM);
                prefetch_k_to_lds_mls_ds_576_512<kHeadDim, kBlockN, kBlockK, WARP_NUM, WARP_N, Element, Is_even_MN>(k_ptr, k_lds, warp_id, seqlen_k_stride, Is_even_MN ? 0: actual_seqlen_k - n_block_min * kBlockN);
            }
        }

        vec_Accum<ElementAccum> scores_max[WARP_M / 16];
        vec_Accum<ElementAccum> scores_sum[WARP_M / 16];
        vec4_Accum<ElementAccum> acc_o[(kHeadDimV / kBlockK) * (WARP_M / 16) * (kBlockK / 32)][2];

        {
            constexpr int K_LOOP_COUNT = kHeadDimV / kBlockK;
            constexpr int M_WARP_COUNT = WARP_M / 16;
            constexpr int K_WARP_COUNT = kBlockK / 32;
            constexpr int M_MMAC_COUNT = 1;

            #pragma unroll
            for (int i = 0; i < M_WARP_COUNT; ++i) {
                scores_max[i].f32[0] = -INFINITY;
                scores_sum[i].f32[0] = 0;
            }

            #pragma unroll
            for (int i = 0; i < K_LOOP_COUNT * M_WARP_COUNT * K_WARP_COUNT; ++i) {
                #pragma unroll
                for (int min_tile_m = 0; min_tile_m < M_MMAC_COUNT; ++min_tile_m) {
                    #pragma unroll
                    for (int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                        acc_o[i][min_tile_n].f32[0] = 0;
                        acc_o[i][min_tile_n].f32[1] = 0;
                        acc_o[i][min_tile_n].f32[2] = 0;
                        acc_o[i][min_tile_n].f32[3] = 0;
                    }
                }
            }
        }

        union_vec4_f16x2<Element> q_reg[(WARP_M * 64) / (16 * 64) * (kHeadDim / kBlockK)];

        auto qk_load_q = &qk_mla_dsa_h64_load_q_d576<kHeadDim, kHeadDimV, kBlockM, kBlockN, 64, WARP_M, WARP_N, STAGES, Element, ElementAccum, Is_even_MN, Is_FlashMLA>;

        prefetch_q_to_lds_mls_ds_576_512<kHeadDim, kBlockM, 64, WARP_M, Element, Is_even_MN>(q_ptr, q_lds, warp_id, seqlen_q_stride, warp_seqq_limit);

        qk_load_q(q_ptr, q_ptr, k_ptr_buffer, v_ptr_buffer, q_lds, k_lds, v_lds, q_reg, warp_id, seqlen_qv_stride, seqlen_q_stride, seqlen_k_stride, seqlen_v_stride, index_ptr, params.k_batch_stride, params.v_batch_stride, warp_seqq_limit);

        auto qk_indexed = &qk_mla_dsa_h64_topk2048_fast_d576<NeedIndexGuard, kHeadDim, kHeadDimV, kBlockM, kBlockN, 64, WARP_M, WARP_N, STAGES, Element, ElementAccum, Is_even_MN, Is_FlashMLA>;
        auto pv_indexed = &pv_mla_dsa_h64_topk2048_fast_d576<NeedIndexGuard, false, kHeadDim, kHeadDimV, kBlockM, 256, kBlockN, WARP_M, 256, STAGES, Element, ElementAccum, Is_even_MN>;

        for (int n_block_loop = n_block_min; n_block_loop < 16; ++n_block_loop) {

            int warp_offset_in_seqkv = n_block_loop * kBlockN;
            int warp_seqkv_limit     = Is_even_MN ? 0: actual_seqlen_k - warp_offset_in_seqkv;

            vec4_Accum<ElementAccum> s_reg[(WARP_M / 16) * (kBlockN / 32)][2];

            if constexpr (Is_FlashMLA) {
                qk_indexed(q_ptr, q_ptr, k_ptr_buffer, v_base_ptr, q_lds, k_lds, v_lds, q_reg, s_reg, warp_id, seqlen_qv_stride, seqlen_q_stride, seqlen_k_stride, seqlen_v_stride, index_lds, fallback_index, params.k_batch_stride, params.v_batch_stride, n_block_loop, warp_seqq_limit, warp_seqkv_limit);
            }

            if constexpr (NeedIndexGuard) {
                prefill_dsa_apply_mask_gfx938<vec4_Accum<ElementAccum>, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, index_lds, warp_offset_in_seqkv, real_topk);
            }

            prefill_mla_softmax_rescale_o<false, Is_causal, vec4_Accum<ElementAccum>, vec_Accum<ElementAccum>, kHeadDimV, kBlockK, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, scores_max, scores_sum, acc_o, params.scale_softmax_log2);

            union_vec2_f16x2<Element> p_reg[(WARP_M / 16) * (kBlockN / 32)][2];
            prefill_mla_convert_pk_type<WARP_M, kBlockN, Element, ElementAccum, 1/* M_MMAC_COUNT */>(p_reg, s_reg);

            pv_indexed(k_base_ptr, k_ptr, v_ptr_buffer, q_lds, k_lds, v_lds, p_reg, acc_o, warp_id, seqlen_q_stride, seqlen_k_stride, seqlen_v_stride, index_lds, fallback_index, params.v_batch_stride, n_block_loop, warp_seqq_limit, warp_seqkv_limit);
        }

        lds_offset = __builtin_amdgcn_readfirstlane(warp_id * 4 * 64);
        g_offset_v = tid * 4;
        g_offset_s = 1024 + warp_id * 256;
        inline_buffer_load_dwordx4_lds(index_lds, index_ptr_buffer, lds_offset, g_offset_s, g_offset_v);
        flash::wait_buffer_data_arrived<true>(0);
        if constexpr (NeedIndexGuard) {
            int index_offset = warp_id * 256 + tid * 4;
            #pragma unroll
            for (int i = 0; i < 4; ++i) {
                const int local_index = index_offset + i;
                int index_value = index_lds[local_index];
                index_lds[local_index] = (index_value < 0 || index_value >= params.seqlen_k) ? -1 : index_value;
            }
            flash::wait_all_warp_arrived();
        }

        for (int n_block_loop = 16; n_block_loop < n_block_max; ++n_block_loop) {

            int warp_offset_in_seqkv = n_block_loop * kBlockN;
            int warp_seqkv_limit     = Is_even_MN ? 0: actual_seqlen_k - warp_offset_in_seqkv;
            int n_loop_real = n_block_loop - 16;

            vec4_Accum<ElementAccum> s_reg[(WARP_M / 16) * (kBlockN / 32)][2];

            if constexpr (Is_FlashMLA) {
                qk_indexed(q_ptr, q_ptr, k_ptr_buffer, v_base_ptr, q_lds, k_lds, v_lds, q_reg, s_reg, warp_id, seqlen_qv_stride, seqlen_q_stride, seqlen_k_stride, seqlen_v_stride, index_lds, fallback_index, params.k_batch_stride, params.v_batch_stride, n_loop_real, warp_seqq_limit, warp_seqkv_limit);
            }

            if constexpr (NeedIndexGuard) {
                prefill_dsa_apply_mask_gfx938<vec4_Accum<ElementAccum>, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, index_lds, warp_offset_in_seqkv, real_topk);
            }

            prefill_mla_softmax_rescale_o<false, Is_causal, vec4_Accum<ElementAccum>, vec_Accum<ElementAccum>, kHeadDimV, kBlockK, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, scores_max, scores_sum, acc_o, params.scale_softmax_log2);

            union_vec2_f16x2<Element> p_reg[(WARP_M / 16) * (kBlockN / 32)][2];
            prefill_mla_convert_pk_type<WARP_M, kBlockN, Element, ElementAccum, 1/* M_MMAC_COUNT */>(p_reg, s_reg);

            pv_indexed(k_base_ptr, k_ptr, v_ptr_buffer, q_lds, k_lds, v_lds, p_reg, acc_o, warp_id, seqlen_q_stride, seqlen_k_stride, seqlen_v_stride, index_lds, fallback_index, params.v_batch_stride, n_loop_real, warp_seqq_limit, warp_seqkv_limit);
        }

        vec_Accum<ElementAccum> lse[WARP_M / 16];
        prefill_mla_epilugue_rescale_acco<WARP_M, kBlockK, kHeadDimV, Is_dropout && Is_training, ElementAccum, vec_Accum<ElementAccum>, 1/* M_MMAC_COUNT */>(acc_o, lse, scores_max, scores_sum, params.scale_softmax, 0/* params.rp_dropout */);

        constexpr bool Is_Interleave = true;
        int lane_id = threadIdx.x & 63;
        if (params.softmax_lse_ptr != nullptr) {
            prefill_mla_epilogue_store_lse<WARP_M, Is_even_MN, false/*SplitD*/, Is_Interleave, ElementAccum, vec_Accum<ElementAccum>, 1/* M_MMAC_COUNT */>(lse, params.softmax_lse_ptr, row_offset_lse, warp_id, lane_id, 0, actual_seqlen_q - m_block * kBlockM);
        }

        Element* o_ptr = reinterpret_cast<Element *>(params.o_ptr) + row_offset_o;
        prefill_mla_epilogue_store_output<kHeadDimV, kBlockM, kBlockK, WARP_M, Is_even_MN, Is_Interleave, false/*TcpSwizzle*/, Element, ElementAccum, 1/* M_MMAC_COUNT */>(o_ptr, acc_o, m_block, warp_id, lane_id, seqlen_o_stride, actual_seqlen_q);
    }
#endif
}


template<typename Kernel_traits, bool Is_training, bool Is_dropout, bool Is_prefix, bool Is_causal, bool Is_even_MN, bool Is_even_K, bool Return_softmax, bool Is_MTP, int Layout, typename Params>
__global__ void __launch_bounds__(256, 1) flash_mla_dsa_prefill_h64_kernel(const Params params) {
    flash_mla_dsa_prefill_h64_body<Kernel_traits, Is_training, Is_dropout, Is_prefix, Is_causal, Is_even_MN, Is_even_K, Return_softmax, Is_MTP, Layout, true, Params>(params);
}

template<typename Kernel_traits, bool Is_training, bool Is_dropout, bool Is_prefix, bool Is_causal, bool Is_even_MN, bool Is_even_K, bool Return_softmax, bool Is_MTP, int Layout, typename Params>
__global__ void __launch_bounds__(256, 1) flash_mla_dsa_prefill_h64_topk1024_kernel(const Params params) {
    flash_mla_dsa_prefill_h64_body<Kernel_traits, Is_training, Is_dropout, Is_prefix, Is_causal, Is_even_MN, Is_even_K, Return_softmax, Is_MTP, Layout, false, Params>(params);
}

template<typename Kernel_traits, bool Is_training, bool Is_dropout, bool Is_prefix, bool Is_causal, bool Is_even_MN, bool Is_even_K, bool Return_softmax, bool Is_MTP, int Layout, bool DecodeCLoad, bool Has_extra, typename Params>
__global__ void __launch_bounds__(256, 1) flash_mla_dsa_decode_h64_kernel(const Params params) {
#if defined(__gfx938__)
    using Element           = typename Kernel_traits::Element;
    using ElementAccum      = typename Kernel_traits::ElementAccum;
    using index_t           = typename Kernel_traits::index_t;
    constexpr int kBlockM   = Kernel_traits::kBlockM;
    constexpr int kBlockN   = Kernel_traits::kBlockN;
    constexpr int kBlockK   = Kernel_traits::kBlockK;
    constexpr int kHeadDim  = Kernel_traits::kHeadDim;
    constexpr int kHeadDimV = Kernel_traits::kHeadDimV;
    constexpr int kNWarps   = Kernel_traits::kNWarps;
    constexpr int WARP_M    = Kernel_traits::kWaveM;
    constexpr int WARP_N    = Kernel_traits::kWaveN;
    constexpr int STAGES    = Kernel_traits::STAGES;
    constexpr int WARP_NUM  = kBlockM / WARP_M;

    {
        const int bidh = blockIdx.y;
        const int bidb = blockIdx.z;
        int warp_id_vec = threadIdx.x / 64;
        const int warp_id = __builtin_amdgcn_readfirstlane(warp_id_vec);
        const int m_block = blockIdx.x;

        constexpr bool Is_FlashMLA = !Is_prefix;

        int actual_seqlen_q = params.seqlen_q;
        int actual_seqlen_k = params.partition_size;

        if (m_block * kBlockM >= actual_seqlen_q || actual_seqlen_k <= 0) return;
        const int warp_offset_in_seq_q = m_block * kBlockM + warp_id * WARP_M;
        const int warp_seqq_limit      = Is_even_MN ? 0: actual_seqlen_q - m_block * kBlockM;

        extern __shared__ Element smem[];
        Element* q_lds = (Element*)&(smem);                     // 16KB
        Element* k_lds = q_lds; // 16KB
        Element* v_lds = q_lds;
        int* index_lds = (int *)(q_lds + 8 * 1024);
        int* extra_index_lds = (int *)(index_lds + 256);

        const int linear_q_start = m_block * kBlockM;
        const int query_idx = linear_q_start / params.ngroups;
        const int q_head_start = linear_q_start - query_idx * params.ngroups;
        const int actual_block_m = min(kBlockM, params.ngroups - q_head_start);

        int main_topk_length = params.topk_length ? params.topk_length[bidb] : params.topk;
        int extra_topk_length = params.extra_topk_length ? params.extra_topk_length[bidb] : params.extra_topk;

        int main_num_blocks = ceil_div(main_topk_length, kBlockN);
        int extra_num_blocks = Has_extra ? ceil_div(extra_topk_length, kBlockN) : 0;

        int seqlen_q_stride = params.q_head_stride;
        int seqlen_k_stride = params.k_row_stride;
        int seqlen_v_stride = params.v_row_stride;
        int seqlen_o_stride = params.o_head_stride;
        int seqlen_qv_stride = params.qv_row_stride;

        int row_offset_q, row_offset_k, row_offset_v, row_offset_o, row_offset_lse, row_offset_qv;

        int *index_ptr = params.sparse_indices
            + bidb * params.sparse_indices_batch_stride
            + query_idx * params.sparse_indices_row_stride
            + (q_head_start / params.ngroups) * params.sparse_indices_head_stride;
        int* extra_index_ptr = nullptr;
        if constexpr (Has_extra) {
            extra_index_ptr = params.extra_sparse_indices
                + bidb * params.extra_sparse_indices_batch_stride
                + query_idx * params.extra_sparse_indices_row_stride
                + (q_head_start / params.ngroups) * params.extra_sparse_indices_head_stride;
        }

        row_offset_q   = bidb * int64_t(params.q_batch_stride) + query_idx * int64_t(params.q_token_stride) + q_head_start * int64_t(params.q_head_stride);
        row_offset_k   = 0;
        row_offset_v   = 0;
        row_offset_o   = bidb * int64_t(params.o_batch_stride) + query_idx * int64_t(params.o_row_stride) + q_head_start * int64_t(params.o_head_stride);
        row_offset_lse = bidb * params.seqlen_q + m_block * kBlockM;

        vec4_uint qv_ptr;
        auto q_ptr = prepare_for_matrix_load<kHeadDim>(reinterpret_cast<Element*>(params.q_ptr) + row_offset_q);
        if constexpr (!Is_FlashMLA)
            qv_ptr = prepare_for_matrix_load<kHeadDim>(reinterpret_cast<Element*>(params.qv_ptr) + row_offset_qv);
        auto k_ptr = prepare_for_matrix_load<kHeadDim>(reinterpret_cast<Element*>(params.k_ptr) + row_offset_k);
        auto k_ptr_buffer = prepare_for_buffer_load_with_stride_bound(reinterpret_cast<Element*>(params.k_ptr) + row_offset_k, params.k_row_stride, params.seqlen_k);
        auto extra_k_ptr_buffer = prepare_for_buffer_load_with_stride_bound(
            reinterpret_cast<Element*>(Has_extra ? params.extra_k_ptr : params.k_ptr),
            Has_extra ? params.extra_k_row_stride : params.k_row_stride,
            Has_extra ? params.extra_seqlen_k : params.seqlen_k);
        auto v_ptr = prepare_for_matrix_load<kHeadDimV>(reinterpret_cast<Element*>(params.v_ptr) + row_offset_v);
        auto v_ptr_buffer = prepare_for_buffer_load_with_stride_bound(reinterpret_cast<Element*>(params.v_ptr) + row_offset_v, params.v_row_stride, params.seqlen_k);
        auto extra_v_ptr_buffer = prepare_for_buffer_load_with_stride_bound(
            reinterpret_cast<Element*>(Has_extra ? params.extra_v_ptr : params.v_ptr),
            Has_extra ? params.extra_v_row_stride : params.v_row_stride,
            Has_extra ? params.extra_seqlen_k : params.seqlen_k);
        auto index_ptr_buffer = tcp_cache_swizzle_func<0, int>(reinterpret_cast<int*>(index_ptr));
        int tid = threadIdx.x % 64;
        if constexpr (Has_extra) {
            auto extra_index_ptr_buffer = tcp_cache_swizzle_func<0, int>(extra_index_ptr);
            int lds_offset = __builtin_amdgcn_readfirstlane(warp_id * 4 * 64);
            int g_offset_v = tid * 4;
            int g_offset_s = warp_id * 256;
            inline_buffer_load_dwordx4_lds(extra_index_lds, extra_index_ptr_buffer, lds_offset, g_offset_s, g_offset_v);
        }
        auto k_base_ptr = reinterpret_cast<Element*>(params.k_ptr) + row_offset_k;
        auto v_base_ptr = reinterpret_cast<Element*>(params.v_ptr) + row_offset_v;
        auto extra_k_base_ptr = reinterpret_cast<Element*>(Has_extra ? params.extra_k_ptr : params.k_ptr);
        auto extra_v_base_ptr = reinterpret_cast<Element*>(Has_extra ? params.extra_v_ptr : params.v_ptr);

        int lds_offset = __builtin_amdgcn_readfirstlane(Has_extra ? warp_id * 64 : warp_id * 4 * 64);
        int g_offset_v = Has_extra ? tid : tid * 4;
        int g_offset_s = Has_extra ? warp_id * 64 : warp_id * 256;
        if constexpr (Has_extra) {
            inline_buffer_load_dword_lds(index_lds, index_ptr_buffer, lds_offset, g_offset_s, g_offset_v);
        } else {
            inline_buffer_load_dwordx4_lds(index_lds, index_ptr_buffer, lds_offset, g_offset_s, g_offset_v);
        }

        flash::wait_buffer_data_arrived<true>(0);
        flash::wait_all_warp_arrived();

        #pragma unroll
        for (int i = 0; i < 4; ++i) {
            const int local_index = Has_extra ? warp_id * 64 + tid : warp_id * 256 + tid * 4 + i;
            if (local_index >= main_topk_length) {
                index_lds[local_index] = main_topk_length > 0 ? index_lds[main_topk_length - 1] : -1;
            }
        }
        if constexpr (Has_extra) {
            #pragma unroll
            for (int i = 0; i < 4; ++i) {
                const int local_index = warp_id * 256 + tid * 4 + i;
                if (local_index >= extra_topk_length) {
                    extra_index_lds[local_index] = extra_topk_length > 0 ? extra_index_lds[extra_topk_length - 1] : -1;
                }
            }
        }
        flash::wait_all_warp_arrived();

        constexpr bool PREFETCH_K = (Is_even_MN) and( ( kHeadDim == 512 and kHeadDimV == 512 ));
        constexpr bool ALLOW_PREFETCH = (STAGES > 1);

        vec_Accum<ElementAccum> scores_max[WARP_M / 16];
        vec_Accum<ElementAccum> scores_sum[WARP_M / 16];
        vec4_Accum<ElementAccum> acc_o[(kHeadDimV / kBlockK) * (WARP_M / 16) * (kBlockK / 32)][2];

        {
            constexpr int K_LOOP_COUNT = kHeadDimV / kBlockK;
            constexpr int M_WARP_COUNT = WARP_M / 16;
            constexpr int K_WARP_COUNT = kBlockK / 32;
            constexpr int M_MMAC_COUNT = 1;

            #pragma unroll
            for (int i = 0; i < M_WARP_COUNT; ++i) {
                scores_max[i].f32[0] = -INFINITY;
                scores_sum[i].f32[0] = 0;
            }

            #pragma unroll
            for (int i = 0; i < K_LOOP_COUNT * M_WARP_COUNT * K_WARP_COUNT; ++i) {
                #pragma unroll
                for (int min_tile_m = 0; min_tile_m < M_MMAC_COUNT; ++min_tile_m) {
                    #pragma unroll
                    for (int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                        acc_o[i][min_tile_n].f32[0] = 0;
                        acc_o[i][min_tile_n].f32[1] = 0;
                        acc_o[i][min_tile_n].f32[2] = 0;
                        acc_o[i][min_tile_n].f32[3] = 0;
                    }
                }
            }
        }

        union_vec4_f16x2<Element> q_reg[(WARP_M * 64) / (16 * 64) * (kHeadDim / kBlockK)];

        auto qk_load_q = &qk_mla_dsa_h64_load_q_d576<kHeadDim, kHeadDimV, kBlockM, kBlockN, 64, WARP_M, WARP_N, STAGES, Element, ElementAccum, Is_even_MN, Is_FlashMLA>;

        prefetch_q_to_lds_mls_ds_576_512<kHeadDim, kBlockM, 64, WARP_M, Element, Is_even_MN>(q_ptr, q_lds, warp_id, seqlen_q_stride, warp_seqq_limit);

        qk_load_q(q_ptr /* q576 */, q_ptr /* q576 */, k_ptr_buffer /* k576 */, v_ptr_buffer /* v512 */, q_lds, k_lds, v_lds, q_reg, warp_id, seqlen_qv_stride, seqlen_q_stride, seqlen_k_stride, seqlen_v_stride, index_ptr, params.k_batch_stride, params.v_batch_stride, warp_seqq_limit);

        auto qk_indexed = &qk_mla_dsa_h64_decode_indexed_d576<kHeadDim, kHeadDimV, kBlockM, kBlockN, 64, WARP_M, WARP_N, STAGES, Element, ElementAccum, Is_even_MN, Is_FlashMLA, DecodeCLoad>;
        auto pv_indexed = &pv_mla_dsa_h64_indexed_d576<false, kHeadDim, kHeadDimV, kBlockM, 256, kBlockN, WARP_M, 256, STAGES, Element, ElementAccum, Is_even_MN, DecodeCLoad>;

        for (int n_block_loop = 0; n_block_loop < main_num_blocks; ++n_block_loop) {

            int warp_offset_in_seqkv = n_block_loop * kBlockN;
            int warp_seqkv_limit     = Is_even_MN ? 0: actual_seqlen_k - warp_offset_in_seqkv;

            vec4_Accum<ElementAccum> s_reg[(WARP_M / 16) * (kBlockN / 32)][2];

            if constexpr (Is_FlashMLA) {
                if constexpr (kHeadDim == 576) {
                    qk_mla_dsa_h64_splitkv_indexed_d576<kHeadDim, kHeadDimV, kBlockM, kBlockN, 64, WARP_M, WARP_N, STAGES, Element, ElementAccum, Is_even_MN, Is_FlashMLA>(
                        q_ptr, q_ptr, k_ptr_buffer, v_base_ptr, q_lds, k_lds, v_lds, q_reg, s_reg, warp_id, seqlen_qv_stride, seqlen_q_stride, seqlen_k_stride, seqlen_v_stride, index_lds, params.k_batch_stride, params.v_batch_stride, params.page_block_size, n_block_loop, warp_seqq_limit, warp_seqkv_limit);
                } else {
                    qk_indexed(q_ptr, q_ptr, k_ptr_buffer, k_base_ptr, q_lds, k_lds, v_lds, q_reg, s_reg, warp_id, seqlen_qv_stride, seqlen_q_stride, seqlen_k_stride, seqlen_v_stride, index_lds, params.k_batch_stride, params.v_batch_stride, params.page_block_size, n_block_loop, warp_seqq_limit, warp_seqkv_limit);
                }
            }

            if constexpr (!Is_causal) {
                decode_dsa_apply_mask_gfx938<vec4_Accum<ElementAccum>, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, index_lds, warp_offset_in_seqkv,main_topk_length);
            } else {
                    if constexpr (Is_MTP) {
                        if constexpr (Is_FlashMLA) {
                            flashmla_apply_mtp_mask_causal_gfx938<vec4_Accum<ElementAccum>, kBlockN, WARP_M, WARP_NUM>(s_reg, warp_offset_in_seqkv, actual_seqlen_k, warp_offset_in_seq_q, actual_seqlen_q, params.ngroups, params.mtp);
                        } else {
                            prefill_mla_apply_mtp_mask_causal_gfx938<vec4_Accum<ElementAccum>, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, warp_offset_in_seqkv, actual_seqlen_k, warp_offset_in_seq_q, actual_seqlen_q);
                        }
                    } else {
                        prefill_mla_apply_mask_causal_gfx938<vec4_Accum<ElementAccum>, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, warp_offset_in_seqkv, actual_seqlen_k, warp_offset_in_seq_q, actual_seqlen_q);
                    }
            }

            prefill_mla_softmax_rescale_o<false, Is_causal, vec4_Accum<ElementAccum>, vec_Accum<ElementAccum>, kHeadDimV, kBlockK, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, scores_max, scores_sum, acc_o, params.scale_softmax_log2);

            union_vec2_f16x2<Element> p_reg[(WARP_M / 16) * (kBlockN / 32)][2];
            prefill_mla_convert_pk_type<WARP_M, kBlockN, Element, ElementAccum, 1/* M_MMAC_COUNT */>(p_reg, s_reg);

            pv_indexed(v_base_ptr, k_ptr, v_ptr_buffer, q_lds, k_lds, v_lds, p_reg, acc_o, warp_id, seqlen_q_stride, seqlen_k_stride, seqlen_v_stride, index_lds, params.v_batch_stride, params.page_block_size, n_block_loop, warp_seqq_limit, warp_seqkv_limit);

        }

        for (int n_block_loop = 0; n_block_loop < extra_num_blocks; ++n_block_loop) {

            int warp_offset_in_seqkv = n_block_loop * kBlockN;
            int warp_seqkv_limit     = Is_even_MN ? 0: actual_seqlen_k - warp_offset_in_seqkv;

            vec4_Accum<ElementAccum> s_reg[(WARP_M / 16) * (kBlockN / 32)][2];

            if constexpr (Is_FlashMLA) {
                qk_indexed(q_ptr, q_ptr, extra_k_ptr_buffer, extra_k_base_ptr, q_lds, k_lds, v_lds, q_reg, s_reg, warp_id, seqlen_qv_stride, seqlen_q_stride, params.extra_k_row_stride, params.extra_v_row_stride, extra_index_lds, params.extra_k_batch_stride, params.extra_v_batch_stride, params.extra_page_block_size, n_block_loop, warp_seqq_limit, warp_seqkv_limit);
            }

            if constexpr (!Is_causal) {
                decode_dsa_apply_mask_gfx938<vec4_Accum<ElementAccum>, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, extra_index_lds, warp_offset_in_seqkv,extra_topk_length);
            } else {
                    if constexpr (Is_MTP) {
                        if constexpr (Is_FlashMLA) {
                            flashmla_apply_mtp_mask_causal_gfx938<vec4_Accum<ElementAccum>, kBlockN, WARP_M, WARP_NUM>(s_reg, warp_offset_in_seqkv, actual_seqlen_k, warp_offset_in_seq_q, actual_seqlen_q, params.ngroups, params.mtp);
                        } else {
                            prefill_mla_apply_mtp_mask_causal_gfx938<vec4_Accum<ElementAccum>, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, warp_offset_in_seqkv, actual_seqlen_k, warp_offset_in_seq_q, actual_seqlen_q);
                        }
                    } else {
                        prefill_mla_apply_mask_causal_gfx938<vec4_Accum<ElementAccum>, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, warp_offset_in_seqkv, actual_seqlen_k, warp_offset_in_seq_q, actual_seqlen_q);
                    }
            }

            prefill_mla_softmax_rescale_o<false, Is_causal, vec4_Accum<ElementAccum>, vec_Accum<ElementAccum>, kHeadDimV, kBlockK, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, scores_max, scores_sum, acc_o, params.scale_softmax_log2);

            union_vec2_f16x2<Element> p_reg[(WARP_M / 16) * (kBlockN / 32)][2];
            prefill_mla_convert_pk_type<WARP_M, kBlockN, Element, ElementAccum, 1/* M_MMAC_COUNT */>(p_reg, s_reg);

            pv_indexed(extra_v_base_ptr, k_ptr, extra_v_ptr_buffer, q_lds, k_lds, v_lds, p_reg, acc_o, warp_id, seqlen_q_stride, params.extra_k_row_stride, params.extra_v_row_stride, extra_index_lds, params.extra_v_batch_stride, params.extra_page_block_size, n_block_loop, warp_seqq_limit, warp_seqkv_limit);

        }

        vec_Accum<ElementAccum> lse[WARP_M / 16];
        decode_dsa_epilugue_rescale_acco<WARP_M, kBlockK, kHeadDimV, Is_dropout && Is_training, ElementAccum, vec_Accum<ElementAccum>, 1/* M_MMAC_COUNT */>(
            acc_o, lse, scores_max, scores_sum, params.scale_softmax, 0/* params.rp_dropout */,
            params.attn_sink == nullptr ? nullptr : params.attn_sink + q_head_start);

        constexpr bool Is_Interleave = true;
        int lane_id = threadIdx.x & 63;
        if (params.softmax_lse_ptr != nullptr) {
            prefill_mla_epilogue_store_lse<WARP_M, Is_even_MN, false/*SplitD*/, Is_Interleave, ElementAccum, vec_Accum<ElementAccum>, 1/* M_MMAC_COUNT */>(lse, params.softmax_lse_ptr, row_offset_lse, warp_id, lane_id, 0, actual_block_m);
        }

        Element* o_ptr = reinterpret_cast<Element *>(params.o_ptr) + row_offset_o;
        prefill_mla_epilogue_store_output<kHeadDimV, kBlockM, kBlockK, WARP_M, Is_even_MN, Is_Interleave, false/*TcpSwizzle*/, Element, ElementAccum, 1/* M_MMAC_COUNT */>(o_ptr, acc_o, 0, warp_id, lane_id, seqlen_o_stride, actual_block_m);
    }
#endif
}

template<typename Kernel_traits, bool Is_training, bool Is_dropout, bool Is_prefix, bool Is_causal, bool Is_even_MN, bool Is_even_K, bool Return_softmax, bool Is_MTP, int Layout, bool Has_extra, bool DecodeCLoad, bool DirectOutput, typename Params>
__device__ __forceinline__ void flash_mla_dsa_decode_h64_splitkv_body(
    const Params params,
    const int bidb,
    const int split_id,
    const int m_block,
    const int n_block_min_override,
    const int n_block_max_override,
    const int64_t accum_split_idx) {
#if defined(__gfx938__)
    using Element           = typename Kernel_traits::Element;
    using ElementAccum      = typename Kernel_traits::ElementAccum;
    using index_t           = typename Kernel_traits::index_t;
    constexpr int kBlockM   = Kernel_traits::kBlockM;
    constexpr int kBlockN   = Kernel_traits::kBlockN;
    constexpr int kBlockK   = Kernel_traits::kBlockK;
    constexpr int kHeadDim  = Kernel_traits::kHeadDim;
    constexpr int kHeadDimV = Kernel_traits::kHeadDimV;
    constexpr int kNWarps   = Kernel_traits::kNWarps;
    constexpr int WARP_M    = Kernel_traits::kWaveM;
    constexpr int WARP_N    = Kernel_traits::kWaveN;
    constexpr int STAGES    = Kernel_traits::STAGES;
    constexpr int WARP_NUM  = kBlockM / WARP_M;

    {
        int warp_id_vec = threadIdx.x / 64;
        const int warp_id = __builtin_amdgcn_readfirstlane(warp_id_vec);

        constexpr bool Is_FlashMLA = !Is_prefix;

        int sum_s_q = Is_FlashMLA ? 0: params.max_seqlen;
        int actual_seqlen_q = params.seqlen_q;
        int actual_seqlen_k = params.partition_size;

        if (m_block * kBlockM >= actual_seqlen_q || actual_seqlen_k <= 0) return;
        const int warp_offset_in_seq_q = m_block * kBlockM + warp_id * WARP_M;
        const int warp_seqq_limit      = Is_even_MN ? 0: actual_seqlen_q - m_block * kBlockM;

        constexpr bool has_extra = Has_extra;
        extern __shared__ Element smem[];
        Element* q_lds = (Element*)&(smem);
        Element* k_lds = q_lds;
        Element* v_lds = q_lds;
        int* index_lds = (int *)(q_lds + 8 * 1024);
        constexpr int kIndexChunk = 1024;
        constexpr int kIndexChunkBlocks = kIndexChunk / kBlockN;
        const int linear_q_start = m_block * kBlockM;
        const int query_idx = linear_q_start / params.ngroups;
        const int q_head_start = linear_q_start - query_idx * params.ngroups;
        const int actual_block_m = min(kBlockM, params.ngroups - q_head_start);

        int main_topk_length = params.topk_length ? params.topk_length[bidb] : params.topk;
        int extra_topk_length = params.extra_topk_length ? params.extra_topk_length[bidb] : params.extra_topk;

        int main_num_blocks = ceil_div(main_topk_length, kBlockN);
        int extra_num_blocks = Has_extra ? ceil_div(extra_topk_length, kBlockN) : 0;
        int total_num_blocks = main_num_blocks + extra_num_blocks;

        int n_block_min;
        int n_block_max;
        if (n_block_min_override >= 0) {
            n_block_min = n_block_min_override;
            n_block_max = min(n_block_max_override, total_num_blocks);
        } else {
            int blocks_per_split = ceil_div(params.partition_size, kBlockN);
            n_block_min = split_id * blocks_per_split;
            n_block_max = min(n_block_min + blocks_per_split, total_num_blocks);
        }

        int seqlen_q_stride = params.q_head_stride;
        int seqlen_k_stride = params.k_row_stride;
        int seqlen_v_stride = params.v_row_stride;
        int seqlen_o_stride = params.o_head_stride;
        int seqlen_qv_stride = params.qv_row_stride;

        int row_offset_q, row_offset_k, row_offset_v, row_offset_o, row_offset_lse, row_offset_qv;
        int headdim_split_id = 0;

        int *index_ptr = params.sparse_indices
            + bidb * params.sparse_indices_batch_stride
            + query_idx * params.sparse_indices_row_stride
            + (q_head_start / params.ngroups) * params.sparse_indices_head_stride;
        int* extra_index_ptr = nullptr;
        if constexpr (Has_extra) {
            extra_index_ptr = params.extra_sparse_indices
                + bidb * params.extra_sparse_indices_batch_stride
                + query_idx * params.extra_sparse_indices_row_stride
                + (q_head_start / params.ngroups) * params.extra_sparse_indices_head_stride;
        }

        row_offset_q   = bidb * int64_t(params.q_batch_stride) + query_idx * int64_t(params.q_token_stride) + q_head_start * int64_t(params.q_head_stride);
        row_offset_k   = 0;
        row_offset_v   = 0;
        row_offset_o   = bidb * int64_t(params.o_batch_stride) + query_idx * int64_t(params.o_row_stride) + q_head_start * int64_t(params.o_head_stride);
        row_offset_lse = bidb * params.seqlen_q + m_block * kBlockM;
        const int official_q_idx = query_idx;
        const int official_h_idx = q_head_start;
        const int64_t official_split_idx = accum_split_idx;
        const int64_t official_accum_row_offset = (official_split_idx * params.max_seqlen * params.ngroups
            + official_q_idx * params.ngroups + official_h_idx) * kHeadDimV;
        const int64_t official_lse_row_offset = official_split_idx * params.max_seqlen * params.ngroups
            + official_q_idx * params.ngroups + official_h_idx;

        vec4_uint qv_ptr;
        auto q_ptr = prepare_for_matrix_load<kHeadDim>(reinterpret_cast<Element*>(params.q_ptr) + row_offset_q);
        if constexpr (!Is_FlashMLA)
            qv_ptr = prepare_for_matrix_load<kHeadDim>(reinterpret_cast<Element*>(params.qv_ptr) + row_offset_qv);
        auto k_ptr = prepare_for_matrix_load<kHeadDim>(reinterpret_cast<Element*>(params.k_ptr) + row_offset_k);
        auto k_ptr_buffer = prepare_for_buffer_load_with_stride_bound(reinterpret_cast<Element*>(params.k_ptr) + row_offset_k, params.k_row_stride, params.seqlen_k);
        auto extra_k_ptr_buffer = prepare_for_buffer_load_with_stride_bound(
            reinterpret_cast<Element*>(Has_extra ? params.extra_k_ptr : params.k_ptr),
            Has_extra ? params.extra_k_row_stride : params.k_row_stride,
            Has_extra ? params.extra_seqlen_k : params.seqlen_k);
        auto v_ptr = prepare_for_matrix_load<kHeadDimV>(reinterpret_cast<Element*>(params.v_ptr) + row_offset_v);
        auto v_ptr_buffer = prepare_for_buffer_load_with_stride_bound(reinterpret_cast<Element*>(params.v_ptr) + row_offset_v, params.v_row_stride, params.seqlen_k);
        auto extra_v_ptr_buffer = prepare_for_buffer_load_with_stride_bound(
            reinterpret_cast<Element*>(Has_extra ? params.extra_v_ptr : params.v_ptr),
            Has_extra ? params.extra_v_row_stride : params.v_row_stride,
            Has_extra ? params.extra_seqlen_k : params.seqlen_k);
        int tid = threadIdx.x % 64;
        auto k_base_ptr = reinterpret_cast<Element*>(params.k_ptr) + row_offset_k;
        auto v_base_ptr = reinterpret_cast<Element*>(params.v_ptr) + row_offset_v;
        constexpr int n_masking_steps = 1;

        constexpr bool PREFETCH_K = (Is_even_MN) and( ( kHeadDim == 512 and kHeadDimV == 512 ));
        constexpr bool ALLOW_PREFETCH = (STAGES > 1);

        vec_Accum<ElementAccum> scores_max[WARP_M / 16];
        vec_Accum<ElementAccum> scores_sum[WARP_M / 16];
        vec4_Accum<ElementAccum> acc_o[(kHeadDimV / kBlockK) * (WARP_M / 16) * (kBlockK / 32)][2];

        {
            constexpr int K_LOOP_COUNT = kHeadDimV / kBlockK;
            constexpr int M_WARP_COUNT = WARP_M / 16;
            constexpr int K_WARP_COUNT = kBlockK / 32;
            constexpr int M_MMAC_COUNT = 1;

            #pragma unroll
            for (int i = 0; i < M_WARP_COUNT; ++i) {
                scores_max[i].f32[0] = -INFINITY;
                scores_sum[i].f32[0] = 0;
            }

            #pragma unroll
            for (int i = 0; i < K_LOOP_COUNT * M_WARP_COUNT * K_WARP_COUNT; ++i) {
                #pragma unroll
                for (int min_tile_m = 0; min_tile_m < M_MMAC_COUNT; ++min_tile_m) {
                    #pragma unroll
                    for (int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                        acc_o[i][min_tile_n].f32[0] = 0;
                        acc_o[i][min_tile_n].f32[1] = 0;
                        acc_o[i][min_tile_n].f32[2] = 0;
                        acc_o[i][min_tile_n].f32[3] = 0;
                    }
                }
            }
        }

        union_vec4_f16x2<Element> q_reg[(WARP_M * 64) / (16 * 64) * (kHeadDim / kBlockK)];

        auto qk_load_q = &qk_mla_dsa_h64_load_q_d576<kHeadDim, kHeadDimV, kBlockM, kBlockN, 64, WARP_M, WARP_N, STAGES, Element, ElementAccum, Is_even_MN, Is_FlashMLA>;

        prefetch_q_to_lds_mls_ds_576_512<kHeadDim, kBlockM, 64, WARP_M, Element, Is_even_MN>(q_ptr, q_lds, warp_id, seqlen_q_stride, warp_seqq_limit);

        qk_load_q(q_ptr, q_ptr, k_ptr_buffer, v_ptr_buffer, q_lds, k_lds, v_lds, q_reg, warp_id, seqlen_qv_stride, seqlen_q_stride, seqlen_k_stride, seqlen_v_stride, index_ptr, params.k_batch_stride, params.v_batch_stride, warp_seqq_limit);

        auto qk_indexed = &qk_mla_dsa_h64_decode_indexed_d576<kHeadDim, kHeadDimV, kBlockM, kBlockN, 64, WARP_M, WARP_N, STAGES, Element, ElementAccum, Is_even_MN, Is_FlashMLA, DecodeCLoad>;
        auto pv_indexed = &pv_mla_dsa_h64_indexed_d576<false, kHeadDim, kHeadDimV, kBlockM, 256, kBlockN, WARP_M, 256, STAGES, Element, ElementAccum, Is_even_MN, DecodeCLoad>;

        int logical_chunk_start = n_block_min;
        while (logical_chunk_start < n_block_max) {
            const bool chunk_is_extra = Has_extra && logical_chunk_start >= main_num_blocks;
            const int chunk_base = chunk_is_extra ? main_num_blocks : 0;
            const int chunk_rel_block_start = ((logical_chunk_start - chunk_base) / kIndexChunkBlocks) * kIndexChunkBlocks;
            const int chunk_topk_length = chunk_is_extra ? extra_topk_length : main_topk_length;
            const int chunk_index_width = chunk_is_extra ? params.extra_topk : params.topk;
            int* chunk_index_ptr = chunk_is_extra ? extra_index_ptr : index_ptr;
            auto chunk_index_ptr_buffer = tcp_cache_swizzle_func<0, int>(chunk_index_ptr + chunk_rel_block_start * kBlockN);

            #pragma unroll
            for (int index_load_iter = 0; index_load_iter < 4; ++index_load_iter) {
                const int local_index_base = index_load_iter * 256 + warp_id * 64;
                const int global_index_base = chunk_rel_block_start * kBlockN + local_index_base;
                if (global_index_base < chunk_index_width) {
                    int lds_offset = __builtin_amdgcn_readfirstlane(local_index_base);
                    int g_offset_v = tid;
                    int g_offset_s = local_index_base;
                    inline_buffer_load_dword_lds(index_lds, chunk_index_ptr_buffer, lds_offset, g_offset_s, g_offset_v);
                }
            }
            flash::wait_buffer_data_arrived<true>(0);
            flash::wait_all_warp_arrived();

            #pragma unroll
            for (int i = 0; i < 4; ++i) {
                const int local_index = warp_id * 256 + tid * 4 + i;
                const int global_index = chunk_rel_block_start * kBlockN + local_index;
                if (global_index >= chunk_topk_length) {
                    index_lds[local_index] = -1;
                }
            }
            const int logical_chunk_aligned_end = chunk_base + chunk_rel_block_start + kIndexChunkBlocks;
            const int logical_side_end = chunk_is_extra ? total_num_blocks : main_num_blocks;
            const int chunk_block_end = min(min(n_block_max, logical_chunk_aligned_end), logical_side_end);
            for (int logical_block = logical_chunk_start; logical_block < chunk_block_end; ++logical_block) {
                int rel_block = chunk_is_extra ? logical_block - main_num_blocks : logical_block;
                int rel_block_in_chunk = rel_block - chunk_rel_block_start;
                int cur_topk_length = chunk_is_extra ? extra_topk_length : main_topk_length;
                auto cur_k_ptr_buffer = chunk_is_extra ? extra_k_ptr_buffer : k_ptr_buffer;
                auto cur_v_ptr_buffer = chunk_is_extra ? extra_v_ptr_buffer : v_ptr_buffer;
                int cur_seqlen_k_stride = chunk_is_extra ? params.extra_k_row_stride : seqlen_k_stride;
                int cur_seqlen_v_stride = chunk_is_extra ? params.extra_v_row_stride : seqlen_v_stride;
                int cur_k_batch_stride = chunk_is_extra ? params.extra_k_batch_stride : params.k_batch_stride;
                int cur_v_batch_stride = chunk_is_extra ? params.extra_v_batch_stride : params.v_batch_stride;
                int cur_page_block_size = chunk_is_extra ? params.extra_page_block_size : params.page_block_size;
                int warp_offset_in_seqkv = rel_block * kBlockN;
                int warp_offset_in_chunk = rel_block_in_chunk * kBlockN;
                int chunk_real_topk = cur_topk_length - chunk_rel_block_start * kBlockN;
                int warp_seqkv_limit = Is_even_MN ? 0 : cur_topk_length - warp_offset_in_seqkv;

            vec4_Accum<ElementAccum> s_reg[(WARP_M / 16) * (kBlockN / 32)][2];

            if constexpr (Is_FlashMLA) {
                if constexpr (kHeadDim == 576) {
                    qk_mla_dsa_h64_splitkv_indexed_d576<kHeadDim, kHeadDimV, kBlockM, kBlockN, 64, WARP_M, WARP_N, STAGES, Element, ElementAccum, Is_even_MN, Is_FlashMLA>(
                        q_ptr, q_ptr, cur_k_ptr_buffer, v_base_ptr, q_lds, k_lds, v_lds, q_reg, s_reg, warp_id, seqlen_qv_stride, seqlen_q_stride, cur_seqlen_k_stride, cur_seqlen_v_stride, index_lds, cur_k_batch_stride, cur_v_batch_stride, cur_page_block_size, rel_block_in_chunk, warp_seqq_limit, warp_seqkv_limit);
                } else {
                    Element* cur_k_ptr_raw = reinterpret_cast<Element*>(chunk_is_extra ? params.extra_k_ptr : params.k_ptr);
                    qk_indexed(q_ptr, q_ptr, cur_k_ptr_buffer, cur_k_ptr_raw, q_lds, k_lds, v_lds, q_reg, s_reg, warp_id, seqlen_qv_stride, seqlen_q_stride, cur_seqlen_k_stride, cur_seqlen_v_stride, index_lds, cur_k_batch_stride, cur_v_batch_stride, cur_page_block_size, rel_block_in_chunk, warp_seqq_limit, warp_seqkv_limit);
                }
            }

            if constexpr (!Is_causal) {
                decode_dsa_apply_mask_gfx938<vec4_Accum<ElementAccum>, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, index_lds, warp_offset_in_chunk, cur_topk_length);
            } else {
                    if constexpr (Is_MTP) {
                        if constexpr (Is_FlashMLA) {
                            flashmla_apply_mtp_mask_causal_gfx938<vec4_Accum<ElementAccum>, kBlockN, WARP_M, WARP_NUM>(s_reg, warp_offset_in_seqkv, actual_seqlen_k, warp_offset_in_seq_q, actual_seqlen_q, params.ngroups, params.mtp);
                        } else {
                            prefill_mla_apply_mtp_mask_causal_gfx938<vec4_Accum<ElementAccum>, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, warp_offset_in_seqkv, actual_seqlen_k, warp_offset_in_seq_q, actual_seqlen_q);
                        }
                    } else {
                        prefill_mla_apply_mask_causal_gfx938<vec4_Accum<ElementAccum>, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, warp_offset_in_seqkv, actual_seqlen_k, warp_offset_in_seq_q, actual_seqlen_q);
                    }
            }

            prefill_mla_softmax_rescale_o<false, true, vec4_Accum<ElementAccum>, vec_Accum<ElementAccum>, kHeadDimV, kBlockK, WARP_M, kBlockN, 1/* M_MMAC_COUNT */>(s_reg, scores_max, scores_sum, acc_o, params.scale_softmax_log2);

            union_vec2_f16x2<Element> p_reg[(WARP_M / 16) * (kBlockN / 32)][2];
            prefill_mla_convert_pk_type<WARP_M, kBlockN, Element, ElementAccum, 1/* M_MMAC_COUNT */>(p_reg, s_reg);

            Element* cur_v_ptr_raw = reinterpret_cast<Element*>(chunk_is_extra ? params.extra_v_ptr : params.v_ptr);
            pv_indexed(cur_v_ptr_raw, k_ptr, cur_v_ptr_buffer, q_lds, k_lds, v_lds, p_reg, acc_o, warp_id, seqlen_q_stride, cur_seqlen_k_stride, cur_seqlen_v_stride, index_lds, cur_v_batch_stride, cur_page_block_size, rel_block_in_chunk, warp_seqq_limit, warp_seqkv_limit);

            }
            logical_chunk_start = chunk_block_end;
        }

        vec_Accum<ElementAccum> lse[WARP_M / 16];
        if constexpr (DirectOutput) {
            decode_dsa_epilugue_rescale_acco<WARP_M, kBlockK, kHeadDimV, Is_dropout && Is_training, ElementAccum, vec_Accum<ElementAccum>, 1/* M_MMAC_COUNT */>(
                acc_o, lse, scores_max, scores_sum, params.scale_softmax, 0/* params.rp_dropout */,
                params.attn_sink == nullptr ? nullptr : params.attn_sink + q_head_start);
        } else {
            prefill_mla_epilugue_rescale_acco<WARP_M, kBlockK, kHeadDimV, Is_dropout && Is_training, ElementAccum, vec_Accum<ElementAccum>, 1/* M_MMAC_COUNT */>(acc_o, lse, scores_max, scores_sum, params.scale_softmax, 0/* params.rp_dropout */);
        }

        constexpr bool Is_Interleave = true;
        int lane_id = threadIdx.x & 63;
        if (params.softmax_lse_ptr != nullptr) {
            const int lse_row_offset = DirectOutput ? row_offset_lse : official_lse_row_offset;
            prefill_mla_epilogue_store_lse<WARP_M, Is_even_MN, false/*SplitD*/, Is_Interleave, ElementAccum, vec_Accum<ElementAccum>, 1/* M_MMAC_COUNT */>(lse, params.softmax_lse_ptr, lse_row_offset, warp_id, lane_id, 0, actual_block_m);
        }

        if constexpr (DirectOutput) {
            Element* o_ptr = reinterpret_cast<Element *>(params.o_ptr) + row_offset_o;
            prefill_mla_epilogue_store_output<kHeadDimV, kBlockM, kBlockK, WARP_M, Is_even_MN, Is_Interleave, false/*TcpSwizzle*/, Element, ElementAccum, 1/* M_MMAC_COUNT */>(o_ptr, acc_o, 0, warp_id, lane_id, seqlen_o_stride, actual_block_m);
        } else {
            float* o_ptr = reinterpret_cast<float *>(params.oaccum_ptr) + official_accum_row_offset;
            prefill_mla_epilogue_store_output_fp32<kHeadDimV, kBlockM, kBlockK, WARP_M, Is_even_MN, ElementAccum, 1/* M_MMAC_COUNT */>(o_ptr, acc_o, 0, warp_id, lane_id, kHeadDimV, actual_block_m);
        }
    }
#endif
}

template<typename Kernel_traits, bool Is_training, bool Is_dropout, bool Is_prefix, bool Is_causal, bool Is_even_MN, bool Is_even_K, bool Return_softmax, bool Is_MTP, int Layout, bool DecodeCLoad, bool Has_extra, typename Params>
__global__ void __launch_bounds__(256, 1) flash_mla_dsa_decode_h64_splitkv_kernel(const Params params) {
#if defined(__gfx938__)
    const int bidb = blockIdx.z;
    const int split_id = blockIdx.y;
    const int m_block = blockIdx.x;
    const int64_t accum_split_idx = int64_t(bidb) * params.num_splits + split_id;
    flash_mla_dsa_decode_h64_splitkv_body<
        Kernel_traits, Is_training, Is_dropout, Is_prefix, Is_causal,
        Is_even_MN, Is_even_K, Return_softmax, Is_MTP, Layout, Has_extra, DecodeCLoad, false, Params>(
            params, bidb, split_id, m_block, -1, -1, accum_split_idx);
#endif
}

template<typename Kernel_traits, bool Is_training, bool Is_dropout, bool Is_prefix, bool Is_causal, bool Is_even_MN, bool Is_even_K, bool Return_softmax, bool Is_MTP, int Layout, bool DecodeCLoad, bool Has_extra, typename Params>
__global__ void __launch_bounds__(256, 1) flash_mla_dsa_decode_h64_splitkv_direct_kernel(const Params params) {
#if defined(__gfx938__)
    const int bidb = blockIdx.z;
    const int m_block = blockIdx.x;
    flash_mla_dsa_decode_h64_splitkv_body<
        Kernel_traits, Is_training, Is_dropout, Is_prefix, Is_causal,
        Is_even_MN, Is_even_K, Return_softmax, Is_MTP, Layout, Has_extra, DecodeCLoad, true, Params>(
            params, bidb, 0, m_block, 0, INT_MAX, bidb);
#endif
}

template<typename Kernel_traits, bool Is_training, bool Is_dropout, bool Is_prefix, bool Is_causal, bool Is_even_MN, bool Is_even_K, bool Return_softmax, bool Is_MTP, int Layout, bool DecodeCLoad, bool Has_extra, typename Params>
__global__ void __launch_bounds__(256, 1) flash_mla_dsa_decode_h64_splitkv_meta_kernel(const Params params) {
#if defined(__gfx938__)
    const int partition_idx = blockIdx.z;
    const int m_block = blockIdx.x;
    auto* metadata = reinterpret_cast<const DecodingSchedMeta*>(params.tile_scheduler_metadata_ptr);
    const DecodingSchedMeta sched_meta = metadata[partition_idx];
    if (sched_meta.begin_req_idx >= params.b) {
        return;
    }

    for (int bidb = sched_meta.begin_req_idx; bidb <= sched_meta.end_req_idx; ++bidb) {
        if (bidb > sched_meta.begin_req_idx) {
            __syncthreads();
        }
        const int n_block_min = bidb == sched_meta.begin_req_idx ? sched_meta.begin_block_idx : 0;
        const int n_block_max = bidb == sched_meta.end_req_idx ? sched_meta.end_block_idx : INT_MAX;
        const int split_id = bidb == sched_meta.begin_req_idx ? sched_meta.begin_split_idx : 0;
        const int64_t accum_split_idx = int64_t(__ldg(params.num_splits_ptr + bidb)) + split_id;
        flash_mla_dsa_decode_h64_splitkv_body<
            Kernel_traits, Is_training, Is_dropout, Is_prefix, Is_causal,
            Is_even_MN, Is_even_K, Return_softmax, Is_MTP, Layout, Has_extra, DecodeCLoad, false, Params>(
                params, bidb, split_id, m_block, n_block_min, n_block_max, accum_split_idx);
    }
#endif
}

} // namespace flash
