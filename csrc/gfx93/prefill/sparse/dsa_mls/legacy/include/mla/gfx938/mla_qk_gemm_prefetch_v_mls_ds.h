#pragma once
#include "mla_pv_gemm_utils_mls_ds.h"



template<int kHeadDim, int kHeadDimV, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, int STAGES, typename Element, typename ElementAccum, bool Is_even_MN, bool Is_FlashMLA>
__forceinline__ __device__ void qk_gemm_prefetch_v_mls_ds_576_512(
        vec4_uint qv_ptr,
        vec4_uint q_ptr,
        vec4_uint k_ptr,
        vec4_uint v_ptr,
        Element* q_lds,
        Element* k_lds,
        Element* v_lds,
        vec4_Accum<ElementAccum> s_reg[(WARP_M / 16) * (kBlockN / 32)][2],
        int warp_id,
        int seqlen_qv_stride,
        int __seqlen_q_stride,
        int seqlen_k_stride,
        int seqlen_v_stride,
        int* index_ptr,
        int* block_table,
        int batch_stride_k,
        int batch_stride_v,
        int page_block_size,
        int n_loop,
        int max_seq_q_offset=0,
        int max_seq_k_offset=0) {

    // Simplify
    static_assert (kBlockK == 32 and "To simplify, only kBlockK = 32 is supported!");
    static_assert (WARP_M == 16 and "To simplify, only WARP_M = 16 is supported!");
    static_assert (WARP_N == 64 and "To simplify, only WARP_N = 64 is supported!");
    constexpr int WARP_NUM        = kBlockM / WARP_M;
    constexpr int kHeadDim_OPT       = (kHeadDim == 576) ? 64 : kHeadDim;
    constexpr int Q_LDS_LOAD_NUM  = (kBlockM * kBlockK) / (16 * 32);
    constexpr int Q_LOAD_REQUESTS = Q_LDS_LOAD_NUM / WARP_NUM;
    constexpr int K_LDS_LOAD_NUM  = (kHeadDim_OPT * WARP_N) / (32 * 16);
    constexpr int K_LOAD_REQUESTS = K_LDS_LOAD_NUM / WARP_NUM;
    constexpr int ELEMENT_BYTES   = sizeof(Element);
    constexpr int WARP_NUM_M = 2; 
    constexpr int WARP_NUM_N = 4;
    int warp_id_m = warp_id / WARP_NUM_N;
    int warp_id_n = warp_id % WARP_NUM_N;

    __builtin_amdgcn_sched_barrier(0);
    if constexpr (kBlockN == 128) {
        inline_vgpr4_init_zero_4x4x4(s_reg);
    } else {
        for (int i = 0; i < (WARP_M / 16) * (kBlockN / 32); ++i) {
            for (int j = 0; j < 2; ++j) {
                s_reg[i][j].u64[0] = 0.0f;
                s_reg[i][j].u64[1] = 0.0f;
            }
        }
    }
    __builtin_amdgcn_sched_barrier(0);

    // 准备 q,k 寄存器
    union_vec4_f16x2<Element> q_reg[(WARP_M * kBlockK) / (16 * 32)];
    union_vec4_f16x2<Element> k_reg[STAGES * (32 * kBlockK) / (32 * 32) * 2];

    // 计算 q_lds,k_lds 的起始偏移量
    int q_lds_base = reinterpret_cast<size_t>(q_lds);
    int k_lds_base = reinterpret_cast<size_t>(k_lds);

    int tid = threadIdx.x % 64;
    // MLS
    vec4_uint q_srsrc;
    vec4_uint k_srsrc;

    q_srsrc[2] = __seqlen_q_stride;
    if constexpr (Is_FlashMLA) {
        k_srsrc[2] = seqlen_k_stride;
    } else {
        k_srsrc[2] = seqlen_v_stride;
    }
    
    q_srsrc[3] = 0; 
    k_srsrc[3] = 0;

    int q_stage_id = 0;
    int k_stage_id = 0;

    if constexpr (STAGES == 2) {
        q_stage_id ^= 1;
        k_stage_id ^= 1;
    }

    {   
        for(int k_loop = 1; k_loop < (kHeadDim / kBlockK); ++k_loop) {
            // k预取的标志位
            int k_even = ((k_loop & 1) == 0x0) ? 1 : 0;
            
            {
                uint64_t q_base_addr;
                int seqlen_q_stride;
                int kloop_true;
                if constexpr (Is_FlashMLA) {
                    q_srsrc[2] = __seqlen_q_stride;
                    q_base_addr = *(uint64_t*)&q_ptr;
                    seqlen_q_stride = __seqlen_q_stride;
                    kloop_true = k_loop;
                } else {
                    q_srsrc[2] = (k_loop >= 2) ? seqlen_qv_stride : __seqlen_q_stride;
                    q_base_addr = (k_loop >= 2) ? *(uint64_t*)&qv_ptr : *(uint64_t*)&q_ptr;
                    seqlen_q_stride = (k_loop >= 2) ? seqlen_qv_stride : __seqlen_q_stride;
                    kloop_true = (k_loop >= 2) ? (k_loop - 2) : (k_loop);
                }

                *(uint64_t*)&q_srsrc = VA_LIMIT_BITS(q_base_addr + (kloop_true * kBlockK + warp_id * 16 * seqlen_q_stride) * ELEMENT_BYTES);
                int nm_filter = inline_min_max<0,16>(16 * warp_id + 16 - max_seq_q_offset);
                q_srsrc[3] = max_seq_q_offset % kBlockM == 0 ? 0: nm_filter << 8;
                int lds_offset = (q_stage_id * kBlockM * kBlockK + warp_id * 16 * 32) * ELEMENT_BYTES;
                flash::wait_all_warp_arrived();
                inline_matrix_load_32x16_b16_lds_trans<0, 1>(q_lds, q_srsrc, lds_offset, 0);
                
                if (k_even) {
                    k_stage_id ^= 1;
                    int index_topk = index_ptr[n_loop * 64 + warp_id_n * 16 + (tid / 4)];
                    int lds_offset = __builtin_amdgcn_readfirstlane((k_stage_id * WARP_N * kHeadDim_OPT + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
                    int g_offset_v = ((k_loop) / 2) * kHeadDim_OPT * ELEMENT_BYTES / 4 + warp_id_m * 16 + ((4 - (tid / 8) % 4) * 4 + tid % 4 * 4) % 16 + block_table[index_topk/128] * batch_stride_k * ELEMENT_BYTES / 4 + (index_topk % 128) * seqlen_k_stride * ELEMENT_BYTES / 4;
                    flash::wait_all_warp_arrived();
                    inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset, 0, g_offset_v); 

                    // k_stage_id ^= 1;
                    // int nm_filter =  inline_min_max<0,16>(16 * warp_id_n + 16 - max_seq_k_offset);
                    // if constexpr (Is_FlashMLA) {
                    //     *(uint64_t*)&k_srsrc = VA_LIMIT_BITS(*(uint64_t*)&k_ptr + (warp_id_m * 32 + warp_id_n * 16 * seqlen_k_stride + ((k_loop) / 2) * kHeadDim_OPT) * ELEMENT_BYTES);
                    // } else {
                    //     *(uint64_t*)&k_srsrc = VA_LIMIT_BITS(*(uint64_t*)&k_ptr + (warp_id_m * 32 + warp_id_n * 16 * seqlen_v_stride + ((k_loop - 2) / 2) * kHeadDim_OPT) * ELEMENT_BYTES);
                    // }
                    // k_srsrc[3] = (max_seq_k_offset % kBlockN == 0x0 ? 0: nm_filter) << 8;
                    // int lds_offset = (k_stage_id * WARP_N * kHeadDim_OPT + warp_id * 32 * 16) * ELEMENT_BYTES;
                    // flash::wait_all_warp_arrived();
                    // inline_matrix_load_32x16_b16_lds_trans<0, 0>(k_lds, k_srsrc, lds_offset, 0);
                }
            }

            // 不对称MLS指令
            if (k_even) {
                flash::wait_buffer_data_arrived<true>(Q_LOAD_REQUESTS + K_LOAD_REQUESTS);
            } else {
                flash::wait_buffer_data_arrived<true>(Q_LOAD_REQUESTS);
            }
            
            q_stage_id ^= 1;

            // Q DS
            {
                int q_lds_load_offset = q_lds_base + (q_stage_id * kBlockM * kBlockK + warp_id * 16 * 32) * ELEMENT_BYTES;
                DS_READ_MATRIX_32X16_B16(q_lds_load_offset, q_reg[0].f16, true);  
            }

            k_stage_id ^= 1;
            int stage_id = 0;

            // K DS  
            {
                int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + k_even * 32 * 64 + 0 * 32 * 32) * ELEMENT_BYTES;
                DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
            }

            // K DS PRE
            stage_id ^= 1;
            {
                int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + k_even * 32 * 64 + 1 * 32 * 32) * ELEMENT_BYTES;
                DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
            }

            // Wait DS
            flash::wait_lds_data_arrived<false>(2);
            flash::raise_priority();

            // MMAC 
            stage_id ^= 1;
            { 
                int min_tile_n = 0;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[0].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            { 
                int min_tile_n = 1;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[0].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            flash::lower_priority();
            flash::wait_lds_data_arrived<false>(0);
            flash::raise_priority();
            stage_id ^= 1;
            { 
                int min_tile_n = 0;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[0].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            { 
                int min_tile_n = 1;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[0].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            flash::lower_priority();
            
        }
        
        constexpr int k_loop = kHeadDim / kBlockK; 
        constexpr int k_even = ((k_loop & 1) == 0x0) ? 1 : 0; 

        if constexpr (k_even) {
            k_stage_id ^= 1;
        }

        // 等回最后的q_panel
        flash::wait_buffer_data_arrived<true>(0);

        // Q DS
        q_stage_id ^= 1;
        {
            int q_lds_load_offset = q_lds_base + (q_stage_id * kBlockM * kBlockK + warp_id * 16 * 32) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X16_B16(q_lds_load_offset, q_reg[0].f16, true);  
        }

        // K DS  
        k_stage_id ^= 1;
        int stage_id = 0;
        {   
            int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + k_even * 32 * 64 + 0 * 32 * 32) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        }

        // K DS PRE
        stage_id ^= 1;
        {
            int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + k_even * 32 * 64 + 1 * 32 * 32) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        }

        // Wait DS
        flash::wait_lds_data_arrived<false>(2);
        flash::raise_priority();

        // MMAC 
        stage_id ^= 1;
        { 
            int min_tile_n = 0;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_n = 1;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        flash::lower_priority();
        flash::wait_lds_data_arrived<false>(0);
        flash::raise_priority();
        stage_id ^= 1;
        { 
            int min_tile_n = 0;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_n = 1;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        flash::lower_priority();

    }

    if constexpr (STAGES == 2) {
    #if defined(__gfx938__) || defined(__gfx946__) || (defined(__gfx92a__) && defined(YY_USE_MPERMUTE))
        prefetch_v_to_lds_mls_ds_576_512_buffer_load<kHeadDimV, kBlockM, kBlockK, kBlockN, WARP_M, kBlockK, Element, Is_even_MN>(v_ptr, v_lds, warp_id, seqlen_v_stride, index_ptr,block_table, batch_stride_v, n_loop, max_seq_k_offset);
    #else

    #endif
    }

} // qk_gemm

template<int kHeadDim, int kHeadDimV, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, int STAGES, typename Element, typename ElementAccum, bool Is_even_MN, bool Is_FlashMLA>
__forceinline__ __device__ void qk_gemm_prefetch_v_mls_ds_576_512_nopage(
        vec4_uint qv_ptr,
        vec4_uint q_ptr,
        vec4_uint k_ptr,
        vec4_uint v_ptr,
        Element* q_lds,
        Element* k_lds,
        Element* v_lds,
        vec4_Accum<ElementAccum> s_reg[(WARP_M / 16) * (kBlockN / 32)][2],
        int warp_id,
        int seqlen_qv_stride,
        int __seqlen_q_stride,
        int seqlen_k_stride,
        int seqlen_v_stride,
        int* index_ptr,
        int batch_stride_k,
        int batch_stride_v,
        int page_block_size,
        int n_loop,
        int max_seq_q_offset=0,
        int max_seq_k_offset=0) {

    // Simplify
    static_assert (kBlockK == 32 and "To simplify, only kBlockK = 32 is supported!");
    static_assert (WARP_M == 16 and "To simplify, only WARP_M = 16 is supported!");
    static_assert (WARP_N == 64 and "To simplify, only WARP_N = 64 is supported!");
    constexpr int WARP_NUM        = kBlockM / WARP_M;
    constexpr int kHeadDim_OPT       = (kHeadDim == 576) ? 64 : kHeadDim;
    constexpr int Q_LDS_LOAD_NUM  = (kBlockM * kBlockK) / (16 * 32);
    constexpr int Q_LOAD_REQUESTS = Q_LDS_LOAD_NUM / WARP_NUM;
    constexpr int K_LDS_LOAD_NUM  = (kHeadDim_OPT * WARP_N) / (32 * 16);
    constexpr int K_LOAD_REQUESTS = K_LDS_LOAD_NUM / WARP_NUM;
    constexpr int ELEMENT_BYTES   = sizeof(Element);
    constexpr int WARP_NUM_M = 2; 
    constexpr int WARP_NUM_N = 4;
    int warp_id_m = warp_id / WARP_NUM_N;
    int warp_id_n = warp_id % WARP_NUM_N;

    __builtin_amdgcn_sched_barrier(0);
    if constexpr (kBlockN == 128) {
        inline_vgpr4_init_zero_4x4x4(s_reg);
    } else {
        for (int i = 0; i < (WARP_M / 16) * (kBlockN / 32); ++i) {
            for (int j = 0; j < 2; ++j) {
                s_reg[i][j].u64[0] = 0.0f;
                s_reg[i][j].u64[1] = 0.0f;
            }
        }
    }
    __builtin_amdgcn_sched_barrier(0);

    // 准备 q,k 寄存器
    union_vec4_f16x2<Element> q_reg[(WARP_M * kBlockK) / (16 * 32)];
    union_vec4_f16x2<Element> k_reg[STAGES * (32 * kBlockK) / (32 * 32) * 2];

    // 计算 q_lds,k_lds 的起始偏移量
    int q_lds_base = reinterpret_cast<size_t>(q_lds);
    int k_lds_base = reinterpret_cast<size_t>(k_lds);

    int tid = threadIdx.x % 64;
    // MLS
    vec4_uint q_srsrc;
    vec4_uint k_srsrc;

    q_srsrc[2] = __seqlen_q_stride;
    if constexpr (Is_FlashMLA) {
        k_srsrc[2] = seqlen_k_stride;
    } else {
        k_srsrc[2] = seqlen_v_stride;
    }
    
    q_srsrc[3] = 0; 
    k_srsrc[3] = 0;

    int q_stage_id = 0;
    int k_stage_id = 0;

    if constexpr (STAGES == 2) {
        q_stage_id ^= 1;
        k_stage_id ^= 1;
    }

    {   
        for(int k_loop = 1; k_loop < (kHeadDim / kBlockK); ++k_loop) {
            // k预取的标志位
            int k_even = ((k_loop & 1) == 0x0) ? 1 : 0;
            
            {
                uint64_t q_base_addr;
                int seqlen_q_stride;
                int kloop_true;
                if constexpr (Is_FlashMLA) {
                    q_srsrc[2] = __seqlen_q_stride;
                    q_base_addr = *(uint64_t*)&q_ptr;
                    seqlen_q_stride = __seqlen_q_stride;
                    kloop_true = k_loop;
                } else {
                    q_srsrc[2] = (k_loop >= 2) ? seqlen_qv_stride : __seqlen_q_stride;
                    q_base_addr = (k_loop >= 2) ? *(uint64_t*)&qv_ptr : *(uint64_t*)&q_ptr;
                    seqlen_q_stride = (k_loop >= 2) ? seqlen_qv_stride : __seqlen_q_stride;
                    kloop_true = (k_loop >= 2) ? (k_loop - 2) : (k_loop);
                }

                *(uint64_t*)&q_srsrc = VA_LIMIT_BITS(q_base_addr + (kloop_true * kBlockK + warp_id * 16 * seqlen_q_stride) * ELEMENT_BYTES);
                int nm_filter = inline_min_max<0,16>(16 * warp_id + 16 - max_seq_q_offset);
                q_srsrc[3] = max_seq_q_offset % kBlockM == 0 ? 0: nm_filter << 8;
                int lds_offset = (q_stage_id * kBlockM * kBlockK + warp_id * 16 * 32) * ELEMENT_BYTES;
                flash::wait_all_warp_arrived();
                inline_matrix_load_32x16_b16_lds_trans<0, 1>(q_lds, q_srsrc, lds_offset, 0);
                
                if (k_even) {
                    k_stage_id ^= 1;
                    int index_topk = index_ptr[n_loop * 64 + warp_id_n * 16 + (tid / 4)];
                    int lds_offset = __builtin_amdgcn_readfirstlane((k_stage_id * WARP_N * kHeadDim_OPT + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
                    int g_offset_v = ((k_loop) / 2) * kHeadDim_OPT * ELEMENT_BYTES / 4 + warp_id_m * 16 + ((4 - (tid / 8) % 4) * 4 + tid % 4 * 4) % 16 + index_topk * seqlen_k_stride * ELEMENT_BYTES / 4;
                    flash::wait_all_warp_arrived();
                    inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset, 0, g_offset_v); 

                    // k_stage_id ^= 1;
                    // int nm_filter =  inline_min_max<0,16>(16 * warp_id_n + 16 - max_seq_k_offset);
                    // if constexpr (Is_FlashMLA) {
                    //     *(uint64_t*)&k_srsrc = VA_LIMIT_BITS(*(uint64_t*)&k_ptr + (warp_id_m * 32 + warp_id_n * 16 * seqlen_k_stride + ((k_loop) / 2) * kHeadDim_OPT) * ELEMENT_BYTES);
                    // } else {
                    //     *(uint64_t*)&k_srsrc = VA_LIMIT_BITS(*(uint64_t*)&k_ptr + (warp_id_m * 32 + warp_id_n * 16 * seqlen_v_stride + ((k_loop - 2) / 2) * kHeadDim_OPT) * ELEMENT_BYTES);
                    // }
                    // k_srsrc[3] = (max_seq_k_offset % kBlockN == 0x0 ? 0: nm_filter) << 8;
                    // int lds_offset = (k_stage_id * WARP_N * kHeadDim_OPT + warp_id * 32 * 16) * ELEMENT_BYTES;
                    // flash::wait_all_warp_arrived();
                    // inline_matrix_load_32x16_b16_lds_trans<0, 0>(k_lds, k_srsrc, lds_offset, 0);
                }
            }

            // 不对称MLS指令
            if (k_even) {
                flash::wait_buffer_data_arrived<true>(Q_LOAD_REQUESTS + K_LOAD_REQUESTS);
            } else {
                flash::wait_buffer_data_arrived<true>(Q_LOAD_REQUESTS);
            }
            
            q_stage_id ^= 1;

            // Q DS
            {
                int q_lds_load_offset = q_lds_base + (q_stage_id * kBlockM * kBlockK + warp_id * 16 * 32) * ELEMENT_BYTES;
                DS_READ_MATRIX_32X16_B16(q_lds_load_offset, q_reg[0].f16, true);  
            }

            k_stage_id ^= 1;
            int stage_id = 0;

            // K DS  
            {
                int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + k_even * 32 * 64 + 0 * 32 * 32) * ELEMENT_BYTES;
                DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
            }

            // K DS PRE
            stage_id ^= 1;
            {
                int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + k_even * 32 * 64 + 1 * 32 * 32) * ELEMENT_BYTES;
                DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
            }

            // Wait DS
            flash::wait_lds_data_arrived<false>(2);
            flash::raise_priority();

            // MMAC 
            stage_id ^= 1;
            { 
                int min_tile_n = 0;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[0].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            { 
                int min_tile_n = 1;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[0].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            flash::lower_priority();
            flash::wait_lds_data_arrived<false>(0);
            flash::raise_priority();
            stage_id ^= 1;
            { 
                int min_tile_n = 0;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[0].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            { 
                int min_tile_n = 1;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[0].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            flash::lower_priority();
            
        }
        
        constexpr int k_loop = kHeadDim / kBlockK; 
        constexpr int k_even = ((k_loop & 1) == 0x0) ? 1 : 0; 

        if constexpr (k_even) {
            k_stage_id ^= 1;
        }

        // 等回最后的q_panel
        flash::wait_buffer_data_arrived<true>(0);

        // Q DS
        q_stage_id ^= 1;
        {
            int q_lds_load_offset = q_lds_base + (q_stage_id * kBlockM * kBlockK + warp_id * 16 * 32) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X16_B16(q_lds_load_offset, q_reg[0].f16, true);  
        }

        // K DS  
        k_stage_id ^= 1;
        int stage_id = 0;
        {   
            int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + k_even * 32 * 64 + 0 * 32 * 32) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        }

        // K DS PRE
        stage_id ^= 1;
        {
            int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + k_even * 32 * 64 + 1 * 32 * 32) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        }

        // Wait DS
        flash::wait_lds_data_arrived<false>(2);
        flash::raise_priority();

        // MMAC 
        stage_id ^= 1;
        { 
            int min_tile_n = 0;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_n = 1;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        flash::lower_priority();
        flash::wait_lds_data_arrived<false>(0);
        flash::raise_priority();
        stage_id ^= 1;
        { 
            int min_tile_n = 0;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_n = 1;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        flash::lower_priority();

    }

    if constexpr (STAGES == 2) {
    #if defined(__gfx938__) || defined(__gfx946__) || (defined(__gfx92a__) && defined(YY_USE_MPERMUTE))
        prefetch_v_to_lds_mls_ds_576_512_buffer_load_nopage<kHeadDimV, kBlockM, kBlockK, kBlockN, WARP_M, kBlockK, Element, Is_even_MN>(v_ptr, v_lds, warp_id, seqlen_v_stride, index_ptr, batch_stride_v, n_loop, max_seq_k_offset);
    #else

    #endif
    }

} // qk_gemm

template<int kHeadDim, int kHeadDimV, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, int STAGES, typename Element, typename ElementAccum, bool Is_even_MN, bool Is_FlashMLA>
__forceinline__ __device__ void qk_gemm_prefetch_v_mls_ds_576_512_nopage_64(
        vec4_uint qv_ptr,
        vec4_uint q_ptr,
        vec4_uint k_ptr,
        vec4_uint v_ptr,
        Element* q_lds,
        Element* k_lds,
        Element* v_lds,
        vec4_Accum<ElementAccum> s_reg[(WARP_M / 16) * (kBlockN / 32)][2],
        int warp_id,
        int seqlen_qv_stride,
        int __seqlen_q_stride,
        int seqlen_k_stride,
        int seqlen_v_stride,
        int* index_ptr,
        int batch_stride_k,
        int batch_stride_v,
        int page_block_size,
        int n_loop,
        int max_seq_q_offset=0,
        int max_seq_k_offset=0) {

    // Simplify
    static_assert (kBlockK == 32 and "To simplify, only kBlockK = 32 is supported!");
    static_assert (WARP_M == 16 and "To simplify, only WARP_M = 16 is supported!");
    static_assert (WARP_N == 64 and "To simplify, only WARP_N = 64 is supported!");
    constexpr int WARP_NUM        = kBlockM / WARP_M;
    constexpr int kHeadDim_OPT       = (kHeadDim == 576) ? 32 : kHeadDim;
    constexpr int Q_LDS_LOAD_NUM  = (kBlockM * kBlockK) / (16 * 32);
    constexpr int Q_LOAD_REQUESTS = Q_LDS_LOAD_NUM / WARP_NUM;
    constexpr int K_LDS_LOAD_NUM  = (kHeadDim_OPT * WARP_N) / (32 * 16);
    constexpr int K_LOAD_REQUESTS = K_LDS_LOAD_NUM / WARP_NUM;
    constexpr int ELEMENT_BYTES   = sizeof(Element);
    constexpr int WARP_NUM_M = 1; 
    constexpr int WARP_NUM_N = 4;
    int warp_id_m = warp_id / WARP_NUM_N;
    int warp_id_n = warp_id % WARP_NUM_N;

    __builtin_amdgcn_sched_barrier(0);
    if constexpr (kBlockN == 128) {
        inline_vgpr4_init_zero_4x4x4(s_reg);
    } else {
        for (int i = 0; i < (WARP_M / 16) * (kBlockN / 32); ++i) {
            for (int j = 0; j < 2; ++j) {
                s_reg[i][j].u64[0] = 0.0f;
                s_reg[i][j].u64[1] = 0.0f;
            }
        }
    }
    __builtin_amdgcn_sched_barrier(0);

    // 准备 q,k 寄存器
    union_vec4_f16x2<Element> q_reg[(WARP_M * kBlockK) / (16 * 32)];
    union_vec4_f16x2<Element> k_reg[STAGES * (32 * kBlockK) / (32 * 32) * 2];

    // 计算 q_lds,k_lds 的起始偏移量
    int q_lds_base = reinterpret_cast<size_t>(q_lds);
    int k_lds_base = reinterpret_cast<size_t>(k_lds);

    int tid = threadIdx.x % 64;
    // MLS
    vec4_uint q_srsrc;
    vec4_uint k_srsrc;

    q_srsrc[2] = __seqlen_q_stride;
    if constexpr (Is_FlashMLA) {
        k_srsrc[2] = seqlen_k_stride;
    } else {
        k_srsrc[2] = seqlen_v_stride;
    }
    
    q_srsrc[3] = 0; 
    k_srsrc[3] = 0;

    int q_stage_id = 0;
    int k_stage_id = 0;

    if constexpr (STAGES == 2) {
        q_stage_id ^= 1;
        k_stage_id ^= 1;
    }

    {   
        for(int k_loop = 1; k_loop < (kHeadDim / kBlockK); ++k_loop) {
            
            {
                uint64_t q_base_addr;
                int seqlen_q_stride;
                int kloop_true;
                if constexpr (Is_FlashMLA) {
                    q_srsrc[2] = __seqlen_q_stride;
                    q_base_addr = *(uint64_t*)&q_ptr;
                    seqlen_q_stride = __seqlen_q_stride;
                    kloop_true = k_loop;
                } else {
                    q_srsrc[2] = (k_loop >= 2) ? seqlen_qv_stride : __seqlen_q_stride;
                    q_base_addr = (k_loop >= 2) ? *(uint64_t*)&qv_ptr : *(uint64_t*)&q_ptr;
                    seqlen_q_stride = (k_loop >= 2) ? seqlen_qv_stride : __seqlen_q_stride;
                    kloop_true = (k_loop >= 2) ? (k_loop - 2) : (k_loop);
                }

                *(uint64_t*)&q_srsrc = VA_LIMIT_BITS(q_base_addr + (kloop_true * kBlockK + warp_id * 16 * seqlen_q_stride) * ELEMENT_BYTES);
                int nm_filter = inline_min_max<0,16>(16 * warp_id + 16 - max_seq_q_offset);
                q_srsrc[3] = max_seq_q_offset % kBlockM == 0 ? 0: nm_filter << 8;
                int lds_offset = (q_stage_id * kBlockM * kBlockK + warp_id * 16 * 32) * ELEMENT_BYTES;
                flash::wait_all_warp_arrived();
                inline_matrix_load_32x16_b16_lds_trans<0, 1>(q_lds, q_srsrc, lds_offset, 0);
                
                int index_topk = index_ptr[n_loop * 64 + warp_id_n * 16 + (tid / 4)];
                lds_offset = __builtin_amdgcn_readfirstlane((k_stage_id * WARP_N * kHeadDim_OPT + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
                int g_offset_v = k_loop * kHeadDim_OPT * ELEMENT_BYTES / 4 + warp_id_m * 16 + ((4 - (tid / 8) % 4) * 4 + tid % 4 * 4) % 16 + index_topk * seqlen_k_stride * ELEMENT_BYTES / 4;
                flash::wait_all_warp_arrived();
                inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset, 0, g_offset_v); 

                    // k_stage_id ^= 1;
                    // int nm_filter =  inline_min_max<0,16>(16 * warp_id_n + 16 - max_seq_k_offset);
                    // if constexpr (Is_FlashMLA) {
                    //     *(uint64_t*)&k_srsrc = VA_LIMIT_BITS(*(uint64_t*)&k_ptr + (warp_id_m * 32 + warp_id_n * 16 * seqlen_k_stride + ((k_loop) / 2) * kHeadDim_OPT) * ELEMENT_BYTES);
                    // } else {
                    //     *(uint64_t*)&k_srsrc = VA_LIMIT_BITS(*(uint64_t*)&k_ptr + (warp_id_m * 32 + warp_id_n * 16 * seqlen_v_stride + ((k_loop - 2) / 2) * kHeadDim_OPT) * ELEMENT_BYTES);
                    // }
                    // k_srsrc[3] = (max_seq_k_offset % kBlockN == 0x0 ? 0: nm_filter) << 8;
                    // int lds_offset = (k_stage_id * WARP_N * kHeadDim_OPT + warp_id * 32 * 16) * ELEMENT_BYTES;
                    // flash::wait_all_warp_arrived();
                    // inline_matrix_load_32x16_b16_lds_trans<0, 0>(k_lds, k_srsrc, lds_offset, 0);
            }

            // 不对称MLS指令
            flash::wait_buffer_data_arrived<true>(Q_LOAD_REQUESTS + K_LOAD_REQUESTS);

            
            q_stage_id ^= 1;

            // Q DS
            {
                int q_lds_load_offset = q_lds_base + (q_stage_id * kBlockM * kBlockK + warp_id * 16 * 32) * ELEMENT_BYTES;
                DS_READ_MATRIX_32X16_B16(q_lds_load_offset, q_reg[0].f16, true);  
            }

            k_stage_id ^= 1;
            int stage_id = 0;

            // K DS  
            {
                int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + 0 * 32 * 32) * ELEMENT_BYTES;
                DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
            }

            // K DS PRE
            stage_id ^= 1;
            {
                int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + 1 * 32 * 32) * ELEMENT_BYTES;
                DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
            }

            // Wait DS
            flash::wait_lds_data_arrived<false>(2);
            flash::raise_priority();

            // MMAC 
            stage_id ^= 1;
            { 
                int min_tile_n = 0;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[0].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            { 
                int min_tile_n = 1;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[0].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            flash::lower_priority();
            flash::wait_lds_data_arrived<false>(0);
            flash::raise_priority();
            stage_id ^= 1;
            { 
                int min_tile_n = 0;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[0].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            { 
                int min_tile_n = 1;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[0].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            flash::lower_priority();
            
        }

        // 等回最后的q_panel
        flash::wait_buffer_data_arrived<true>(0);

        // Q DS
        q_stage_id ^= 1;
        {
            int q_lds_load_offset = q_lds_base + (q_stage_id * kBlockM * kBlockK + warp_id * 16 * 32) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X16_B16(q_lds_load_offset, q_reg[0].f16, true);  
        }

        // K DS  
        k_stage_id ^= 1;
        int stage_id = 0;
        {   
            int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + 0 * 32 * 32) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        }

        // K DS PRE
        stage_id ^= 1;
        {
            int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + 1 * 32 * 32) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        }

        // Wait DS
        flash::wait_lds_data_arrived<false>(2);
        flash::raise_priority();

        // MMAC 
        stage_id ^= 1;
        { 
            int min_tile_n = 0;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_n = 1;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        flash::lower_priority();
        flash::wait_lds_data_arrived<false>(0);
        flash::raise_priority();
        stage_id ^= 1;
        { 
            int min_tile_n = 0;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_n = 1;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        flash::lower_priority();

    }

    if constexpr (STAGES == 2) {
    #if defined(__gfx938__) || defined(__gfx946__) || (defined(__gfx92a__) && defined(YY_USE_MPERMUTE))
        prefetch_v_to_lds_mls_ds_576_512_buffer_load_nopage_64<kHeadDimV, kBlockM, kBlockK, kBlockN, WARP_M, kBlockK, Element, Is_even_MN>(v_ptr, v_lds, warp_id, seqlen_v_stride, index_ptr, batch_stride_v, n_loop, max_seq_k_offset);
    #else

    #endif
    }
}

template<int kHeadDim, int kHeadDimV, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, int STAGES, typename Element, typename ElementAccum, bool Is_even_MN, bool Is_FlashMLA>
__forceinline__ __device__ void qk_gemm_prefetch_v_mls_ds_576_512_nopage_64_new(
        vec4_uint qv_ptr,
        vec4_uint q_ptr,
        vec4_uint k_ptr,
        Element* v_faker,
        Element* q_lds,
        Element* k_lds,
        Element* v_lds,
        union_vec4_f16x2<Element> q_reg[(WARP_M * kBlockK) / (16 * 64) * (kHeadDim / kBlockK)],
        vec4_Accum<ElementAccum> s_reg[(WARP_M / 16) * (kBlockN / 32)][2],
        int warp_id,
        int seqlen_qv_stride,
        int __seqlen_q_stride,
        int seqlen_k_stride,
        int seqlen_v_stride,
        int* index_ptr,
        int batch_stride_k,
        int batch_stride_v,
        int page_block_size,
        int n_loop,
        int max_seq_q_offset=0,
        int max_seq_k_offset=0) {

    // Simplify
    static_assert (kBlockK == 32 and "To simplify, only kBlockK = 32 is supported!");
    static_assert (WARP_M == 16 and "To simplify, only WARP_M = 16 is supported!");
    static_assert (WARP_N == 64 and "To simplify, only WARP_N = 64 is supported!");
    constexpr int WARP_NUM        = kBlockM / WARP_M;
    constexpr int kHeadDim_OPT       = (kHeadDim == 576) ? 32 : kHeadDim;
    constexpr int Q_LDS_LOAD_NUM  = (kBlockM * kBlockK) / (16 * 32);
    constexpr int Q_LOAD_REQUESTS = Q_LDS_LOAD_NUM / WARP_NUM;
    constexpr int K_LDS_LOAD_NUM  = (kHeadDim_OPT * WARP_N) / (32 * 16);
    constexpr int K_LOAD_REQUESTS = K_LDS_LOAD_NUM / WARP_NUM;
    constexpr int ELEMENT_BYTES   = sizeof(Element);
    constexpr int WARP_NUM_M = 1; 
    constexpr int WARP_NUM_N = 4;
    int warp_id_m = warp_id / WARP_NUM_N;
    int warp_id_n = warp_id % WARP_NUM_N;

    __builtin_amdgcn_sched_barrier(0);
    if constexpr (kBlockN == 128) {
        inline_vgpr4_init_zero_4x4x4(s_reg);
    } else {
        for (int i = 0; i < (WARP_M / 16) * (kBlockN / 32); ++i) {
            for (int j = 0; j < 2; ++j) {
                s_reg[i][j].u64[0] = 0.0f;
                s_reg[i][j].u64[1] = 0.0f;
            }
        }
    }
    __builtin_amdgcn_sched_barrier(0);

    // 准备 q,k 寄存器
    union_vec4_f16x2<Element> k_reg[STAGES * (32 * kBlockK) / (32 * 32) * 2];

    // 计算 q_lds,k_lds 的起始偏移量
    int k_lds_base = reinterpret_cast<size_t>(k_lds);

    int tid = threadIdx.x % 64;
    // MLS
    vec4_uint k_srsrc;

    if constexpr (Is_FlashMLA) {
        k_srsrc[2] = seqlen_k_stride;
    } else {
        k_srsrc[2] = seqlen_v_stride;
    }
    
    k_srsrc[3] = 0;

    int k_stage_id = 0;

    int index_topk = index_ptr[(n_loop * 64) + warp_id_n * 16 + (tid / 4)];
    int lds_offset = __builtin_amdgcn_readfirstlane((warp_id * 32 * 16) * ELEMENT_BYTES / 4);
    int g_offset_v = ((4 - (tid / 8) % 4) * 4 + tid % 4 * 4) % 16 + index_topk * seqlen_k_stride * ELEMENT_BYTES / 4;
    int g_offset_s = ((kHeadDim / kBlockK) - 1) * kHeadDim_OPT * ELEMENT_BYTES / 4 + warp_id_m * 16;
    flash::wait_all_warp_arrived();
    inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset, g_offset_s, g_offset_v); 

    if constexpr (STAGES == 2) {
        k_stage_id ^= 1;
    }

    {   
        // int index_topk = index_ptr[(n_loop * 64) + warp_id_n * 16 + (tid / 4)];
        g_offset_v = ((4 - (tid / 8) % 4) * 4 + tid % 4 * 4) % 16 + index_topk * seqlen_k_stride * ELEMENT_BYTES / 4;
        for(int k_loop = (kHeadDim / kBlockK) - 2; k_loop >= 0; --k_loop) {
            
            {
                lds_offset = __builtin_amdgcn_readfirstlane((k_stage_id * WARP_N * kHeadDim_OPT + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
                g_offset_s = k_loop * kHeadDim_OPT * ELEMENT_BYTES / 4 + warp_id_m * 16;
                flash::wait_all_warp_arrived();
                inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset, g_offset_s, g_offset_v); 

                    // k_stage_id ^= 1;
                    // int nm_filter =  inline_min_max<0,16>(16 * warp_id_n + 16 - max_seq_k_offset);
                    // if constexpr (Is_FlashMLA) {
                    //     *(uint64_t*)&k_srsrc = VA_LIMIT_BITS(*(uint64_t*)&k_ptr + (warp_id_m * 32 + warp_id_n * 16 * seqlen_k_stride + ((k_loop) / 2) * kHeadDim_OPT) * ELEMENT_BYTES);
                    // } else {
                    //     *(uint64_t*)&k_srsrc = VA_LIMIT_BITS(*(uint64_t*)&k_ptr + (warp_id_m * 32 + warp_id_n * 16 * seqlen_v_stride + ((k_loop - 2) / 2) * kHeadDim_OPT) * ELEMENT_BYTES);
                    // }
                    // k_srsrc[3] = (max_seq_k_offset % kBlockN == 0x0 ? 0: nm_filter) << 8;
                    // int lds_offset = (k_stage_id * WARP_N * kHeadDim_OPT + warp_id * 32 * 16) * ELEMENT_BYTES;
                    // flash::wait_all_warp_arrived();
                    // inline_matrix_load_32x16_b16_lds_trans<0, 0>(k_lds, k_srsrc, lds_offset, 0);
            }

            // 不对称MLS指令
            flash::wait_buffer_data_arrived<true>(K_LOAD_REQUESTS);

            k_stage_id ^= 1;
            int stage_id = 0;

            // K DS  
            {
                int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + 0 * 32 * 32) * ELEMENT_BYTES;
                DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
            }

            // K DS PRE
            stage_id ^= 1;
            {
                int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + 1 * 32 * 32) * ELEMENT_BYTES;
                DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
            }

            // Wait DS
            flash::wait_lds_data_arrived<false>(2);
            flash::raise_priority();

            // MMAC 
            stage_id ^= 1;
            { 
                int min_tile_n = 0;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[k_loop+1].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            { 
                int min_tile_n = 1;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[k_loop+1].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            flash::lower_priority();
            flash::wait_lds_data_arrived<false>(0);
            flash::raise_priority();
            stage_id ^= 1;
            { 
                int min_tile_n = 0;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[k_loop+1].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            { 
                int min_tile_n = 1;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[k_loop+1].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            flash::lower_priority();
            
        }

        // 等回最后的q_panel
        flash::wait_buffer_data_arrived<true>(0);

        // K DS  
        k_stage_id ^= 1;
        int stage_id = 0;
        {   
            int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + 0 * 32 * 32) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        }

        // K DS PRE
        stage_id ^= 1;
        {
            int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + 1 * 32 * 32) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        }

        // Wait DS
        flash::wait_lds_data_arrived<false>(2);
        flash::raise_priority();

        // MMAC 
        stage_id ^= 1;
        { 
            int min_tile_n = 0;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_n = 1;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        flash::lower_priority();
        flash::wait_lds_data_arrived<false>(0);

        // int abc[1];
        // int index_topk = index_ptr[(((n_loop+1) % 16) * 64) + warp_id * 16];
        // int offset_m = index_topk * seqlen_v_stride;
        // auto g_abc = (reinterpret_cast<uint64_t>(v_faker + offset_m)); 
        // inline_s_load_dword(abc[0], g_abc, 0); 

        flash::raise_priority();
        stage_id ^= 1;
        { 
            int min_tile_n = 0;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_n = 1;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        flash::lower_priority();

    }

    if constexpr (STAGES == 2) {
    #if defined(__gfx938__) || defined(__gfx946__) || (defined(__gfx92a__) && defined(YY_USE_MPERMUTE))
        // prefetch_v_to_lds_mls_ds_576_512_buffer_load_nopage_64<kHeadDimV, kBlockM, kBlockK, kBlockN, WARP_M, kBlockK, Element, Is_even_MN>(v_ptr, v_lds, warp_id, seqlen_v_stride, index_ptr, batch_stride_v, n_loop, max_seq_k_offset);
    #else

    #endif
    }
}


template<int kHeadDim, int kHeadDimV, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, int STAGES, typename Element, typename ElementAccum, bool Is_even_MN, bool Is_FlashMLA>
__forceinline__ __device__ void qk_gemm_prefetch_v_mls_ds_576_512_nopage_64_new_666(
        vec4_uint qv_ptr,
        vec4_uint q_ptr,
        vec4_uint k_ptr,
        Element* v_faker,
        Element* q_lds,
        Element* k_lds,
        Element* v_lds,
        union_vec4_f16x2<Element> q_reg[(WARP_M * kBlockK) / (16 * 32) * (kHeadDim / kBlockK)],
        vec4_Accum<ElementAccum> s_reg[(WARP_M / 16) * (kBlockN / 32)][2],
        int warp_id,
        int seqlen_qv_stride,
        int __seqlen_q_stride,
        int seqlen_k_stride,
        int seqlen_v_stride,
        int* index_ptr,
        int batch_stride_k,
        int batch_stride_v,
        int page_block_size,
        int n_loop,
        int max_seq_q_offset=0,
        int max_seq_k_offset=0) {

    // Simplify
    static_assert (kBlockK == 64 and "To simplify, only kBlockK = 32 is supported!");
    static_assert (WARP_M == 16 and "To simplify, only WARP_M = 16 is supported!");
    static_assert (WARP_N == 64 and "To simplify, only WARP_N = 64 is supported!");
    constexpr int WARP_NUM        = kBlockM / WARP_M;
    constexpr int kHeadDim_OPT       = (kHeadDim == 576) ? 64 : kHeadDim;
    constexpr int Q_LDS_LOAD_NUM  = (kBlockM * kBlockK) / (16 * 32);
    constexpr int Q_LOAD_REQUESTS = Q_LDS_LOAD_NUM / WARP_NUM;
    constexpr int K_LDS_LOAD_NUM  = (kHeadDim_OPT * WARP_N) / (32 * 16);
    constexpr int K_LOAD_REQUESTS = K_LDS_LOAD_NUM / WARP_NUM;
    constexpr int ELEMENT_BYTES   = sizeof(Element);
    constexpr int WARP_NUM_M = 1; 
    constexpr int WARP_NUM_N = 4;
    int warp_id_m = warp_id / WARP_NUM_N;
    int warp_id_n = warp_id % WARP_NUM_N;

    __builtin_amdgcn_sched_barrier(0);
    if constexpr (kBlockN == 128) {
        inline_vgpr4_init_zero_4x4x4(s_reg);
    } else {
        for (int i = 0; i < (WARP_M / 16) * (kBlockN / 32); ++i) {
            for (int j = 0; j < 2; ++j) {
                s_reg[i][j].u64[0] = 0.0f;
                s_reg[i][j].u64[1] = 0.0f;
            }
        }
    }
    __builtin_amdgcn_sched_barrier(0);

    // 准备 q,k 寄存器
    union_vec4_f16x2<Element> k_reg[STAGES * (32 * kBlockK) / (32 * 32) * 2];

    // 计算 q_lds,k_lds 的起始偏移量
    int k_lds_base = reinterpret_cast<size_t>(k_lds);

    int tid = threadIdx.x % 64;
    // MLS
    vec4_uint k_srsrc;

    if constexpr (Is_FlashMLA) {
        k_srsrc[2] = seqlen_k_stride;
    } else {
        k_srsrc[2] = seqlen_v_stride;
    }
    
    k_srsrc[3] = 0;

    int k_stage_id = 0;

    int index_topk = index_ptr[(n_loop * 64) + warp_id_n * 16 + (tid / 4)];
    int lds_offset = __builtin_amdgcn_readfirstlane((warp_id * 32 * 16) * ELEMENT_BYTES / 4);
    int lds_offset_2 = __builtin_amdgcn_readfirstlane((warp_id * 32 * 16 + 32 * 64) * ELEMENT_BYTES / 4);
    int g_offset_v = ((4 - (tid / 8) % 4) * 4 + tid % 4 * 4) % 16 + index_topk * seqlen_k_stride * ELEMENT_BYTES / 4;
    int g_offset_s = ((kHeadDim / kBlockK) - 1) * kHeadDim_OPT * ELEMENT_BYTES / 4 + warp_id_m * 16;
    int g_offset_s_2 = ((kHeadDim / kBlockK) - 1) * kHeadDim_OPT * ELEMENT_BYTES / 4 + warp_id_m * 16 + 16;
    flash::wait_all_warp_arrived();
    inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset, g_offset_s, g_offset_v); 
    inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset_2, g_offset_s_2, g_offset_v); 

    if constexpr (STAGES == 2) {
        k_stage_id ^= 1;
    }

    {   
        // int index_topk = index_ptr[(n_loop * 64) + warp_id_n * 16 + (tid / 4)];
        // g_offset_v = ((4 - (tid / 8) % 4) * 4 + tid % 4 * 4) % 16 + index_topk * seqlen_k_stride * ELEMENT_BYTES / 4;
        for(int k_loop = (kHeadDim / kBlockK) - 2; k_loop >= 0; --k_loop) {
            
            {
                lds_offset = __builtin_amdgcn_readfirstlane((k_stage_id * WARP_N * kHeadDim_OPT + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
                lds_offset_2 = __builtin_amdgcn_readfirstlane((k_stage_id * WARP_N * kHeadDim_OPT + warp_id * 32 * 16 + 32 * 64) * ELEMENT_BYTES / 4);
                g_offset_s = k_loop * kHeadDim_OPT * ELEMENT_BYTES / 4 + warp_id_m * 16;
                g_offset_s_2 = k_loop * kHeadDim_OPT * ELEMENT_BYTES / 4 + warp_id_m * 16 + 16;
                flash::wait_all_warp_arrived();
                inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset, g_offset_s, g_offset_v); 
                inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset_2, g_offset_s_2, g_offset_v); 
                    // k_stage_id ^= 1;
                    // int nm_filter =  inline_min_max<0,16>(16 * warp_id_n + 16 - max_seq_k_offset);
                    // if constexpr (Is_FlashMLA) {
                    //     *(uint64_t*)&k_srsrc = VA_LIMIT_BITS(*(uint64_t*)&k_ptr + (warp_id_m * 32 + warp_id_n * 16 * seqlen_k_stride + ((k_loop) / 2) * kHeadDim_OPT) * ELEMENT_BYTES);
                    // } else {
                    //     *(uint64_t*)&k_srsrc = VA_LIMIT_BITS(*(uint64_t*)&k_ptr + (warp_id_m * 32 + warp_id_n * 16 * seqlen_v_stride + ((k_loop - 2) / 2) * kHeadDim_OPT) * ELEMENT_BYTES);
                    // }
                    // k_srsrc[3] = (max_seq_k_offset % kBlockN == 0x0 ? 0: nm_filter) << 8;
                    // int lds_offset = (k_stage_id * WARP_N * kHeadDim_OPT + warp_id * 32 * 16) * ELEMENT_BYTES;
                    // flash::wait_all_warp_arrived();
                    // inline_matrix_load_32x16_b16_lds_trans<0, 0>(k_lds, k_srsrc, lds_offset, 0);
            }

            // 不对称MLS指令
            flash::wait_buffer_data_arrived<true>(K_LOAD_REQUESTS);

            k_stage_id ^= 1;
            int stage_id = 0;

            // K DS  
            {
                int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + 0 * 32 * 32) * ELEMENT_BYTES;
                int k_lds_load_offset_2 = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + 0 * 32 * 32 + 32 * 64) * ELEMENT_BYTES;
                DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
                DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
            }

            // K DS PRE
            stage_id ^= 1;
            {
                int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + 1 * 32 * 32) * ELEMENT_BYTES;
                int k_lds_load_offset_2 = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + 1 * 32 * 32 + 32 * 64) * ELEMENT_BYTES;
                DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
                DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
            }

            // Wait DS
            flash::wait_lds_data_arrived<false>(6);
            // flash::raise_priority();

            // MMAC 
            stage_id ^= 1;
            { 
                int min_tile_n = 0;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[(k_loop + 1) * 2 + 0].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            { 
                int min_tile_n = 1;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[(k_loop + 1) * 2 + 0].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            // flash::lower_priority();
            flash::wait_lds_data_arrived<false>(4);
            // flash::raise_priority();

            {
                int min_tile_n = 0;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[(k_loop + 1) * 2 + 1].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            { 
                int min_tile_n = 1;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[(k_loop + 1) * 2 + 1].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            // flash::lower_priority();
            flash::wait_lds_data_arrived<false>(2);
            // flash::raise_priority();

            stage_id ^= 1;
            { 
                int min_tile_n = 0;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[(k_loop + 1) * 2 + 0].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            { 
                int min_tile_n = 1;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[(k_loop + 1) * 2 + 0].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            // flash::lower_priority();
            flash::wait_lds_data_arrived<false>(0);
            // flash::raise_priority();

            { 
                int min_tile_n = 0;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[(k_loop + 1) * 2 + 1].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }

            { 
                int min_tile_n = 1;
                #pragma unroll
                for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                        int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                        s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            q_reg[(k_loop + 1) * 2 + 1].f16x4[min_tile_k],
                            k_reg[k_tile_id].f16x4[min_tile_k],
                            s_reg[stage_id][min_tile_n].f32);
                }
            }
            // flash::lower_priority();
            
        }

        // 等回最后的q_panel
        flash::wait_buffer_data_arrived<true>(0);

        // K DS  
        k_stage_id ^= 1;
        int stage_id = 0;
        {   
            int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + 0 * 32 * 32) * ELEMENT_BYTES;
            int k_lds_load_offset_2 = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + 0 * 32 * 32 + 32 * 64) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
            DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
        }

        // K DS PRE
        stage_id ^= 1;
        {
            int k_lds_load_offset = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + 1 * 32 * 32) * ELEMENT_BYTES;
            int k_lds_load_offset_2 = k_lds_base + (k_stage_id * WARP_N * kHeadDim_OPT + 1 * 32 * 32 + 32 * 64) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
            DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
        }


        // Wait DS
        flash::wait_lds_data_arrived<false>(6);
        // flash::raise_priority();

        // MMAC 
        stage_id ^= 1;
        { 
            int min_tile_n = 0;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_n = 1;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        // flash::lower_priority();
        flash::wait_lds_data_arrived<false>(4);
        // flash::raise_priority();

        {
            int min_tile_n = 0;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[1].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_n = 1;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[1].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        // flash::lower_priority();
        flash::wait_lds_data_arrived<false>(2);
        // flash::raise_priority();

        stage_id ^= 1;
        { 
            int min_tile_n = 0;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_n = 1;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[0].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        // flash::lower_priority();
        flash::wait_lds_data_arrived<false>(0);

        // int abc[2];
        // int index_topk = index_ptr[(n_loop * 64)];
        // int index_topk2 = index_ptr[(n_loop * 64) + 8];
        // int offset_m = index_topk * seqlen_k_stride;
        // int offset_m2 = index_topk2 * seqlen_k_stride;
        // auto g_abc = (reinterpret_cast<uint64_t>(v_faker + offset_m)); 
        // auto g_abc2 = (reinterpret_cast<uint64_t>(v_faker + offset_m2)); 
        // inline_s_load_dword(abc[0], g_abc, 0); 
        // inline_s_load_dword(abc[1], g_abc2, 0); 

        // flash::raise_priority();

        { 
            int min_tile_n = 0;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[1].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_n = 1;
            #pragma unroll
            for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                    int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                    s_reg[stage_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        q_reg[1].f16x4[min_tile_k],
                        k_reg[k_tile_id].f16x4[min_tile_k],
                        s_reg[stage_id][min_tile_n].f32);
            }
        }
        // flash::lower_priority();

    }
}

template<int kHeadDim, int kHeadDimV, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, int STAGES, typename Element, typename ElementAccum, bool Is_even_MN, bool Is_FlashMLA>
__forceinline__ __device__ void qk_gemm_prefetch_v_mls_ds_576_512_nopage_64_new_777(
        vec4_uint qv_ptr,
        vec4_uint q_ptr,
        vec4_uint k_ptr,
        Element* v_faker,
        Element* q_lds,
        Element* k_lds,
        Element* v_lds,
        union_vec4_f16x2<Element> q_reg[(WARP_M * kBlockK) / (16 * 32) * (kHeadDim / kBlockK)],
        vec4_Accum<ElementAccum> s_reg[(WARP_M / 16) * (kBlockN / 32)][2],
        int warp_id,
        int seqlen_qv_stride,
        int __seqlen_q_stride,
        int seqlen_k_stride,
        int seqlen_v_stride,
        int* index_ptr,
        int batch_stride_k,
        int batch_stride_v,
        int page_block_size,
        int n_loop,
        int max_seq_q_offset=0,
        int max_seq_k_offset=0) {

    // Simplify
    static_assert (kBlockK == 64 and "To simplify, only kBlockK = 32 is supported!");
    static_assert (WARP_M == 16 and "To simplify, only WARP_M = 16 is supported!");
    static_assert (WARP_N == 64 and "To simplify, only WARP_N = 64 is supported!");
    constexpr int WARP_NUM        = kBlockM / WARP_M;
    constexpr int kHeadDim_OPT       = 64;
    constexpr int Q_LDS_LOAD_NUM  = (kBlockM * kBlockK) / (16 * 32);
    constexpr int Q_LOAD_REQUESTS = Q_LDS_LOAD_NUM / WARP_NUM;
    constexpr int K_LDS_LOAD_NUM  = (kHeadDim_OPT * WARP_N) / (32 * 16);
    constexpr int K_LOAD_REQUESTS = K_LDS_LOAD_NUM / WARP_NUM;
    constexpr int ELEMENT_BYTES   = sizeof(Element);

    __builtin_amdgcn_sched_barrier(0);
    if constexpr (kBlockN == 128) {
        inline_vgpr4_init_zero_4x4x4(s_reg);
    } else {
        for (int i = 0; i < (WARP_M / 16) * (kBlockN / 32); ++i) {
            for (int j = 0; j < 2; ++j) {
                s_reg[i][j].u64[0] = 0.0f;
                s_reg[i][j].u64[1] = 0.0f;
            }
        }
    }
    __builtin_amdgcn_sched_barrier(0);

    int tid = threadIdx.x % 64;
    int index_topk[4];
    index_topk[0] = index_ptr[(n_loop * 64) + 0 * 16 + (tid / 4)];
    index_topk[1] = index_ptr[(n_loop * 64) + 1 * 16 + (tid / 4)];
    index_topk[2] = index_ptr[(n_loop * 64) + 2 * 16 + (tid / 4)];
    index_topk[3] = index_ptr[(n_loop * 64) + 3 * 16 + (tid / 4)];

    bool invalid_topk[4];
    invalid_topk[0] = index_topk[0] == -1;
    invalid_topk[1] = index_topk[1] == -1;
    invalid_topk[2] = index_topk[2] == -1;
    invalid_topk[3] = index_topk[3] == -1;

    int fallback_index = index_ptr[0] == -1 ? 0 : index_ptr[0];
    index_topk[0] = (index_topk[0] == -1) ? fallback_index : index_topk[0];
    index_topk[1] = (index_topk[1] == -1) ? fallback_index : index_topk[1];
    index_topk[2] = (index_topk[2] == -1) ? fallback_index : index_topk[2];
    index_topk[3] = (index_topk[3] == -1) ? fallback_index : index_topk[3];

    // 准备 q,k 寄存器
    union_vec4_f16x2<Element> k_reg[STAGES * (32 * kBlockK) / (32 * 32) * 2];

    // 计算 q_lds,k_lds 的起始偏移量
    int k_lds_base = reinterpret_cast<size_t>(k_lds);

    #pragma unroll 1
    for(int i=3;i>=0;i--)
    {
    int k_stage_id = 0;

    int lds_offset = __builtin_amdgcn_readfirstlane((warp_id * 32 * 16) * ELEMENT_BYTES / 4);
    int lds_offset_2;
    int index_block = index_topk[i] / page_block_size;
    int index_offset = index_topk[i] - index_block * page_block_size;
    int g_offset_v = ((4 - (tid / 8) % 4) * 4 + tid % 4 * 4) % 16
        + (index_block * batch_stride_k + index_offset * seqlen_k_stride) * ELEMENT_BYTES / 4;
    int g_offset_s = 512 * ELEMENT_BYTES / 4 + warp_id * 16;
    int g_offset_s_2;
    flash::wait_all_warp_arrived();

    if(warp_id < 2){
        inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset, g_offset_s, g_offset_v); 
    }

    if constexpr (STAGES == 2) {
        k_stage_id ^= 1;
    }

    lds_offset = __builtin_amdgcn_readfirstlane((k_stage_id * 16 * 256 + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
    lds_offset_2 = __builtin_amdgcn_readfirstlane((k_stage_id * 16 * 256 + warp_id * 32 * 16 + 128 * 16) * ELEMENT_BYTES / 4);
    g_offset_s = 256 * ELEMENT_BYTES / 4 + warp_id * 16;
    g_offset_s_2 = 256 * ELEMENT_BYTES / 4 + warp_id * 16 + 64;
    flash::wait_all_warp_arrived();
    inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset, g_offset_s, g_offset_v); 
    inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset_2, g_offset_s_2, g_offset_v); 

    flash::wait_buffer_data_arrived<true>(K_LOAD_REQUESTS);

    k_stage_id ^= 1;
    int stage_id = 0;

    // K DS  
    {
        int k_lds_load_offset = k_lds_base + (k_stage_id * 16 * 256) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
    }

    // Wait DS
    flash::wait_lds_data_arrived<false>(0);
    // flash::raise_priority();

    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[16].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[17].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    // flash::lower_priority();

    lds_offset = __builtin_amdgcn_readfirstlane((k_stage_id * 16 * 256 + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
    lds_offset_2 = __builtin_amdgcn_readfirstlane((k_stage_id * 16 * 256 + warp_id * 32 * 16 + 128 * 16) * ELEMENT_BYTES / 4);
    g_offset_s = 0 * ELEMENT_BYTES / 4 + warp_id * 16;
    g_offset_s_2 = 0 * ELEMENT_BYTES / 4 + warp_id * 16 + 64;
    flash::wait_all_warp_arrived();
    inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset, g_offset_s, g_offset_v); 
    inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset_2, g_offset_s_2, g_offset_v); 

    flash::wait_buffer_data_arrived<true>(K_LOAD_REQUESTS);

    k_stage_id ^= 1;
    stage_id = 0;

    // K DS  
    {
        int k_lds_load_offset = k_lds_base + (k_stage_id * 16 * 256) * ELEMENT_BYTES;
        int k_lds_load_offset_2 = k_lds_base + (k_stage_id * 16 * 256 + 16 * 64) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
    }

    // K DS PRE
    stage_id ^= 1;
    {
        int k_lds_load_offset = k_lds_base + (k_stage_id * 16 * 256 + 16 * 128) * ELEMENT_BYTES;
        int k_lds_load_offset_2 = k_lds_base + (k_stage_id * 16 * 256 + 16 * 192) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
    }
                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                       
    // Wait DS
    flash::wait_lds_data_arrived<false>(6);
    // flash::raise_priority();

    // MMAC 
    stage_id ^= 1;
    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[8].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[9].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    // flash::lower_priority();
    flash::wait_lds_data_arrived<false>(4);
    // flash::raise_priority();

    {
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[10].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[11].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    // flash::lower_priority();
    flash::wait_lds_data_arrived<false>(2);
    // flash::raise_priority();

    stage_id ^= 1;
    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[12].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[13].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    // flash::lower_priority();
    flash::wait_lds_data_arrived<false>(0);
    // flash::raise_priority();

    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[14].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[15].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }
    // flash::lower_priority();

    flash::wait_buffer_data_arrived<true>(0);

    k_stage_id ^= 1;
    stage_id = 0;

    // K DS  
    {
        int k_lds_load_offset = k_lds_base + (k_stage_id * 16 * 256) * ELEMENT_BYTES;
        int k_lds_load_offset_2 = k_lds_base + (k_stage_id * 16 * 256 + 16 * 64) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
    }

    // K DS PRE
    stage_id ^= 1;
    {
        int k_lds_load_offset = k_lds_base + (k_stage_id * 16 * 256 + 16 * 128) * ELEMENT_BYTES;
        int k_lds_load_offset_2 = k_lds_base + (k_stage_id * 16 * 256 + 16 * 192) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
    }
                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                       
    // Wait DS
    flash::wait_lds_data_arrived<false>(6);
    // flash::raise_priority();

    // MMAC 
    stage_id ^= 1;
    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[0].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[1].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    // flash::lower_priority();
    flash::wait_lds_data_arrived<false>(4);
    // flash::raise_priority();

    {
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[2].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[3].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    // flash::lower_priority();
    flash::wait_lds_data_arrived<false>(2);
    // flash::raise_priority();

    stage_id ^= 1;
    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[4].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[5].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    // flash::lower_priority();
    flash::wait_lds_data_arrived<false>(0);
    // flash::raise_priority();

    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[6].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[7].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }
    // flash::lower_priority();
    }
}

// Old topk=2048 prefill fast path. Keep separate from the generic paged/fallback variant.
template<bool NeedIndexGuard, int kHeadDim, int kHeadDimV, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, int STAGES, typename Element, typename ElementAccum, bool Is_even_MN, bool Is_FlashMLA>
__forceinline__ __device__ void qk_gemm_prefetch_v_mls_ds_576_512_nopage_64_new_777_topk2048_fast(
        vec4_uint qv_ptr,
        vec4_uint q_ptr,
        vec4_uint k_ptr,
        Element* v_faker,
        Element* q_lds,
        Element* k_lds,
        Element* v_lds,
        union_vec4_f16x2<Element> q_reg[(WARP_M * kBlockK) / (16 * 32) * (kHeadDim / kBlockK)],
        vec4_Accum<ElementAccum> s_reg[(WARP_M / 16) * (kBlockN / 32)][2],
        int warp_id,
        int seqlen_qv_stride,
        int __seqlen_q_stride,
        int seqlen_k_stride,
        int seqlen_v_stride,
        int* index_ptr,
        int batch_stride_k,
        int batch_stride_v,
        int n_loop,
        int max_seq_q_offset=0,
        int max_seq_k_offset=0) {

    // Simplify
    static_assert (kBlockK == 64 and "To simplify, only kBlockK = 32 is supported!");
    static_assert (WARP_M == 16 and "To simplify, only WARP_M = 16 is supported!");
    static_assert (WARP_N == 64 and "To simplify, only WARP_N = 64 is supported!");
    constexpr int WARP_NUM        = kBlockM / WARP_M;
    constexpr int kHeadDim_OPT       = (kHeadDim == 576) ? 64 : kHeadDim;
    constexpr int Q_LDS_LOAD_NUM  = (kBlockM * kBlockK) / (16 * 32);
    constexpr int Q_LOAD_REQUESTS = Q_LDS_LOAD_NUM / WARP_NUM;
    constexpr int K_LDS_LOAD_NUM  = (kHeadDim_OPT * WARP_N) / (32 * 16);
    constexpr int K_LOAD_REQUESTS = K_LDS_LOAD_NUM / WARP_NUM;
    constexpr int ELEMENT_BYTES   = sizeof(Element);

    __builtin_amdgcn_sched_barrier(0);
    if constexpr (kBlockN == 128) {
        inline_vgpr4_init_zero_4x4x4(s_reg);
    } else {
        for (int i = 0; i < (WARP_M / 16) * (kBlockN / 32); ++i) {
            for (int j = 0; j < 2; ++j) {
                s_reg[i][j].u64[0] = 0.0f;
                s_reg[i][j].u64[1] = 0.0f;
            }
        }
    }
    __builtin_amdgcn_sched_barrier(0);

    int tid = threadIdx.x % 64;
    int index_topk[4];
    index_topk[0] = index_ptr[(n_loop * 64) + 0 * 16 + (tid / 4)];
    index_topk[1] = index_ptr[(n_loop * 64) + 1 * 16 + (tid / 4)];
    index_topk[2] = index_ptr[(n_loop * 64) + 2 * 16 + (tid / 4)];
    index_topk[3] = index_ptr[(n_loop * 64) + 3 * 16 + (tid / 4)];

    if constexpr (NeedIndexGuard) {
        int fallback_index = index_ptr[0] == -1 ? 0 : index_ptr[0];
        index_topk[0] = (index_topk[0] == -1) ? fallback_index : index_topk[0];
        index_topk[1] = (index_topk[1] == -1) ? fallback_index : index_topk[1];
        index_topk[2] = (index_topk[2] == -1) ? fallback_index : index_topk[2];
        index_topk[3] = (index_topk[3] == -1) ? fallback_index : index_topk[3];
    }

    // 准备 q,k 寄存器
    union_vec4_f16x2<Element> k_reg[STAGES * (32 * kBlockK) / (32 * 32) * 2];

    // 计算 q_lds,k_lds 的起始偏移量
    int k_lds_base = reinterpret_cast<size_t>(k_lds);

    for(int i=3;i>=0;i--)
    {
    int k_stage_id = 0;

    int lds_offset = __builtin_amdgcn_readfirstlane((warp_id * 32 * 16) * ELEMENT_BYTES / 4);
    int lds_offset_2;
    int g_offset_v = ((4 - (tid / 8) % 4) * 4 + tid % 4 * 4) % 16 + index_topk[i] * seqlen_k_stride * ELEMENT_BYTES / 4;
    int g_offset_s = 512 * ELEMENT_BYTES / 4 + warp_id * 16;
    int g_offset_s_2;
    flash::wait_all_warp_arrived();

    if(warp_id < 2){
        inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset, g_offset_s, g_offset_v); 
    }

    if constexpr (STAGES == 2) {
        k_stage_id ^= 1;
    }

    lds_offset = __builtin_amdgcn_readfirstlane((k_stage_id * 16 * 256 + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
    lds_offset_2 = __builtin_amdgcn_readfirstlane((k_stage_id * 16 * 256 + warp_id * 32 * 16 + 128 * 16) * ELEMENT_BYTES / 4);
    g_offset_s = 256 * ELEMENT_BYTES / 4 + warp_id * 16;
    g_offset_s_2 = 256 * ELEMENT_BYTES / 4 + warp_id * 16 + 64;
    flash::wait_all_warp_arrived();
    inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset, g_offset_s, g_offset_v); 
    inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset_2, g_offset_s_2, g_offset_v); 

    flash::wait_buffer_data_arrived<true>(K_LOAD_REQUESTS);

    k_stage_id ^= 1;
    int stage_id = 0;

    // K DS  
    {
        int k_lds_load_offset = k_lds_base + (k_stage_id * 16 * 256) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
    }

    // Wait DS
    flash::wait_lds_data_arrived<false>(0);
    // flash::raise_priority();

    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[16].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[17].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    // flash::lower_priority();

    lds_offset = __builtin_amdgcn_readfirstlane((k_stage_id * 16 * 256 + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
    lds_offset_2 = __builtin_amdgcn_readfirstlane((k_stage_id * 16 * 256 + warp_id * 32 * 16 + 128 * 16) * ELEMENT_BYTES / 4);
    g_offset_s = 0 * ELEMENT_BYTES / 4 + warp_id * 16;
    g_offset_s_2 = 0 * ELEMENT_BYTES / 4 + warp_id * 16 + 64;
    flash::wait_all_warp_arrived();
    inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset, g_offset_s, g_offset_v); 
    inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset_2, g_offset_s_2, g_offset_v); 

    flash::wait_buffer_data_arrived<true>(K_LOAD_REQUESTS);

    k_stage_id ^= 1;
    stage_id = 0;

    // K DS  
    {
        int k_lds_load_offset = k_lds_base + (k_stage_id * 16 * 256) * ELEMENT_BYTES;
        int k_lds_load_offset_2 = k_lds_base + (k_stage_id * 16 * 256 + 16 * 64) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
    }

    // K DS PRE
    stage_id ^= 1;
    {
        int k_lds_load_offset = k_lds_base + (k_stage_id * 16 * 256 + 16 * 128) * ELEMENT_BYTES;
        int k_lds_load_offset_2 = k_lds_base + (k_stage_id * 16 * 256 + 16 * 192) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
    }
                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                       
    // Wait DS
    flash::wait_lds_data_arrived<false>(6);
    // flash::raise_priority();

    // MMAC 
    stage_id ^= 1;
    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[8].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[9].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    // flash::lower_priority();
    flash::wait_lds_data_arrived<false>(4);
    // flash::raise_priority();

    {
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[10].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[11].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    // flash::lower_priority();
    flash::wait_lds_data_arrived<false>(2);
    // flash::raise_priority();

    stage_id ^= 1;
    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[12].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[13].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    // flash::lower_priority();
    flash::wait_lds_data_arrived<false>(0);
    // flash::raise_priority();

    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[14].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[15].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }
    // flash::lower_priority();

    flash::wait_buffer_data_arrived<true>(0);

    k_stage_id ^= 1;
    stage_id = 0;

    // K DS  
    {
        int k_lds_load_offset = k_lds_base + (k_stage_id * 16 * 256) * ELEMENT_BYTES;
        int k_lds_load_offset_2 = k_lds_base + (k_stage_id * 16 * 256 + 16 * 64) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
    }

    // K DS PRE
    stage_id ^= 1;
    {
        int k_lds_load_offset = k_lds_base + (k_stage_id * 16 * 256 + 16 * 128) * ELEMENT_BYTES;
        int k_lds_load_offset_2 = k_lds_base + (k_stage_id * 16 * 256 + 16 * 192) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
    }
                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                       
    // Wait DS
    flash::wait_lds_data_arrived<false>(6);
    // flash::raise_priority();

    // MMAC 
    stage_id ^= 1;
    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[0].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[1].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    // flash::lower_priority();
    flash::wait_lds_data_arrived<false>(4);
    // flash::raise_priority();

    {
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[2].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[3].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    // flash::lower_priority();
    flash::wait_lds_data_arrived<false>(2);
    // flash::raise_priority();

    stage_id ^= 1;
    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[4].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[5].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    // flash::lower_priority();
    flash::wait_lds_data_arrived<false>(0);
    // flash::raise_priority();

    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[6].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[7].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }
    // flash::lower_priority();
    }
}

template<int kHeadDim, int kHeadDimV, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, int STAGES, typename Element, typename ElementAccum, bool Is_even_MN, bool Is_FlashMLA, bool DecodeCLoad = false>
__forceinline__ __device__ void qk_gemm_prefetch_v_mls_ds_576_512_nopage_64_new_888(
        vec4_uint qv_ptr,
        vec4_uint q_ptr,
        vec4_uint k_ptr,
        Element* k_ptr_raw,
        Element* q_lds,
        Element* k_lds,
        Element* v_lds,
        union_vec4_f16x2<Element> q_reg[(WARP_M * kBlockK) / (16 * 32) * (kHeadDim / kBlockK)],
        vec4_Accum<ElementAccum> s_reg[(WARP_M / 16) * (kBlockN / 32)][2],
        int warp_id,
        int seqlen_qv_stride,
        int __seqlen_q_stride,
        int seqlen_k_stride,
        int seqlen_v_stride,
        int* index_ptr,
        int batch_stride_k,
        int batch_stride_v,
        int page_block_size,
        int n_loop,
        int max_seq_q_offset=0,
        int max_seq_k_offset=0) {

    // Simplify
    static_assert (kBlockK == 64 and "To simplify, only kBlockK = 32 is supported!");
    static_assert (WARP_M == 16 and "To simplify, only WARP_M = 16 is supported!");
    static_assert (WARP_N == 64 and "To simplify, only WARP_N = 64 is supported!");
    constexpr int WARP_NUM        = kBlockM / WARP_M;
    constexpr int kHeadDim_OPT       = (kHeadDim == 512) ? 64 : kHeadDim;
    constexpr int Q_LDS_LOAD_NUM  = (kBlockM * kBlockK) / (16 * 32);
    constexpr int Q_LOAD_REQUESTS = Q_LDS_LOAD_NUM / WARP_NUM;
    constexpr int K_LDS_LOAD_NUM  = (kHeadDim_OPT * WARP_N) / (32 * 16);
    constexpr int K_LOAD_REQUESTS = K_LDS_LOAD_NUM / WARP_NUM;
    constexpr int ELEMENT_BYTES   = sizeof(Element);

    __builtin_amdgcn_sched_barrier(0);
    if constexpr (kBlockN == 128) {
        inline_vgpr4_init_zero_4x4x4(s_reg);
    } else {
        for (int i = 0; i < (WARP_M / 16) * (kBlockN / 32); ++i) {
            for (int j = 0; j < 2; ++j) {
                s_reg[i][j].u64[0] = 0.0f;
                s_reg[i][j].u64[1] = 0.0f;
            }
        }
    }
    __builtin_amdgcn_sched_barrier(0);

    int tid = threadIdx.x % 64;
    int index_topk[4];
    index_topk[0] = index_ptr[(n_loop * 64) + 0 * 16 + (tid / 4)];
    index_topk[1] = index_ptr[(n_loop * 64) + 1 * 16 + (tid / 4)];
    index_topk[2] = index_ptr[(n_loop * 64) + 2 * 16 + (tid / 4)];
    index_topk[3] = index_ptr[(n_loop * 64) + 3 * 16 + (tid / 4)];

    bool invalid_topk[4];
    invalid_topk[0] = index_topk[0] == -1;
    invalid_topk[1] = index_topk[1] == -1;
    invalid_topk[2] = index_topk[2] == -1;
    invalid_topk[3] = index_topk[3] == -1;

    int fallback_index = index_ptr[0] == -1 ? 0 : index_ptr[0];
    index_topk[0] = (index_topk[0] == -1) ? fallback_index : index_topk[0];
    index_topk[1] = (index_topk[1] == -1) ? fallback_index : index_topk[1];
    index_topk[2] = (index_topk[2] == -1) ? fallback_index : index_topk[2];
    index_topk[3] = (index_topk[3] == -1) ? fallback_index : index_topk[3];

    // 准备 q,k 寄存器
    union_vec4_f16x2<Element> k_reg[STAGES * (32 * kBlockK) / (32 * 32) * 2];

    // 计算 q_lds,k_lds 的起始偏移量
    int k_lds_base = reinterpret_cast<size_t>(k_lds);

    int k_stage_id = 0;
    int stage_id;
    using uint4_t = unsigned int __attribute__((ext_vector_type(4)));
    const uint4_t zero4 = {0u, 0u, 0u, 0u};

    int index_block = index_topk[3] / page_block_size;
    int index_offset = index_topk[3] - index_block * page_block_size;
    int g_offset_v = ((4 - (tid / 8) % 4) * 4 + tid % 4 * 4) % 16
        + (index_block * batch_stride_k + index_offset * seqlen_k_stride) * ELEMENT_BYTES / 4;
    int lds_offset = __builtin_amdgcn_readfirstlane((k_stage_id * 16 * 256 + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
    int lds_offset_2 = __builtin_amdgcn_readfirstlane((k_stage_id * 16 * 256 + warp_id * 32 * 16 + 128 * 16) * ELEMENT_BYTES / 4);
    int g_offset_s = 256 * ELEMENT_BYTES / 4 + warp_id * 16;
    int g_offset_s_2 = 256 * ELEMENT_BYTES / 4 + warp_id * 16 + 64;
    flash::wait_all_warp_arrived();
    if constexpr (DecodeCLoad) {
        const int64_t token_base_elem = int64_t(index_block) * batch_stride_k + int64_t(index_offset) * seqlen_k_stride;
        const int64_t src0_elem = token_base_elem + int64_t(g_offset_s + (((4 - (tid / 8) % 4) * 4 + tid % 4 * 4) % 16)) * 4 / ELEMENT_BYTES;
        const int64_t src1_elem = token_base_elem + int64_t(g_offset_s_2 + (((4 - (tid / 8) % 4) * 4 + tid % 4 * 4) % 16)) * 4 / ELEMENT_BYTES;
        const int64_t lane_store_elem = int64_t(tid) * 16 / ELEMENT_BYTES;
        const int64_t dst0_elem = int64_t(lds_offset) * 4 / ELEMENT_BYTES + lane_store_elem;
        const int64_t dst1_elem = int64_t(lds_offset_2) * 4 / ELEMENT_BYTES + lane_store_elem;
        *reinterpret_cast<uint4_t*>(k_lds + dst0_elem) = invalid_topk[3] ? zero4 : *reinterpret_cast<const uint4_t*>(k_ptr_raw + src0_elem);
        *reinterpret_cast<uint4_t*>(k_lds + dst1_elem) = invalid_topk[3] ? zero4 : *reinterpret_cast<const uint4_t*>(k_ptr_raw + src1_elem);
    } else {
        inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset, g_offset_s, g_offset_v); 
        inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset_2, g_offset_s_2, g_offset_v); 
    }

    k_stage_id ^= 1;

    // #pragma unroll 1
    for(int i=6;i>=0;i--)
    {
    int score_id = (i + 1) >> 1;

    index_block = index_topk[i / 2] / page_block_size;
    index_offset = index_topk[i / 2] - index_block * page_block_size;
    g_offset_v = ((4 - (tid / 8) % 4) * 4 + tid % 4 * 4) % 16
        + (index_block * batch_stride_k + index_offset * seqlen_k_stride) * ELEMENT_BYTES / 4;
    lds_offset = __builtin_amdgcn_readfirstlane((k_stage_id * 16 * 256 + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
    lds_offset_2 = __builtin_amdgcn_readfirstlane((k_stage_id * 16 * 256 + warp_id * 32 * 16 + 128 * 16) * ELEMENT_BYTES / 4);
    g_offset_s = (i % 2) * 256 * ELEMENT_BYTES / 4 + warp_id * 16;
    g_offset_s_2 = (i % 2) * 256  * ELEMENT_BYTES / 4 + warp_id * 16 + 64;
    flash::wait_all_warp_arrived();
    if constexpr (DecodeCLoad) {
        const int64_t token_base_elem = int64_t(index_block) * batch_stride_k + int64_t(index_offset) * seqlen_k_stride;
        const int lane_dword = ((4 - (tid / 8) % 4) * 4 + tid % 4 * 4) % 16;
        const int64_t src0_elem = token_base_elem + int64_t(g_offset_s + lane_dword) * 4 / ELEMENT_BYTES;
        const int64_t src1_elem = token_base_elem + int64_t(g_offset_s_2 + lane_dword) * 4 / ELEMENT_BYTES;
        const int64_t lane_store_elem = int64_t(tid) * 16 / ELEMENT_BYTES;
        const int64_t dst0_elem = int64_t(lds_offset) * 4 / ELEMENT_BYTES + lane_store_elem;
        const int64_t dst1_elem = int64_t(lds_offset_2) * 4 / ELEMENT_BYTES + lane_store_elem;
        const bool invalid_index = invalid_topk[i / 2];
        *reinterpret_cast<uint4_t*>(k_lds + dst0_elem) = invalid_index ? zero4 : *reinterpret_cast<const uint4_t*>(k_ptr_raw + src0_elem);
        *reinterpret_cast<uint4_t*>(k_lds + dst1_elem) = invalid_index ? zero4 : *reinterpret_cast<const uint4_t*>(k_ptr_raw + src1_elem);
    } else {
        inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset, g_offset_s, g_offset_v); 
        inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset_2, g_offset_s_2, g_offset_v); 
    }

    if constexpr (DecodeCLoad) {
        flash::wait_all_warp_arrived();
    } else {
        flash::wait_buffer_data_arrived<true>(K_LOAD_REQUESTS);
    }

    k_stage_id ^= 1;
    stage_id = 0;

    // K DS  
    {
        int k_lds_load_offset = k_lds_base + (k_stage_id * 16 * 256) * ELEMENT_BYTES;
        int k_lds_load_offset_2 = k_lds_base + (k_stage_id * 16 * 256 + 16 * 64) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
    }

    // K DS PRE
    stage_id ^= 1;
    {
        int k_lds_load_offset = k_lds_base + (k_stage_id * 16 * 256 + 16 * 128) * ELEMENT_BYTES;
        int k_lds_load_offset_2 = k_lds_base + (k_stage_id * 16 * 256 + 16 * 192) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
    }
                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                       
    // Wait DS
    flash::wait_lds_data_arrived<false>(6);
    flash::raise_priority();

    // MMAC 
    stage_id ^= 1;
    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[score_id / 2][score_id % 2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[((i + 1) % 2) * 8 + 0].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[score_id / 2][score_id % 2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[score_id / 2][score_id % 2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[((i + 1) % 2) * 8 + 1].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[score_id / 2][score_id % 2].f32);
        }
    }

    flash::lower_priority();
    flash::wait_lds_data_arrived<false>(4);
    flash::raise_priority();

    {
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[score_id / 2][score_id % 2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[((i + 1) % 2) * 8 + 2].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[score_id / 2][score_id % 2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[score_id / 2][score_id % 2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[((i + 1) % 2) * 8 + 3].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[score_id / 2][score_id % 2].f32);
        }
    }

    flash::lower_priority();
    flash::wait_lds_data_arrived<false>(2);
    flash::raise_priority();

    stage_id ^= 1;
    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[score_id / 2][score_id % 2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[((i + 1) % 2) * 8 + 4].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[score_id / 2][score_id % 2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[score_id / 2][score_id % 2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[((i + 1) % 2) * 8 + 5].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[score_id / 2][score_id % 2].f32);
        }
    }

    flash::lower_priority();
    flash::wait_lds_data_arrived<false>(0);
    flash::raise_priority();

    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[score_id / 2][score_id % 2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[((i + 1) % 2) * 8 + 6].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[score_id / 2][score_id % 2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[score_id / 2][score_id % 2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[((i + 1) % 2) * 8 + 7].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[score_id / 2][score_id % 2].f32);
        }
    }
    flash::lower_priority();
    }

    flash::wait_buffer_data_arrived<true>(0);

    k_stage_id ^= 1;
    stage_id = 0;

    // K DS  
    {
        int k_lds_load_offset = k_lds_base + (k_stage_id * 16 * 256) * ELEMENT_BYTES;
        int k_lds_load_offset_2 = k_lds_base + (k_stage_id * 16 * 256 + 16 * 64) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
    }

    // K DS PRE
    stage_id ^= 1;
    {
        int k_lds_load_offset = k_lds_base + (k_stage_id * 16 * 256 + 16 * 128) * ELEMENT_BYTES;
        int k_lds_load_offset_2 = k_lds_base + (k_stage_id * 16 * 256 + 16 * 192) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
    }
                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                       
    // Wait DS
    flash::wait_lds_data_arrived<false>(6);
    flash::raise_priority();

    // MMAC 
    stage_id ^= 1;
    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[0][0].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[0].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[0][0].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[0][0].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[1].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[0][0].f32);
        }
    }

    flash::lower_priority();
    flash::wait_lds_data_arrived<false>(4);
    flash::raise_priority();

    {
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[0][0].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[2].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[0][0].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[0][0].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[3].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[0][0].f32);
        }
    }

    flash::lower_priority();
    flash::wait_lds_data_arrived<false>(2);
    flash::raise_priority();

    stage_id ^= 1;
    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[0][0].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[4].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[0][0].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[0][0].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[5].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[0][0].f32);
        }
    }

    flash::lower_priority();
    flash::wait_lds_data_arrived<false>(0);
    flash::raise_priority();

    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[0][0].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[6].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[0][0].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[0][0].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[7].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[0][0].f32);
        }
    }
    flash::lower_priority();
}


template<int kHeadDim, int kHeadDimV, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, int STAGES, typename Element, typename ElementAccum, bool Is_even_MN, bool Is_FlashMLA>
__forceinline__ __device__ void qk_gemm_prefetch_v_mls_ds_576_512_nopage_64_new_999(
        vec4_uint qv_ptr,
        vec4_uint q_ptr,
        vec4_uint k_ptr,
        Element* v_faker,
        Element* q_lds,
        Element* k_lds,
        Element* v_lds,
        union_vec4_f16x2<Element> q_reg[(WARP_M * kBlockK) / (16 * 32) * (kHeadDim / kBlockK)],
        vec4_Accum<ElementAccum> s_reg[(WARP_M / 16) * (kBlockN / 32)][2],
        int warp_id,
        int seqlen_qv_stride,
        int __seqlen_q_stride,
        int seqlen_k_stride,
        int seqlen_v_stride,
        int* index_ptr,
        int batch_stride_k,
        int batch_stride_v,
        int page_block_size,
        int n_loop,
        int max_seq_q_offset=0,
        int max_seq_k_offset=0) {

    // Simplify
    static_assert (kBlockK == 64 and "To simplify, only kBlockK = 32 is supported!");
    static_assert (WARP_M == 16 and "To simplify, only WARP_M = 16 is supported!");
    static_assert (WARP_N == 64 and "To simplify, only WARP_N = 64 is supported!");
    constexpr int WARP_NUM        = kBlockM / WARP_M;
    constexpr int kHeadDim_OPT       = (kHeadDim == 576) ? 64 : kHeadDim;
    constexpr int Q_LDS_LOAD_NUM  = (kBlockM * kBlockK) / (16 * 32);
    constexpr int Q_LOAD_REQUESTS = Q_LDS_LOAD_NUM / WARP_NUM;
    constexpr int K_LDS_LOAD_NUM  = (kHeadDim_OPT * WARP_N) / (32 * 16);
    constexpr int K_LOAD_REQUESTS = K_LDS_LOAD_NUM / WARP_NUM;
    constexpr int ELEMENT_BYTES   = sizeof(Element);

    __builtin_amdgcn_sched_barrier(0);
    if constexpr (kBlockN == 128) {
        inline_vgpr4_init_zero_4x4x4(s_reg);
    } else {
        for (int i = 0; i < (WARP_M / 16) * (kBlockN / 32); ++i) {
            for (int j = 0; j < 2; ++j) {
                s_reg[i][j].u64[0] = 0.0f;
                s_reg[i][j].u64[1] = 0.0f;
            }
        }
    }
    __builtin_amdgcn_sched_barrier(0);

    int tid = threadIdx.x % 64;
    int index_topk[4];
    index_topk[0] = index_ptr[(n_loop * 64) + 0 * 16 + (tid / 4)];
    index_topk[1] = index_ptr[(n_loop * 64) + 1 * 16 + (tid / 4)];
    index_topk[2] = index_ptr[(n_loop * 64) + 2 * 16 + (tid / 4)];
    index_topk[3] = index_ptr[(n_loop * 64) + 3 * 16 + (tid / 4)];

    int fallback_index = index_ptr[0] == -1 ? 0 : index_ptr[0];
    index_topk[0] = (index_topk[0] == -1) ? fallback_index : index_topk[0];
    index_topk[1] = (index_topk[1] == -1) ? fallback_index : index_topk[1];
    index_topk[2] = (index_topk[2] == -1) ? fallback_index : index_topk[2];
    index_topk[3] = (index_topk[3] == -1) ? fallback_index : index_topk[3];

    // 准备 q,k 寄存器
    union_vec4_f16x2<Element> k_reg[STAGES * (32 * kBlockK) / (32 * 32) * 2];

    // 计算 q_lds,k_lds 的起始偏移量
    int k_lds_base = reinterpret_cast<size_t>(k_lds);

    int k_stage_id = 0;

    int lds_offset = __builtin_amdgcn_readfirstlane((warp_id * 32 * 16) * ELEMENT_BYTES / 4);
    int lds_offset_2;
    int index_block = index_topk[3] / page_block_size;
    int index_offset = index_topk[3] - index_block * page_block_size;
    int g_offset_v = ((4 - (tid / 8) % 4) * 4 + tid % 4 * 4) % 16
        + (index_block * batch_stride_k + index_offset * seqlen_k_stride) * ELEMENT_BYTES / 4;
    int g_offset_s = 512 * ELEMENT_BYTES / 4 + warp_id * 16;
    int g_offset_s_2;
    flash::wait_all_warp_arrived();
    if(warp_id<2)
    {
        inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset, g_offset_s, g_offset_v); 
    }

    if constexpr (STAGES == 2) {
        k_stage_id ^= 1;
    }
{
    #pragma unroll 1
    for(int i = 3;i >= 0;i--)
    {
    lds_offset = __builtin_amdgcn_readfirstlane((k_stage_id * 16 * 256 + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
    lds_offset_2 = __builtin_amdgcn_readfirstlane((k_stage_id * 16 * 256 + warp_id * 32 * 16 + 128 * 16) * ELEMENT_BYTES / 4);
    g_offset_s = 256 * ELEMENT_BYTES / 4 + warp_id * 16;
    g_offset_s_2 = 256 * ELEMENT_BYTES / 4 + warp_id * 16 + 64;
    flash::wait_all_warp_arrived();
    inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset, g_offset_s, g_offset_v); 
    inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset_2, g_offset_s_2, g_offset_v); 

    flash::wait_buffer_data_arrived<true>(K_LOAD_REQUESTS);

    k_stage_id ^= 1;
    int stage_id = 0;

    // K DS  
    {
        int k_lds_load_offset = k_lds_base + (k_stage_id * 16 * 256) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
    }

    // Wait DS
    flash::wait_lds_data_arrived<false>(0);
    flash::raise_priority();

    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[16].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[17].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    flash::lower_priority();

    lds_offset = __builtin_amdgcn_readfirstlane((k_stage_id * 16 * 256 + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
    lds_offset_2 = __builtin_amdgcn_readfirstlane((k_stage_id * 16 * 256 + warp_id * 32 * 16 + 128 * 16) * ELEMENT_BYTES / 4);
    g_offset_s = 0 * ELEMENT_BYTES / 4 + warp_id * 16;
    g_offset_s_2 = 0 * ELEMENT_BYTES / 4 + warp_id * 16 + 64;
    flash::wait_all_warp_arrived();
    inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset, g_offset_s, g_offset_v); 
    inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset_2, g_offset_s_2, g_offset_v); 

    flash::wait_buffer_data_arrived<true>(K_LOAD_REQUESTS);

    k_stage_id ^= 1;
    stage_id = 0;

    // K DS  
    {
        int k_lds_load_offset = k_lds_base + (k_stage_id * 16 * 256) * ELEMENT_BYTES;
        int k_lds_load_offset_2 = k_lds_base + (k_stage_id * 16 * 256 + 16 * 64) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
    }

    // K DS PRE
    stage_id ^= 1;
    {
        int k_lds_load_offset = k_lds_base + (k_stage_id * 16 * 256 + 16 * 128) * ELEMENT_BYTES;
        int k_lds_load_offset_2 = k_lds_base + (k_stage_id * 16 * 256 + 16 * 192) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
    }
                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                       
    // Wait DS
    flash::wait_lds_data_arrived<false>(6);
    flash::raise_priority();

    // MMAC 
    stage_id ^= 1;
    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[8].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[9].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    flash::lower_priority();
    flash::wait_lds_data_arrived<false>(4);
    flash::raise_priority();

    {
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[10].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[11].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    flash::lower_priority();
    flash::wait_lds_data_arrived<false>(2);
    flash::raise_priority();

    stage_id ^= 1;
    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[12].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[13].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    flash::lower_priority();
    flash::wait_lds_data_arrived<false>(0);
    flash::raise_priority();

    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[14].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[15].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }
    flash::lower_priority();

    if(i != 0){
        lds_offset = __builtin_amdgcn_readfirstlane((k_stage_id * 16 * 256 + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
        index_block = index_topk[i - 1] / page_block_size;
        index_offset = index_topk[i - 1] - index_block * page_block_size;
        g_offset_v = ((4 - (tid / 8) % 4) * 4 + tid % 4 * 4) % 16
            + (index_block * batch_stride_k + index_offset * seqlen_k_stride) * ELEMENT_BYTES / 4;
        g_offset_s = 512 * ELEMENT_BYTES / 4 + warp_id * 16;
        flash::wait_all_warp_arrived();

        if(warp_id<2){
            inline_buffer_load_dwordx4_lds(k_lds, k_ptr, lds_offset, g_offset_s, g_offset_v); 
            flash::wait_buffer_data_arrived<true>(1);
        }
        else{
            flash::wait_buffer_data_arrived<true>(0);
        }
    }
    else{
        flash::wait_buffer_data_arrived<true>(0);
    }

    k_stage_id ^= 1;
    stage_id = 0;

    // K DS  
    {
        int k_lds_load_offset = k_lds_base + (k_stage_id * 16 * 256) * ELEMENT_BYTES;
        int k_lds_load_offset_2 = k_lds_base + (k_stage_id * 16 * 256 + 16 * 64) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
    }

    // K DS PRE
    stage_id ^= 1;
    {
        int k_lds_load_offset = k_lds_base + (k_stage_id * 16 * 256 + 16 * 128) * ELEMENT_BYTES;
        int k_lds_load_offset_2 = k_lds_base + (k_stage_id * 16 * 256 + 16 * 192) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset, k_reg[stage_id * 2].f16, k_reg[stage_id * 2 + 1].f16, true);
        DS_READ_MATRIX_32X32_B16(k_lds_load_offset_2, k_reg[4 + stage_id * 2].f16, k_reg[4 + stage_id * 2 + 1].f16, true);
    }
                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                       
    // Wait DS
    flash::wait_lds_data_arrived<false>(6);
    flash::raise_priority();

    // MMAC 
    stage_id ^= 1;
    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[0].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[1].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    flash::lower_priority();
    flash::wait_lds_data_arrived<false>(4);
    flash::raise_priority();

    {
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[2].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[3].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    flash::lower_priority();
    flash::wait_lds_data_arrived<false>(2);
    flash::raise_priority();

    stage_id ^= 1;
    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[4].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[5].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    flash::lower_priority();
    flash::wait_lds_data_arrived<false>(0);
    flash::raise_priority();

    { 
        int min_tile_n = 0;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[6].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }

    { 
        int min_tile_n = 1;
        #pragma unroll
        for(int min_tile_k = 0; min_tile_k < 2; ++min_tile_k) {
                int k_tile_id  = 4 + stage_id * 2 + min_tile_n;
                s_reg[i/2][i%2].f32 = mmac_4interleave<Element, ElementAccum>(
                    q_reg[7].f16x4[min_tile_k],
                    k_reg[k_tile_id].f16x4[min_tile_k],
                    s_reg[i/2][i%2].f32);
        }
    }
    flash::lower_priority();
    }
}

}

template<int kHeadDim, int kHeadDimV, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, int STAGES, typename Element, typename ElementAccum, bool Is_even_MN, bool Is_FlashMLA>
__forceinline__ __device__ void qk_gemm_prefetch_v_mls_ds_576_512_nopage_64_new_q(
        vec4_uint qv_ptr,
        vec4_uint q_ptr,
        vec4_uint k_ptr,
        vec4_uint v_ptr,
        Element* q_lds,
        Element* k_lds,
        Element* v_lds,
        union_vec4_f16x2<Element> q_reg[(WARP_M * kBlockK) / (16 * 64) * (kHeadDim / kBlockK)],
        int warp_id,
        int seqlen_qv_stride,
        int __seqlen_q_stride,
        int seqlen_k_stride,
        int seqlen_v_stride,
        int* index_ptr,
        int batch_stride_k,
        int batch_stride_v,
        int max_seq_q_offset=0) {

    // Simplify
    static_assert (kBlockK == 64 and "To simplify, only kBlockK = 32 is supported!");
    static_assert (WARP_M == 16 and "To simplify, only WARP_M = 16 is supported!");
    static_assert (WARP_N == 64 and "To simplify, only WARP_N = 64 is supported!");
    constexpr int WARP_NUM        = kBlockM / WARP_M;
    constexpr int kHeadDim_OPT       = 32;
    constexpr int Q_LDS_LOAD_NUM  = (kBlockM * kBlockK) / (16 * 32);
    constexpr int Q_LOAD_REQUESTS = Q_LDS_LOAD_NUM / WARP_NUM;
    constexpr int K_LDS_LOAD_NUM  = (kHeadDim_OPT * WARP_N) / (32 * 16);
    constexpr int K_LOAD_REQUESTS = K_LDS_LOAD_NUM / WARP_NUM;
    constexpr int ELEMENT_BYTES   = sizeof(Element);
    constexpr int WARP_NUM_M = 1; 
    constexpr int WARP_NUM_N = 4;
    int warp_id_m = warp_id / WARP_NUM_N;
    int warp_id_n = warp_id % WARP_NUM_N;

    // 计算 q_lds,k_lds 的起始偏移量
    int q_lds_base = reinterpret_cast<size_t>(q_lds);

    int tid = threadIdx.x % 64;
    // MLS
    vec4_uint q_srsrc;
    vec4_uint q_srsrc2;

    q_srsrc[2] = __seqlen_q_stride;
    q_srsrc2[2] = __seqlen_q_stride;

    q_srsrc[3] = 0; 
    q_srsrc2[3] = 0;

    int q_stage_id = 0;

    if constexpr (STAGES == 2) {
        q_stage_id ^= 1;
    }

    {   
        for(int k_loop = 1; k_loop < (kHeadDim / kBlockK); ++k_loop) {
            
            {
                uint64_t q_base_addr;
                int seqlen_q_stride;
                int kloop_true;
                if constexpr (Is_FlashMLA) {
                    q_srsrc[2] = __seqlen_q_stride;
                    q_base_addr = *(uint64_t*)&q_ptr;
                    seqlen_q_stride = __seqlen_q_stride;
                    kloop_true = k_loop;
                } else {
                    q_srsrc[2] = (k_loop >= 2) ? seqlen_qv_stride : __seqlen_q_stride;
                    q_base_addr = (k_loop >= 2) ? *(uint64_t*)&qv_ptr : *(uint64_t*)&q_ptr;
                    seqlen_q_stride = (k_loop >= 2) ? seqlen_qv_stride : __seqlen_q_stride;
                    kloop_true = (k_loop >= 2) ? (k_loop - 2) : (k_loop);
                }

                *(uint64_t*)&q_srsrc = VA_LIMIT_BITS(q_base_addr + (kloop_true * kBlockK + warp_id * 16 * seqlen_q_stride) * ELEMENT_BYTES);
                *(uint64_t*)&q_srsrc2 = VA_LIMIT_BITS(q_base_addr + (kloop_true * kBlockK + warp_id * 16 * seqlen_q_stride + 32) * ELEMENT_BYTES);
                // int nm_filter = inline_min_max<0,16>(16 * warp_id + 16 - max_seq_q_offset);
                // q_srsrc[3] = max_seq_q_offset % kBlockM == 0 ? 0: nm_filter << 8;
                int lds_offset = (q_stage_id * kBlockM * kBlockK + warp_id * 16 * 64) * ELEMENT_BYTES;
                int lds_offset2 = (q_stage_id * kBlockM * kBlockK + warp_id * 16 * 64 + 16 * 32) * ELEMENT_BYTES;
                flash::wait_all_warp_arrived();
                inline_matrix_load_32x16_b16_lds_trans<0, 1>(q_lds, q_srsrc, lds_offset, 0);
                inline_matrix_load_32x16_b16_lds_trans<0, 1>(q_lds, q_srsrc2, lds_offset2, 0);
            }

            // 不对称MLS指令
            flash::wait_buffer_data_arrived<true>(Q_LOAD_REQUESTS);
            
            q_stage_id ^= 1;

            // Q DS
            {
                int q_lds_load_offset = q_lds_base + (q_stage_id * kBlockM * kBlockK + warp_id * 16 * 64) * ELEMENT_BYTES;
                int q_lds_load_offset2 = q_lds_base + (q_stage_id * kBlockM * kBlockK + warp_id * 16 * 64 + 16 * 32) * ELEMENT_BYTES;
                DS_READ_MATRIX_32X16_B16(q_lds_load_offset, q_reg[(k_loop-1) * 2 + 0].f16, true);  
                DS_READ_MATRIX_32X16_B16(q_lds_load_offset2, q_reg[(k_loop-1) * 2 + 1].f16, true);  
            }

            // Wait DS
            flash::wait_lds_data_arrived<false>(0);
        }

        // 等回最后的q_panel
        flash::wait_buffer_data_arrived<true>(0);

        // Q DS
        q_stage_id ^= 1;
        {
            int q_lds_load_offset = q_lds_base + (q_stage_id * kBlockM * kBlockK + warp_id * 16 * 64) * ELEMENT_BYTES;
            int q_lds_load_offset2 = q_lds_base + (q_stage_id * kBlockM * kBlockK + warp_id * 16 * 64 + 16 * 32) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X16_B16(q_lds_load_offset, q_reg[(kHeadDim / kBlockK - 1) * 2 + 0].f16, true);  
            DS_READ_MATRIX_32X16_B16(q_lds_load_offset2, q_reg[(kHeadDim / kBlockK - 1) * 2 + 1].f16, true);  
        }

        // Wait DS
        flash::wait_lds_data_arrived<false>(0);
    }
}
