#include "mla_qk_gemm_utils_mls_ds.h"
#include "static_switch.h"


template<bool PREFETCH_K, int kHeadDim, int kHeadDimV, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, int STAGES, typename Element, typename ElementAccum, bool Is_even_MN>
__forceinline__ __device__ void pv_gemm_prefetch_k_mls_ds_576_512(
        vec4_uint q_ptr,
        vec4_uint k_ptr,
        vec4_uint v_ptr,
        Element* q_lds,
        Element* k_lds,
        Element* v_lds,
        union_vec2_f16x2<Element> p_reg[(WARP_M / 16) * (kBlockK / 32)][2],
        vec4_Accum<ElementAccum> pv_reg[(kHeadDimV / kBlockN) * (WARP_M / 16) * (kBlockN / 32)][2],
        int warp_id,
        int seqlen_q_stride,
        int seqlen_k_stride,
        int seqlen_v_stride,
        int* index_ptr,
        int* block_table,
        int batch_stride,
        int page_block_size,
        int n_loop_real,
        int max_seq_q_offset=0,
        int max_seq_kv_offset=0) {

    constexpr int WARP_NUM = kBlockM * kBlockN / (WARP_M * WARP_N);
    constexpr int WARP_K   = 32;
    constexpr int READ_ONCE_COUNT = 32 * 32;
    constexpr int kHeadDimV_OPT = 256;          // lds 32x32x8x2B == 16KB
    constexpr int V_LDS_LOAD_NUM  = (kHeadDimV_OPT * WARP_K) / READ_ONCE_COUNT;
    constexpr int V_LOAD_REQUESTS = V_LDS_LOAD_NUM / WARP_NUM;
    constexpr int ELEMENT_BYTES   = sizeof(Element);
    static_assert (kBlockK >= 32, "Error: pv gemm kBlockK must be equal or greater than 32");
    static_assert (kBlockM >= WARP_M, "Error: pv gemm kBlockM must be equal or greater than WARP_M");
    static_assert (kBlockN == WARP_N, "Error: pv gemm kBlockN must be equal to WARP_N");
    static_assert (WARP_K == 32 and "Error: To simplify, only WARP_K = 32 is supported!");
    static_assert (WARP_M == 16 and "Error: To simplify, only WARP_M = 16 is supported!");
    static_assert (WARP_N == 32 and "Error: To simplify, only WARP_N = 32 is supported!");

    // 计算 V lds 起始偏移量
    int v_lds_base = reinterpret_cast<size_t>(v_lds);

    int tid = threadIdx.x % 64;
    // 准备 V 寄存器
    union_vec4_f16x2<Element> v_reg[STAGES * (32 * WARP_N) / (32 * 32) * 2];

    // MLS
    vec4_uint v_srsrc;
    v_srsrc[0] = v_ptr[0];
    v_srsrc[1] = v_ptr[1];
    v_srsrc[2] = seqlen_v_stride; // stride
    v_srsrc[3] = 0;

    int lds_stage_id = 1;
    for (int n_loop = 1; n_loop < (kBlockK / WARP_K); ++n_loop) {
        // prefetch same warpk, next 32x256 G2S
        {   
            int n_load = 1;
            int n_loop_ = n_loop - 1;
            // *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + n_load * WARP_NUM * 32) * ELEMENT_BYTES);
            // if constexpr (true) {
            //     int nm_filter     = inline_min_max<0, 32>(n_loop_ * WARP_K + 32 - max_seq_kv_offset);
            //     v_srsrc[3]        = max_seq_kv_offset % kBlockK == 0 ? 0: nm_filter << 8;
            // }
            // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
            // flash::wait_all_warp_arrived();
            // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

            int index_topk_1 = index_ptr[n_loop_real * 64 + (tid / 4)];
            int index_topk_2 = index_ptr[n_loop_real * 64 + (tid / 4) + 16];

            int lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            int g_offset_v = n_load * WARP_NUM * 16 + warp_id * 16 + tid % 4 * 4 + block_table[index_topk_1/128] * batch_stride * ELEMENT_BYTES / 4 + (index_topk_1 % 128) * seqlen_v_stride * ELEMENT_BYTES / 4;
            int lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            int g_offset_v_add = n_load * WARP_NUM * 16 + warp_id * 16 + tid % 4 * 4 + block_table[index_topk_2/128] * batch_stride * ELEMENT_BYTES / 4 + (index_topk_2 % 128) * seqlen_v_stride * ELEMENT_BYTES / 4;
            flash::wait_all_warp_arrived();
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
        }
        
        // DS
        lds_stage_id ^= 1;
        int stage_id = 0;
        flash::wait_buffer_data_arrived<true>(V_LOAD_REQUESTS*2);

        int lds_load_offset = v_lds_base + (0/*k_loop*/ * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);

        stage_id ^= 1;
        for (int k_loop = 1; k_loop < (kHeadDimV / kBlockN); ++k_loop) {

            // Wait for special headdim
            if ((k_loop & 7) == 0x0) {
                flash::wait_buffer_data_arrived<true>(0);   
            }

            int lds_load_offset = v_lds_base + (k_loop * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);
            flash::wait_lds_data_arrived<false>(3);

            // MMAC
            flash::raise_priority();
            stage_id ^= 1;
            {
                constexpr int min_tile_k = 0;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::wait_lds_data_arrived<false>(2);
            {
                constexpr int min_tile_k = 1;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::lower_priority();

            // MLS for special headdimV
            if ((k_loop & 7) == 0x0) {
                int n_loop_ = n_loop;
                    
                // if constexpr (Is_even_MN) {
                //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
                // } else {
                //     int nm_filter_max = n_loop_ * WARP_K + 32 - max_seq_kv_offset;
                //     int real_mls_loop = nm_filter_max >= 32 ? 0: n_loop_; // 如果全越界了, 则只访问 n_loop = 0 的那波数据
                //     int nm_filter     = inline_min_max<0, 32>(real_mls_loop * WARP_K + 32 - max_seq_kv_offset); // 重新计算 nm_filter
                //     v_srsrc[3]        = nm_filter << 8;
                //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (real_mls_loop * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
                // }
                // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
                // flash::wait_all_warp_arrived(); // 预防有 warp 还没算完7,还在读 v lds, 若是此时写 v lds,则 data cover
                // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

                int index_topk_1 = index_ptr[n_loop * 32 + n_loop_real * 64 + (tid / 4)];
                int index_topk_2 = index_ptr[n_loop * 32 + n_loop_real * 64 + (tid / 4) + 16];

                int lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
                int g_offset_v = warp_id * 16 + tid % 4 * 4 + block_table[index_topk_1/128] * batch_stride * ELEMENT_BYTES / 4 + (index_topk_1 % 128) * seqlen_v_stride * ELEMENT_BYTES / 4;
                int lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
                int g_offset_v_add = warp_id * 16 + tid % 4 * 4 + block_table[index_topk_2/128] * batch_stride * ELEMENT_BYTES / 4 + (index_topk_2 % 128) * seqlen_v_stride * ELEMENT_BYTES / 4;
                flash::wait_all_warp_arrived();
                inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
                inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
            }
        }
        stage_id ^= 1;
        // Wait DS
        flash::wait_lds_data_arrived<false>(1);
        // last mmac
        flash::raise_priority();
        {
            constexpr int min_tile_k = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::wait_lds_data_arrived<false>(0);
        {
            constexpr int min_tile_k = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::lower_priority();
    }

    {
        constexpr int n_loop = kBlockK / WARP_K;
        // MLS for special headdimV
        {
            constexpr int n_loop_ = n_loop - 1;
            int n_load = 1;
            lds_stage_id ^= 1;
            
            // if constexpr (Is_even_MN) {
            //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + n_load * WARP_NUM * 32) * ELEMENT_BYTES);
            // } else {
            //     int nm_filter_max = n_loop_ * WARP_K + 32 - max_seq_kv_offset;
            //     int real_mls_loop = nm_filter_max >= 32 ? 0: n_loop_; // 如果全越界了, 则只访问 n_loop = 0 的那波数据
            //     int nm_filter     = inline_min_max<0, 32>(real_mls_loop * WARP_K + 32 - max_seq_kv_offset); // 重新计算 nm_filter
            //     v_srsrc[3]        = nm_filter << 8;
            //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (real_mls_loop * WARP_K * seqlen_v_stride + warp_id * 32 + n_load * WARP_NUM * 32) * ELEMENT_BYTES);
            // }
            // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
            // flash::wait_all_warp_arrived();
            // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

            int index_topk_1 = index_ptr[n_loop_ * 32 + n_loop_real * 64 + (tid / 4)];
            int index_topk_2 = index_ptr[n_loop_ * 32 + n_loop_real * 64 + (tid / 4) + 16];

            int lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            int g_offset_v = n_load * WARP_NUM * 16 + warp_id * 16 + tid % 4 * 4 + block_table[index_topk_1/128] * batch_stride * ELEMENT_BYTES / 4 + (index_topk_1 % 128) * seqlen_v_stride * ELEMENT_BYTES / 4;
            int lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            int g_offset_v_add = n_load * WARP_NUM * 16 + warp_id * 16 + tid % 4 * 4 + block_table[index_topk_2/128] * batch_stride * ELEMENT_BYTES / 4 + (index_topk_2 % 128) * seqlen_v_stride * ELEMENT_BYTES / 4;
            flash::wait_all_warp_arrived();
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add);
        }

        lds_stage_id ^= 1;
        int stage_id = 0;

        flash::wait_buffer_data_arrived<true>(V_LOAD_REQUESTS*2); // [TODO]更早的预取

        // DS
        int lds_load_offset = v_lds_base + (0/*k_loop*/ * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);

        stage_id ^= 1;
        for (int k_loop = 1; k_loop < (kHeadDimV / kBlockN); ++k_loop) {

            // Wait for special headdim
            if ((k_loop & 7) == 0x0) {
                flash::wait_buffer_data_arrived<true>(0);   
            }

            // DS
            int lds_load_offset = v_lds_base + (k_loop * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);
            flash::wait_lds_data_arrived<false>(3);

            // MMAC
            flash::raise_priority();
            stage_id ^= 1;
            {
                constexpr int min_tile_k = 0;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::wait_lds_data_arrived<false>(2);
            {
                constexpr int min_tile_k = 1;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::lower_priority();
        }

        stage_id ^= 1;
        flash::wait_lds_data_arrived<false>(1);
        // last mmac
        flash::raise_priority();
        {
            constexpr int min_tile_k = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::wait_lds_data_arrived<false>(0);
        {
            constexpr int min_tile_k = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::lower_priority();
    }

    
    // 预取Q K
    if constexpr (PREFETCH_K) {
        prefetch_q_to_lds_mls_ds_576_512<kHeadDim, kBlockM, kBlockK, WARP_M, Element, Is_even_MN>(q_ptr, q_lds, warp_id, seqlen_q_stride, max_seq_q_offset);
        prefetch_k_to_lds_mls_ds_576_512<kHeadDim, kBlockK, kBlockN, WARP_NUM, WARP_N, Element, Is_even_MN>(k_ptr, k_lds, warp_id, seqlen_k_stride, max_seq_kv_offset - kBlockK);
    }
}

template<bool PREFETCH_K, int kHeadDim, int kHeadDimV, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, int STAGES, typename Element, typename ElementAccum, bool Is_even_MN>
__forceinline__ __device__ void pv_gemm_prefetch_k_mls_ds_576_512_nopage(
        vec4_uint q_ptr,
        vec4_uint k_ptr,
        vec4_uint v_ptr,
        Element* q_lds,
        Element* k_lds,
        Element* v_lds,
        union_vec2_f16x2<Element> p_reg[(WARP_M / 16) * (kBlockK / 32)][2],
        vec4_Accum<ElementAccum> pv_reg[(kHeadDimV / kBlockN) * (WARP_M / 16) * (kBlockN / 32)][2],
        int warp_id,
        int seqlen_q_stride,
        int seqlen_k_stride,
        int seqlen_v_stride,
        int* index_ptr,
        int batch_stride,
        int page_block_size,
        int n_loop_real,
        int max_seq_q_offset=0,
        int max_seq_kv_offset=0) {

    constexpr int WARP_NUM = kBlockM * kBlockN / (WARP_M * WARP_N);
    constexpr int WARP_K   = 32;
    constexpr int READ_ONCE_COUNT = 32 * 32;
    constexpr int kHeadDimV_OPT = 256;          // lds 32x32x8x2B == 16KB
    constexpr int V_LDS_LOAD_NUM  = (kHeadDimV_OPT * WARP_K) / READ_ONCE_COUNT;
    constexpr int V_LOAD_REQUESTS = V_LDS_LOAD_NUM / WARP_NUM;
    constexpr int ELEMENT_BYTES   = sizeof(Element);
    static_assert (kBlockK >= 32, "Error: pv gemm kBlockK must be equal or greater than 32");
    static_assert (kBlockM >= WARP_M, "Error: pv gemm kBlockM must be equal or greater than WARP_M");
    static_assert (kBlockN == WARP_N, "Error: pv gemm kBlockN must be equal to WARP_N");
    static_assert (WARP_K == 32 and "Error: To simplify, only WARP_K = 32 is supported!");
    static_assert (WARP_M == 16 and "Error: To simplify, only WARP_M = 16 is supported!");
    static_assert (WARP_N == 32 and "Error: To simplify, only WARP_N = 32 is supported!");

    // 计算 V lds 起始偏移量
    int v_lds_base = reinterpret_cast<size_t>(v_lds);

    int tid = threadIdx.x % 64;
    // 准备 V 寄存器
    union_vec4_f16x2<Element> v_reg[STAGES * (32 * WARP_N) / (32 * 32) * 2];

    // MLS
    vec4_uint v_srsrc;
    v_srsrc[0] = v_ptr[0];
    v_srsrc[1] = v_ptr[1];
    v_srsrc[2] = seqlen_v_stride; // stride
    v_srsrc[3] = 0;

    int lds_stage_id = 1;
    for (int n_loop = 1; n_loop < (kBlockK / WARP_K); ++n_loop) {
        // prefetch same warpk, next 32x256 G2S
        {   
            int n_load = 1;
            int n_loop_ = n_loop - 1;
            // *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + n_load * WARP_NUM * 32) * ELEMENT_BYTES);
            // if constexpr (true) {
            //     int nm_filter     = inline_min_max<0, 32>(n_loop_ * WARP_K + 32 - max_seq_kv_offset);
            //     v_srsrc[3]        = max_seq_kv_offset % kBlockK == 0 ? 0: nm_filter << 8;
            // }
            // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
            // flash::wait_all_warp_arrived();
            // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

            int index_topk_1 = index_ptr[n_loop_real * 64 + (tid / 4)];
            int index_topk_2 = index_ptr[n_loop_real * 64 + (tid / 4) + 16];

            int lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            int g_offset_v = n_load * WARP_NUM * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_1 * seqlen_v_stride * ELEMENT_BYTES / 4;
            int lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            int g_offset_v_add = n_load * WARP_NUM * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_2 * seqlen_v_stride * ELEMENT_BYTES / 4;
            flash::wait_all_warp_arrived();
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
        }
        
        // DS
        lds_stage_id ^= 1;
        int stage_id = 0;
        flash::wait_buffer_data_arrived<true>(V_LOAD_REQUESTS*2);

        int lds_load_offset = v_lds_base + (0/*k_loop*/ * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);

        stage_id ^= 1;
        for (int k_loop = 1; k_loop < (kHeadDimV / kBlockN); ++k_loop) {

            // Wait for special headdim
            if ((k_loop & 7) == 0x0) {
                flash::wait_buffer_data_arrived<true>(0);   
            }

            int lds_load_offset = v_lds_base + (k_loop * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);
            flash::wait_lds_data_arrived<false>(3);

            // MMAC
            flash::raise_priority();
            stage_id ^= 1;
            {
                constexpr int min_tile_k = 0;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::wait_lds_data_arrived<false>(2);
            {
                constexpr int min_tile_k = 1;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::lower_priority();

            // MLS for special headdimV
            if ((k_loop & 7) == 0x0) {
                int n_loop_ = n_loop;
                    
                // if constexpr (Is_even_MN) {
                //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
                // } else {
                //     int nm_filter_max = n_loop_ * WARP_K + 32 - max_seq_kv_offset;
                //     int real_mls_loop = nm_filter_max >= 32 ? 0: n_loop_; // 如果全越界了, 则只访问 n_loop = 0 的那波数据
                //     int nm_filter     = inline_min_max<0, 32>(real_mls_loop * WARP_K + 32 - max_seq_kv_offset); // 重新计算 nm_filter
                //     v_srsrc[3]        = nm_filter << 8;
                //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (real_mls_loop * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
                // }
                // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
                // flash::wait_all_warp_arrived(); // 预防有 warp 还没算完7,还在读 v lds, 若是此时写 v lds,则 data cover
                // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

                int index_topk_1 = index_ptr[n_loop * 32 + n_loop_real * 64 + (tid / 4)];
                int index_topk_2 = index_ptr[n_loop * 32 + n_loop_real * 64 + (tid / 4) + 16];

                int lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
                int g_offset_v = warp_id * 16 + tid % 4 * 4 + index_topk_1 * seqlen_v_stride * ELEMENT_BYTES / 4;
                int lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
                int g_offset_v_add = warp_id * 16 + tid % 4 * 4 + index_topk_2 * seqlen_v_stride * ELEMENT_BYTES / 4;
                flash::wait_all_warp_arrived();
                inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
                inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
            }
        }
        stage_id ^= 1;
        // Wait DS
        flash::wait_lds_data_arrived<false>(1);
        // last mmac
        flash::raise_priority();
        {
            constexpr int min_tile_k = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::wait_lds_data_arrived<false>(0);
        {
            constexpr int min_tile_k = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::lower_priority();
    }

    {
        constexpr int n_loop = kBlockK / WARP_K;
        // MLS for special headdimV
        {
            constexpr int n_loop_ = n_loop - 1;
            int n_load = 1;
            lds_stage_id ^= 1;
            
            // if constexpr (Is_even_MN) {
            //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + n_load * WARP_NUM * 32) * ELEMENT_BYTES);
            // } else {
            //     int nm_filter_max = n_loop_ * WARP_K + 32 - max_seq_kv_offset;
            //     int real_mls_loop = nm_filter_max >= 32 ? 0: n_loop_; // 如果全越界了, 则只访问 n_loop = 0 的那波数据
            //     int nm_filter     = inline_min_max<0, 32>(real_mls_loop * WARP_K + 32 - max_seq_kv_offset); // 重新计算 nm_filter
            //     v_srsrc[3]        = nm_filter << 8;
            //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (real_mls_loop * WARP_K * seqlen_v_stride + warp_id * 32 + n_load * WARP_NUM * 32) * ELEMENT_BYTES);
            // }
            // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
            // flash::wait_all_warp_arrived();
            // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

            int index_topk_1 = index_ptr[n_loop_ * 32 + n_loop_real * 64 + (tid / 4)];
            int index_topk_2 = index_ptr[n_loop_ * 32 + n_loop_real * 64 + (tid / 4) + 16];

            int lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            int g_offset_v = n_load * WARP_NUM * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_1 * seqlen_v_stride * ELEMENT_BYTES / 4;
            int lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            int g_offset_v_add = n_load * WARP_NUM * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_2 * seqlen_v_stride * ELEMENT_BYTES / 4;
            flash::wait_all_warp_arrived();
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add);
        }

        lds_stage_id ^= 1;
        int stage_id = 0;

        flash::wait_buffer_data_arrived<true>(V_LOAD_REQUESTS*2); // [TODO]更早的预取

        // DS
        int lds_load_offset = v_lds_base + (0/*k_loop*/ * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);

        stage_id ^= 1;
        for (int k_loop = 1; k_loop < (kHeadDimV / kBlockN); ++k_loop) {

            // Wait for special headdim
            if ((k_loop & 7) == 0x0) {
                flash::wait_buffer_data_arrived<true>(0);   
            }

            // DS
            int lds_load_offset = v_lds_base + (k_loop * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);
            flash::wait_lds_data_arrived<false>(3);

            // MMAC
            flash::raise_priority();
            stage_id ^= 1;
            {
                constexpr int min_tile_k = 0;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::wait_lds_data_arrived<false>(2);
            {
                constexpr int min_tile_k = 1;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::lower_priority();
        }

        stage_id ^= 1;
        flash::wait_lds_data_arrived<false>(1);
        // last mmac
        flash::raise_priority();
        {
            constexpr int min_tile_k = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::wait_lds_data_arrived<false>(0);
        {
            constexpr int min_tile_k = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::lower_priority();
    }

    
    // 预取Q K
    if constexpr (PREFETCH_K) {
        prefetch_q_to_lds_mls_ds_576_512<kHeadDim, kBlockM, kBlockK, WARP_M, Element, Is_even_MN>(q_ptr, q_lds, warp_id, seqlen_q_stride, max_seq_q_offset);
        prefetch_k_to_lds_mls_ds_576_512<kHeadDim, kBlockK, kBlockN, WARP_NUM, WARP_N, Element, Is_even_MN>(k_ptr, k_lds, warp_id, seqlen_k_stride, max_seq_kv_offset - kBlockK);
    }
}

template<bool PREFETCH_K, int kHeadDim, int kHeadDimV, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, int STAGES, typename Element, typename ElementAccum, bool Is_even_MN>
__forceinline__ __device__ void pv_gemm_prefetch_k_mls_ds_576_512_nopage_64(
        vec4_uint q_ptr,
        vec4_uint k_ptr,
        vec4_uint v_ptr,
        Element* q_lds,
        Element* k_lds,
        Element* v_lds,
        union_vec2_f16x2<Element> p_reg[(WARP_M / 16) * (kBlockK / 32)][2],
        vec4_Accum<ElementAccum> pv_reg[(kHeadDimV / kBlockN) * (WARP_M / 16) * (kBlockN / 32)][2],
        int warp_id,
        int seqlen_q_stride,
        int seqlen_k_stride,
        int seqlen_v_stride,
        int* index_ptr,
        int batch_stride,
        int page_block_size,
        int n_loop_real,
        int max_seq_q_offset=0,
        int max_seq_kv_offset=0) {

    constexpr int WARP_NUM = kBlockM * kBlockN / (WARP_M * WARP_N);
    constexpr int WARP_K   = 32;
    constexpr int READ_ONCE_COUNT = 32 * 32;
    constexpr int kHeadDimV_OPT = 256;          // lds 32x32x8x2B == 16KB
    constexpr int V_LDS_LOAD_NUM  = (kHeadDimV_OPT * WARP_K) / READ_ONCE_COUNT;
    constexpr int V_LOAD_REQUESTS = V_LDS_LOAD_NUM / WARP_NUM;
    constexpr int ELEMENT_BYTES   = sizeof(Element);
    static_assert (kBlockK >= 32, "Error: pv gemm kBlockK must be equal or greater than 32");
    static_assert (kBlockM >= WARP_M, "Error: pv gemm kBlockM must be equal or greater than WARP_M");
    static_assert (kBlockN == WARP_N, "Error: pv gemm kBlockN must be equal to WARP_N");
    static_assert (WARP_K == 32 and "Error: To simplify, only WARP_K = 32 is supported!");
    static_assert (WARP_M == 16 and "Error: To simplify, only WARP_M = 16 is supported!");
    static_assert (WARP_N == 32 and "Error: To simplify, only WARP_N = 32 is supported!");

    // 计算 V lds 起始偏移量
    int v_lds_base = reinterpret_cast<size_t>(v_lds);

    int tid = threadIdx.x % 64;
    // 准备 V 寄存器
    union_vec4_f16x2<Element> v_reg[STAGES * (32 * WARP_N) / (32 * 32) * 2];

    // MLS
    vec4_uint v_srsrc;
    v_srsrc[0] = v_ptr[0];
    v_srsrc[1] = v_ptr[1];
    v_srsrc[2] = seqlen_v_stride; // stride
    v_srsrc[3] = 0;

    int lds_stage_id = 1;
    for (int n_loop = 1; n_loop < (kBlockK / WARP_K); ++n_loop) {
        // prefetch same warpk, next 32x256 G2S
        {   
            int n_load = 1;
            int n_loop_ = n_loop - 1;
            // *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + n_load * WARP_NUM * 32) * ELEMENT_BYTES);
            // if constexpr (true) {
            //     int nm_filter     = inline_min_max<0, 32>(n_loop_ * WARP_K + 32 - max_seq_kv_offset);
            //     v_srsrc[3]        = max_seq_kv_offset % kBlockK == 0 ? 0: nm_filter << 8;
            // }
            // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
            // flash::wait_all_warp_arrived();
            // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

            int index_topk_1 = index_ptr[n_loop_real * 64 + (tid / 4)];
            int index_topk_2 = index_ptr[n_loop_real * 64 + (tid / 4) + 16];

            int lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            int g_offset_v = n_load * WARP_NUM * 32 + warp_id * 16 + tid % 4 * 4 + index_topk_1 * seqlen_v_stride * ELEMENT_BYTES / 4;
            int lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            int g_offset_v_add = n_load * WARP_NUM * 32 + warp_id * 16 + tid % 4 * 4 + index_topk_2 * seqlen_v_stride * ELEMENT_BYTES / 4;
            flash::wait_all_warp_arrived();
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
            g_offset_v += WARP_NUM * 32 * ELEMENT_BYTES / 4;
            g_offset_v_add += WARP_NUM * 32 * ELEMENT_BYTES / 4;
            lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
            lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
        }
        
        // DS
        lds_stage_id ^= 1;
        int stage_id = 0;
        flash::wait_buffer_data_arrived<true>(V_LOAD_REQUESTS*2);

        int lds_load_offset = v_lds_base + (0/*k_loop*/ * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);

        stage_id ^= 1;
        for (int k_loop = 1; k_loop < (kHeadDimV / kBlockN); ++k_loop) {

            // Wait for special headdim
            if ((k_loop & 7) == 0x0) {
                flash::wait_buffer_data_arrived<true>(0);   
            }

            int lds_load_offset = v_lds_base + (k_loop * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);
            flash::wait_lds_data_arrived<false>(3);

            // MMAC
            flash::raise_priority();
            stage_id ^= 1;
            {
                constexpr int min_tile_k = 0;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::wait_lds_data_arrived<false>(2);
            {
                constexpr int min_tile_k = 1;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::lower_priority();

            // MLS for special headdimV
            if ((k_loop & 7) == 0x0) {
                int n_loop_ = n_loop;
                    
                // if constexpr (Is_even_MN) {
                //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
                // } else {
                //     int nm_filter_max = n_loop_ * WARP_K + 32 - max_seq_kv_offset;
                //     int real_mls_loop = nm_filter_max >= 32 ? 0: n_loop_; // 如果全越界了, 则只访问 n_loop = 0 的那波数据
                //     int nm_filter     = inline_min_max<0, 32>(real_mls_loop * WARP_K + 32 - max_seq_kv_offset); // 重新计算 nm_filter
                //     v_srsrc[3]        = nm_filter << 8;
                //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (real_mls_loop * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
                // }
                // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
                // flash::wait_all_warp_arrived(); // 预防有 warp 还没算完7,还在读 v lds, 若是此时写 v lds,则 data cover
                // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

                int index_topk_1 = index_ptr[n_loop * 32 + n_loop_real * 64 + (tid / 4)];
                int index_topk_2 = index_ptr[n_loop * 32 + n_loop_real * 64 + (tid / 4) + 16];

                int lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
                int g_offset_v = warp_id * 16 + tid % 4 * 4 + index_topk_1 * seqlen_v_stride * ELEMENT_BYTES / 4;
                int lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
                int g_offset_v_add = warp_id * 16 + tid % 4 * 4 + index_topk_2 * seqlen_v_stride * ELEMENT_BYTES / 4;
                flash::wait_all_warp_arrived();
                inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
                inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
                g_offset_v += WARP_NUM * 32 * ELEMENT_BYTES / 4;
                g_offset_v_add += WARP_NUM * 32 * ELEMENT_BYTES / 4;
                lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
                lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
                inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
                inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
            }
        }
        stage_id ^= 1;
        // Wait DS
        flash::wait_lds_data_arrived<false>(1);
        // last mmac
        flash::raise_priority();
        {
            constexpr int min_tile_k = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::wait_lds_data_arrived<false>(0);
        {
            constexpr int min_tile_k = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::lower_priority();
    }

    {
        constexpr int n_loop = kBlockK / WARP_K;
        // MLS for special headdimV
        {
            constexpr int n_loop_ = n_loop - 1;
            int n_load = 1;
            lds_stage_id ^= 1;
            
            // if constexpr (Is_even_MN) {
            //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + n_load * WARP_NUM * 32) * ELEMENT_BYTES);
            // } else {
            //     int nm_filter_max = n_loop_ * WARP_K + 32 - max_seq_kv_offset;
            //     int real_mls_loop = nm_filter_max >= 32 ? 0: n_loop_; // 如果全越界了, 则只访问 n_loop = 0 的那波数据
            //     int nm_filter     = inline_min_max<0, 32>(real_mls_loop * WARP_K + 32 - max_seq_kv_offset); // 重新计算 nm_filter
            //     v_srsrc[3]        = nm_filter << 8;
            //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (real_mls_loop * WARP_K * seqlen_v_stride + warp_id * 32 + n_load * WARP_NUM * 32) * ELEMENT_BYTES);
            // }
            // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
            // flash::wait_all_warp_arrived();
            // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

            int index_topk_1 = index_ptr[n_loop_ * 32 + n_loop_real * 64 + (tid / 4)];
            int index_topk_2 = index_ptr[n_loop_ * 32 + n_loop_real * 64 + (tid / 4) + 16];

            int lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            int g_offset_v = n_load * WARP_NUM * 32 + warp_id * 16 + tid % 4 * 4 + index_topk_1 * seqlen_v_stride * ELEMENT_BYTES / 4;
            int lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            int g_offset_v_add = n_load * WARP_NUM * 32 + warp_id * 16 + tid % 4 * 4 + index_topk_2 * seqlen_v_stride * ELEMENT_BYTES / 4;
            flash::wait_all_warp_arrived();
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add);
            g_offset_v += WARP_NUM * 32 * ELEMENT_BYTES / 4;
            g_offset_v_add += WARP_NUM * 32 * ELEMENT_BYTES / 4;
            lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
            lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
        }

        lds_stage_id ^= 1;
        int stage_id = 0;

        flash::wait_buffer_data_arrived<true>(V_LOAD_REQUESTS*2); // [TODO]更早的预取

        // DS
        int lds_load_offset = v_lds_base + (0/*k_loop*/ * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);

        stage_id ^= 1;
        for (int k_loop = 1; k_loop < (kHeadDimV / kBlockN); ++k_loop) {

            // Wait for special headdim
            if ((k_loop & 7) == 0x0) {
                flash::wait_buffer_data_arrived<true>(0);   
            }

            // DS
            int lds_load_offset = v_lds_base + (k_loop * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);
            flash::wait_lds_data_arrived<false>(3);

            // MMAC
            flash::raise_priority();
            stage_id ^= 1;
            {
                constexpr int min_tile_k = 0;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::wait_lds_data_arrived<false>(2);
            {
                constexpr int min_tile_k = 1;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::lower_priority();
        }

        stage_id ^= 1;
        flash::wait_lds_data_arrived<false>(1);
        // last mmac
        flash::raise_priority();
        {
            constexpr int min_tile_k = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::wait_lds_data_arrived<false>(0);
        {
            constexpr int min_tile_k = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::lower_priority();
    }

    
    // 预取Q K
    if constexpr (PREFETCH_K) {
        prefetch_q_to_lds_mls_ds_576_512<kHeadDim, kBlockM, kBlockK, WARP_M, Element, Is_even_MN>(q_ptr, q_lds, warp_id, seqlen_q_stride, max_seq_q_offset);
        prefetch_k_to_lds_mls_ds_576_512<kHeadDim, kBlockK, kBlockN, WARP_NUM, WARP_N, Element, Is_even_MN>(k_ptr, k_lds, warp_id, seqlen_k_stride, max_seq_kv_offset - kBlockK);
    }
}

template<bool PREFETCH_K, int kHeadDim, int kHeadDimV, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, int STAGES, typename Element, typename ElementAccum, bool Is_even_MN>
__forceinline__ __device__ void pv_gemm_prefetch_k_mls_ds_576_512_nopage_64_new(
        Element* k_faker,
        vec4_uint k_ptr,
        vec4_uint v_ptr,
        Element* q_lds,
        Element* k_lds,
        Element* v_lds,
        union_vec2_f16x2<Element> p_reg[(WARP_M / 16) * (kBlockK / 32)][2],
        vec4_Accum<ElementAccum> pv_reg[(kHeadDimV / kBlockN) * (WARP_M / 16) * (kBlockN / 32)][2],
        int warp_id,
        int seqlen_q_stride,
        int seqlen_k_stride,
        int seqlen_v_stride,
        int* index_ptr,
        int batch_stride,
        int page_block_size,
        int n_loop_real,
        int max_seq_q_offset=0,
        int max_seq_kv_offset=0) {

    constexpr int WARP_NUM = kBlockM * kBlockN / (WARP_M * WARP_N);
    constexpr int WARP_K   = 32;
    constexpr int READ_ONCE_COUNT = 32 * 32;
    constexpr int kHeadDimV_OPT = 128;          // lds 32x32x8x2B == 16KB
    constexpr int V_LDS_LOAD_NUM  = (kHeadDimV_OPT * WARP_K) / READ_ONCE_COUNT;
    constexpr int V_LOAD_REQUESTS = V_LDS_LOAD_NUM / WARP_NUM;
    constexpr int ELEMENT_BYTES   = sizeof(Element);
    static_assert (kBlockK >= 32, "Error: pv gemm kBlockK must be equal or greater than 32");
    static_assert (kBlockM >= WARP_M, "Error: pv gemm kBlockM must be equal or greater than WARP_M");
    static_assert (kBlockN == WARP_N, "Error: pv gemm kBlockN must be equal to WARP_N");
    static_assert (WARP_K == 32 and "Error: To simplify, only WARP_K = 32 is supported!");
    static_assert (WARP_M == 16 and "Error: To simplify, only WARP_M = 16 is supported!");
    static_assert (WARP_N == 32 and "Error: To simplify, only WARP_N = 32 is supported!");

    // 计算 V lds 起始偏移量
    int v_lds_base = reinterpret_cast<size_t>(v_lds);

    int tid = threadIdx.x % 64;
    // 准备 V 寄存器
    union_vec4_f16x2<Element> v_reg[STAGES * (32 * WARP_N) / (32 * 32) * 2];

    // MLS
    vec4_uint v_srsrc;
    v_srsrc[0] = v_ptr[0];
    v_srsrc[1] = v_ptr[1];
    v_srsrc[2] = seqlen_v_stride; // stride
    v_srsrc[3] = 0;

    int index_topk_1[2];
    index_topk_1[0] = index_ptr[((n_loop_real * 64)) + (tid / 4)];
    index_topk_1[1] = index_ptr[((n_loop_real * 64)) + (tid / 4) + 32];
    int index_topk_2[2];
    index_topk_2[0] = index_ptr[((n_loop_real * 64)) + (tid / 4) + 16];
    index_topk_2[1] = index_ptr[((n_loop_real * 64)) + (tid / 4) + 48];
    // int index_topk_2 = index_ptr[((n_loop_real * 64)) + (tid / 4) + 16];
    int lds_offset = __builtin_amdgcn_readfirstlane((warp_id * 32 * 32) * ELEMENT_BYTES / 4);
    int g_offset_v = tid % 4 * 4 + index_topk_1[0] * seqlen_v_stride * ELEMENT_BYTES / 4;
    int g_offset_s = warp_id * 16;
    int lds_offset_add = __builtin_amdgcn_readfirstlane((32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
    int g_offset_v_add = tid % 4 * 4 + index_topk_2[0] * seqlen_v_stride * ELEMENT_BYTES / 4;
    int g_offset_s_add = warp_id * 16;
    flash::wait_all_warp_arrived();
    inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, g_offset_s, g_offset_v); 
    inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, g_offset_s_add, g_offset_v_add); 
    // __builtin_amdgcn_sched_barrier(0);

    int lds_stage_id = 1;
    for (int n_loop = 1; n_loop < (kBlockK / WARP_K); ++n_loop) {
        // prefetch same warpk, next 32x256 G2S
        {   
            int n_load = 1;
            int n_loop_ = n_loop - 1;
            // *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + n_load * WARP_NUM * 32) * ELEMENT_BYTES);
            // if constexpr (true) {
            //     int nm_filter     = inline_min_max<0, 32>(n_loop_ * WARP_K + 32 - max_seq_kv_offset);
            //     v_srsrc[3]        = max_seq_kv_offset % kBlockK == 0 ? 0: nm_filter << 8;
            // }
            // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
            // flash::wait_all_warp_arrived();
            // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

             lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
             g_offset_v = tid % 4 * 4 + index_topk_1[0] * seqlen_v_stride * ELEMENT_BYTES / 4;
             g_offset_s = n_load * WARP_NUM * 16 + warp_id * 16;
             lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
             g_offset_v_add = tid % 4 * 4 + index_topk_2[0] * seqlen_v_stride * ELEMENT_BYTES / 4;
             g_offset_s_add = n_load * WARP_NUM * 16 + warp_id * 16;
            flash::wait_all_warp_arrived();
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, g_offset_s, g_offset_v); 
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, g_offset_s_add, g_offset_v_add); 
            // g_offset_v += WARP_NUM * 32 * ELEMENT_BYTES / 4;
            // g_offset_v_add += WARP_NUM * 32 * ELEMENT_BYTES / 4;
            // lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
            // lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
            // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
            // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
        }
        
        // DS
        lds_stage_id ^= 1;
        int stage_id = 0;
        flash::wait_buffer_data_arrived<true>(V_LOAD_REQUESTS*2);

        int lds_load_offset = v_lds_base + (0/*k_loop*/ * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
        // v_reg[stage_id * 2 + 0].f16x8  =  __builtin_hcu_ds_read_matrix_format_f16(lds_load_offset, 0, 2, 1, 0);
        // v_reg[stage_id * 2 + 1].f16x8  =  __builtin_hcu_ds_read_matrix_format_f16(lds_load_offset, 1024, 2, 1, 0);
        DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);

        stage_id ^= 1;
        for (int k_loop = 1; k_loop < (kHeadDimV / kBlockN); ++k_loop) {

            // Wait for special headdim
            if ((k_loop & 3) == 0x0) {
                flash::wait_buffer_data_arrived<true>(0);   
                lds_stage_id ^= 1;
            }

            int lds_load_offset = v_lds_base + ((k_loop & 3) * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
            // v_reg[stage_id * 2 + 0].f16x8  =  __builtin_hcu_ds_read_matrix_format_f16(lds_load_offset, 0, 2, 1, 0);
            // v_reg[stage_id * 2 + 1].f16x8  =  __builtin_hcu_ds_read_matrix_format_f16(lds_load_offset, 1024, 2, 1, 0);
            DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);
            flash::wait_lds_data_arrived<false>(3);

            // MMAC
            flash::raise_priority();
            stage_id ^= 1;
            {
                constexpr int min_tile_k = 0;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::wait_lds_data_arrived<false>(2);
            {
                constexpr int min_tile_k = 1;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::lower_priority();

            // MLS for special headdimV
            if ((k_loop & 3) == 0x0) {
                int n_loop_ = n_loop;
                lds_stage_id ^= 1;
                // if constexpr (Is_even_MN) {
                //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
                // } else {
                //     int nm_filter_max = n_loop_ * WARP_K + 32 - max_seq_kv_offset;
                //     int real_mls_loop = nm_filter_max >= 32 ? 0: n_loop_; // 如果全越界了, 则只访问 n_loop = 0 的那波数据
                //     int nm_filter     = inline_min_max<0, 32>(real_mls_loop * WARP_K + 32 - max_seq_kv_offset); // 重新计算 nm_filter
                //     v_srsrc[3]        = nm_filter << 8;
                //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (real_mls_loop * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
                // }
                // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
                // flash::wait_all_warp_arrived(); // 预防有 warp 还没算完7,还在读 v lds, 若是此时写 v lds,则 data cover
                // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

                //  index_topk_1 = index_ptr[k_loop / 12 * 32 + (n_loop_real * 64) + (tid / 4)];
                //  index_topk_2 = index_ptr[k_loop / 12 * 32 + (n_loop_real * 64) + (tid / 4) + 16];

                 lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
                 g_offset_v = tid % 4 * 4 + index_topk_1[k_loop / 12] * seqlen_v_stride * ELEMENT_BYTES / 4;
                 g_offset_s = ((k_loop + 4) & 15) * 16 + warp_id * 16;
                 lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
                 g_offset_v_add = tid % 4 * 4 + index_topk_2[k_loop / 12] * seqlen_v_stride * ELEMENT_BYTES / 4;
                 g_offset_s_add = ((k_loop + 4) & 15) * 16 + warp_id * 16;
                flash::wait_all_warp_arrived();
                inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, g_offset_s, g_offset_v); 
                inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, g_offset_s_add, g_offset_v_add); 
                // g_offset_v += WARP_NUM * 32 * ELEMENT_BYTES / 4;
                // g_offset_v_add += WARP_NUM * 32 * ELEMENT_BYTES / 4;
                // lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
                // lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
                // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
                // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
                lds_stage_id ^= 1;
            }
        }
        stage_id ^= 1;
        // Wait DS
        flash::wait_lds_data_arrived<false>(1);
        // last mmac
        flash::raise_priority();
        {
            constexpr int min_tile_k = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::wait_lds_data_arrived<false>(0);
        {
            constexpr int min_tile_k = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::lower_priority();
    }

    {
        constexpr int n_loop = kBlockK / WARP_K;
        // MLS for special headdimV
        {
            constexpr int n_loop_ = n_loop - 1;
            int n_load = 1;
            // lds_stage_id ^= 1;
            
            // if constexpr (Is_even_MN) {
            //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + n_load * WARP_NUM * 32) * ELEMENT_BYTES);
            // } else {
            //     int nm_filter_max = n_loop_ * WARP_K + 32 - max_seq_kv_offset;
            //     int real_mls_loop = nm_filter_max >= 32 ? 0: n_loop_; // 如果全越界了, 则只访问 n_loop = 0 的那波数据
            //     int nm_filter     = inline_min_max<0, 32>(real_mls_loop * WARP_K + 32 - max_seq_kv_offset); // 重新计算 nm_filter
            //     v_srsrc[3]        = nm_filter << 8;
            //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (real_mls_loop * WARP_K * seqlen_v_stride + warp_id * 32 + n_load * WARP_NUM * 32) * ELEMENT_BYTES);
            // }
            // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
            // flash::wait_all_warp_arrived();
            // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

            // int index_topk_1 = index_ptr[n_loop_ * 32 + (n_loop_real * 64) + (tid / 4)];
            // int index_topk_2 = index_ptr[n_loop_ * 32 + (n_loop_real * 64) + (tid / 4) + 16];

            int lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            int g_offset_v = tid % 4 * 4 + index_topk_1[1] * seqlen_v_stride * ELEMENT_BYTES / 4;
            int g_offset_s = n_load * WARP_NUM * 16 + warp_id * 16;
            int lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            int g_offset_v_add = tid % 4 * 4 + index_topk_2[1] * seqlen_v_stride * ELEMENT_BYTES / 4;
            int g_offset_s_add = n_load * WARP_NUM * 16 + warp_id * 16;
            flash::wait_all_warp_arrived();
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, g_offset_s, g_offset_v); 
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, g_offset_s_add, g_offset_v_add);
            // g_offset_v += WARP_NUM * 32 * ELEMENT_BYTES / 4;
            // g_offset_v_add += WARP_NUM * 32 * ELEMENT_BYTES / 4;
            // lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
            // lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
            // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
            // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
        }

        lds_stage_id ^= 1;
        int stage_id = 0;

        flash::wait_buffer_data_arrived<true>(V_LOAD_REQUESTS*2); // [TODO]更早的预取

        // DS
        int lds_load_offset = v_lds_base + (0/*k_loop*/ * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
        // v_reg[stage_id * 2 + 0].f16x8  =  __builtin_hcu_ds_read_matrix_format_f16(lds_load_offset, 0, 2, 1, 0);
        // v_reg[stage_id * 2 + 1].f16x8  =  __builtin_hcu_ds_read_matrix_format_f16(lds_load_offset, 1024, 2, 1, 0);
        DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);

        stage_id ^= 1;
        for (int k_loop = 1; k_loop < (kHeadDimV / kBlockN); ++k_loop) {

            // Wait for special headdim
            if ((k_loop & 3) == 0x0) {
                flash::wait_buffer_data_arrived<true>(0);   
                lds_stage_id ^= 1;
            }

            // DS
            int lds_load_offset = v_lds_base + ((k_loop & 3) * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
            // v_reg[stage_id * 2 + 0].f16x8  =  __builtin_hcu_ds_read_matrix_format_f16(lds_load_offset, 0, 2, 1, 0);
            // v_reg[stage_id * 2 + 1].f16x8  =  __builtin_hcu_ds_read_matrix_format_f16(lds_load_offset, 1024, 2, 1, 0);
            DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);
            flash::wait_lds_data_arrived<false>(3);

            // MMAC
            flash::raise_priority();
            stage_id ^= 1;
            {
                constexpr int min_tile_k = 0;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::wait_lds_data_arrived<false>(2);
            {
                constexpr int min_tile_k = 1;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::lower_priority();

            // MLS for special headdimV
            if (k_loop == 4 || k_loop == 8) {
                lds_stage_id ^= 1;
                // if constexpr (Is_even_MN) {
                //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
                // } else {
                //     int nm_filter_max = n_loop_ * WARP_K + 32 - max_seq_kv_offset;
                //     int real_mls_loop = nm_filter_max >= 32 ? 0: n_loop_; // 如果全越界了, 则只访问 n_loop = 0 的那波数据
                //     int nm_filter     = inline_min_max<0, 32>(real_mls_loop * WARP_K + 32 - max_seq_kv_offset); // 重新计算 nm_filter
                //     v_srsrc[3]        = nm_filter << 8;
                //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (real_mls_loop * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
                // }
                // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
                // flash::wait_all_warp_arrived(); // 预防有 warp 还没算完7,还在读 v lds, 若是此时写 v lds,则 data cover
                // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

                // int index_topk_1 = index_ptr[32 + (n_loop_real * 64) + (tid / 4)];
                // int index_topk_2 = index_ptr[32 + (n_loop_real * 64) + (tid / 4) + 16];

                int lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
                int g_offset_v = tid % 4 * 4 + index_topk_1[1] * seqlen_v_stride * ELEMENT_BYTES / 4;
                int g_offset_s = ((k_loop + 4) & 15) * 16 + warp_id * 16;
                int lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
                int g_offset_v_add = tid % 4 * 4 + index_topk_2[1] * seqlen_v_stride * ELEMENT_BYTES / 4;
                int g_offset_s_add = ((k_loop + 4) & 15) * 16 + warp_id * 16;
                flash::wait_all_warp_arrived();
                inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, g_offset_s, g_offset_v); 
                inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, g_offset_s_add, g_offset_v_add); 
                // g_offset_v += WARP_NUM * 32 * ELEMENT_BYTES / 4;
                // g_offset_v_add += WARP_NUM * 32 * ELEMENT_BYTES / 4;
                // lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
                // lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
                // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
                // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
                lds_stage_id ^= 1;
            }
        }

        stage_id ^= 1;
        flash::wait_lds_data_arrived<false>(1);
        // last mmac
        flash::raise_priority();
        {
            constexpr int min_tile_k = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::lower_priority();
        flash::wait_lds_data_arrived<false>(0);
        flash::raise_priority();

        int abc[1];
        int index_topk = index_ptr[(((n_loop_real+1) % 16) * 64) + warp_id * 16];
        int offset_m = index_topk * seqlen_k_stride;
        auto g_abc = (reinterpret_cast<uint64_t>(k_faker + offset_m)); 
        inline_s_load_dword(abc[0], g_abc, 0); 

        {
            constexpr int min_tile_k = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::lower_priority();
    }

    
    // 预取Q K
    // if constexpr (PREFETCH_K) {
    //     prefetch_q_to_lds_mls_ds_576_512<kHeadDim, kBlockM, kBlockK, WARP_M, Element, Is_even_MN>(q_ptr, q_lds, warp_id, seqlen_q_stride, max_seq_q_offset);
    //     prefetch_k_to_lds_mls_ds_576_512<kHeadDim, kBlockK, kBlockN, WARP_NUM, WARP_N, Element, Is_even_MN>(k_ptr, k_lds, warp_id, seqlen_k_stride, max_seq_kv_offset - kBlockK);
    // }
}

template<bool PREFETCH_K, int kHeadDim, int kHeadDimV, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, int STAGES, typename Element, typename ElementAccum, bool Is_even_MN>
__forceinline__ __device__ void pv_gemm_prefetch_k_mls_ds_576_512_nopage_64_new_666(
        Element* k_faker,
        vec4_uint k_ptr,
        vec4_uint v_ptr,
        Element* q_lds,
        Element* k_lds,
        Element* v_lds,
        union_vec2_f16x2<Element> p_reg[(WARP_M / 16) * (kBlockK / 32)][2],
        vec4_Accum<ElementAccum> pv_reg[(kHeadDimV / kBlockN) * (WARP_M / 16) * (kBlockN / 32)][2],
        int warp_id,
        int seqlen_q_stride,
        int seqlen_k_stride,
        int seqlen_v_stride,
        int* index_ptr,
        int batch_stride,
        int n_loop_real,
        int max_seq_q_offset=0,
        int max_seq_kv_offset=0) {

    constexpr int WARP_NUM = kBlockM * kBlockN / (WARP_M * WARP_N);
    constexpr int WARP_K   = 64;
    constexpr int READ_ONCE_COUNT = 16 * 32;
    constexpr int kHeadDimV_OPT = 64;          // lds 32x32x8x2B == 16KB
    constexpr int V_LDS_LOAD_NUM  = (kHeadDimV_OPT * WARP_K) / READ_ONCE_COUNT;
    constexpr int V_LOAD_REQUESTS = V_LDS_LOAD_NUM / WARP_NUM;
    constexpr int ELEMENT_BYTES   = sizeof(Element);
    static_assert (kBlockK >= 32, "Error: pv gemm kBlockK must be equal or greater than 32");
    static_assert (kBlockM >= WARP_M, "Error: pv gemm kBlockM must be equal or greater than WARP_M");
    static_assert (kBlockN == WARP_N, "Error: pv gemm kBlockN must be equal to WARP_N");
    static_assert (WARP_K == 64 and "Error: To simplify, only WARP_K = 32 is supported!");
    static_assert (WARP_M == 16 and "Error: To simplify, only WARP_M = 16 is supported!");
    static_assert (WARP_N == 64 and "Error: To simplify, only WARP_N = 32 is supported!");

    // 计算 V lds 起始偏移量
    int v_lds_base = reinterpret_cast<size_t>(v_lds);

    int tid = threadIdx.x % 64;
    // 准备 V 寄存器
    union_vec4_f16x2<Element> v_reg[STAGES * (32 * WARP_N) / (32 * 32) * 2];

    // MLS
    vec4_uint v_srsrc;
    v_srsrc[0] = v_ptr[0];
    v_srsrc[1] = v_ptr[1];
    v_srsrc[2] = seqlen_v_stride; // stride
    v_srsrc[3] = 0;

    int index_topk = index_ptr[(n_loop_real * 64) + warp_id * 16 + (tid / 4)];
    int lds_offset = __builtin_amdgcn_readfirstlane((warp_id * 32 * 16) * ELEMENT_BYTES / 4);
    int lds_offset_2 = __builtin_amdgcn_readfirstlane((warp_id * 32 * 16 + 32 * 64) * ELEMENT_BYTES / 4);
    int g_offset_v = tid % 4 * 4 + index_topk * seqlen_v_stride * ELEMENT_BYTES / 4;
    int g_offset_s = 0 * WARP_N * ELEMENT_BYTES / 4 + 0;
    int g_offset_s_2 = 0 * WARP_N * ELEMENT_BYTES / 4 + 16;
    flash::wait_all_warp_arrived();
    inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, g_offset_s, g_offset_v); 
    inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_2, g_offset_s_2, g_offset_v); 

    int lds_stage_id = 1;

    for(int k_loop = 1; k_loop < (kHeadDimV / kBlockN); ++k_loop) {
            
        {
            lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * WARP_N + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
            lds_offset_2 = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * WARP_N + warp_id * 32 * 16 + 32 * 64) * ELEMENT_BYTES / 4);
            g_offset_s = k_loop * WARP_N * ELEMENT_BYTES / 4;
            g_offset_s_2 = k_loop * WARP_N * ELEMENT_BYTES / 4 + 16;
            flash::wait_all_warp_arrived();
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, g_offset_s, g_offset_v); 
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_2, g_offset_s_2, g_offset_v); 
        }

        // 不对称MLS指令
        flash::wait_buffer_data_arrived<true>(V_LOAD_REQUESTS);

        lds_stage_id ^= 1;
        int stage_id = 0;

        // K DS  
        {
            int v_lds_load_offset = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 0 * 32 * 32) * ELEMENT_BYTES;
            int v_lds_load_offset_2 = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 0 * 32 * 32 + 32 * 64) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(v_lds_load_offset, v_reg[stage_id * 2].f16, v_reg[stage_id * 2 + 1].f16, false);
            DS_READ_MATRIX_32X32_B16(v_lds_load_offset_2, v_reg[4 + stage_id * 2].f16, v_reg[4 + stage_id * 2 + 1].f16, false);
        }

        // K DS PRE
        stage_id ^= 1;
        {
            int v_lds_load_offset = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 1 * 32 * 32) * ELEMENT_BYTES;
            int v_lds_load_offset_2 = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 1 * 32 * 32 + 32 * 64) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(v_lds_load_offset, v_reg[stage_id * 2].f16, v_reg[stage_id * 2 + 1].f16, false);
            DS_READ_MATRIX_32X32_B16(v_lds_load_offset_2, v_reg[4 + stage_id * 2].f16, v_reg[4 + stage_id * 2 + 1].f16, false);
        }

        // Wait DS
        flash::wait_lds_data_arrived<false>(6);
        flash::raise_priority();

        // MMAC 
        stage_id ^= 1;
        { 
            int min_tile_k = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = (k_loop - 1) * 2 + 0;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[0][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_k = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = (k_loop - 1) * 2 + 0;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[0][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        flash::lower_priority();
        flash::wait_lds_data_arrived<false>(4);
        flash::raise_priority();

        { 
            int min_tile_k = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = (k_loop - 1) * 2 + 1;
                    int v_tile_id = 4 + stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[0][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_k = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = (k_loop - 1) * 2 + 1;
                    int v_tile_id = 4 + stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[0][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        flash::lower_priority();
        flash::wait_lds_data_arrived<false>(2);
        flash::raise_priority();

        stage_id ^= 1;
        { 
            int min_tile_k = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = (k_loop - 1) * 2 + 0;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_k = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = (k_loop - 1) * 2 + 0;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        flash::lower_priority();
        flash::wait_lds_data_arrived<false>(0);
        flash::raise_priority();

        { 
            int min_tile_k = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = (k_loop - 1) * 2 + 1;
                    int v_tile_id = 4 + stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_k = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = (k_loop - 1) * 2 + 1;
                    int v_tile_id = 4 + stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }
        flash::lower_priority();
        
    }

    // 等回最后的q_panel
    flash::wait_buffer_data_arrived<true>(0);

    int k_loop = kHeadDimV / kBlockN;

    lds_stage_id ^= 1;
    int stage_id = 0;

    // K DS  
    {
        int v_lds_load_offset = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 0 * 32 * 32) * ELEMENT_BYTES;
        int v_lds_load_offset_2 = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 0 * 32 * 32 + 32 * 64) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(v_lds_load_offset, v_reg[stage_id * 2].f16, v_reg[stage_id * 2 + 1].f16, false);
        DS_READ_MATRIX_32X32_B16(v_lds_load_offset_2, v_reg[4 + stage_id * 2].f16, v_reg[4 + stage_id * 2 + 1].f16, false);
    }

    // K DS PRE
    stage_id ^= 1;
    {
        int v_lds_load_offset = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 1 * 32 * 32) * ELEMENT_BYTES;
        int v_lds_load_offset_2 = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 1 * 32 * 32 + 32 * 64) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(v_lds_load_offset, v_reg[stage_id * 2].f16, v_reg[stage_id * 2 + 1].f16, false);
        DS_READ_MATRIX_32X32_B16(v_lds_load_offset_2, v_reg[4 + stage_id * 2].f16, v_reg[4 + stage_id * 2 + 1].f16, false);
    }

    // Wait DS
    flash::wait_lds_data_arrived<false>(6);
    flash::raise_priority();

    // MMAC 
    stage_id ^= 1;
    { 
        int min_tile_k = 0;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = (k_loop - 1) * 2 + 0;
                int v_tile_id = stage_id * 2 + min_tile_k;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[0][min_tile_k].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    { 
        int min_tile_k = 1;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = (k_loop - 1) * 2 + 0;
                int v_tile_id = stage_id * 2 + min_tile_k;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[0][min_tile_k].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    flash::lower_priority();
    flash::wait_lds_data_arrived<false>(4);
    flash::raise_priority();

    { 
        int min_tile_k = 0;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = (k_loop - 1) * 2 + 1;
                int v_tile_id = 4 + stage_id * 2 + min_tile_k;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[0][min_tile_k].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    { 
        int min_tile_k = 1;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = (k_loop - 1) * 2 + 1;
                int v_tile_id = 4 + stage_id * 2 + min_tile_k;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[0][min_tile_k].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    flash::lower_priority();
    flash::wait_lds_data_arrived<false>(2);
    flash::raise_priority();

    stage_id ^= 1;
    { 
        int min_tile_k = 0;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = (k_loop - 1) * 2 + 0;
                int v_tile_id = stage_id * 2 + min_tile_k;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][min_tile_k].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    { 
        int min_tile_k = 1;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = (k_loop - 1) * 2 + 0;
                int v_tile_id = stage_id * 2 + min_tile_k;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][min_tile_k].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    flash::lower_priority();
    flash::wait_lds_data_arrived<false>(0);
    flash::raise_priority();

    { 
        int min_tile_k = 0;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = (k_loop - 1) * 2 + 1;
                int v_tile_id = 4 + stage_id * 2 + min_tile_k;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][min_tile_k].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    { 
        int min_tile_k = 1;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = (k_loop - 1) * 2 + 1;
                int v_tile_id = 4 + stage_id * 2 + min_tile_k;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][min_tile_k].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }
    flash::lower_priority();

}
                                                                           
template<bool PREFETCH_K, int kHeadDim, int kHeadDimV, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, int STAGES, typename Element, typename ElementAccum, bool Is_even_MN, bool DecodeCLoad = false>
__forceinline__ __device__ void pv_gemm_prefetch_k_mls_ds_576_512_nopage_64_new_999(
        Element* v_ptr_raw,
        vec4_uint k_ptr,
        vec4_uint v_ptr,
        Element* q_lds,
        Element* k_lds,
        Element* v_lds,
        union_vec2_f16x2<Element> p_reg[(WARP_M / 16) * (kBlockK / 32)][2],
        vec4_Accum<ElementAccum> pv_reg[(kHeadDimV / kBlockN) * (WARP_M / 16) * (kBlockN / 32)][2],
        int warp_id,
        int seqlen_q_stride,
        int seqlen_k_stride,
        int seqlen_v_stride,
        int* index_ptr,
        int batch_stride,
        int page_block_size,
        int n_loop_real,
        int max_seq_q_offset=0,
        int max_seq_kv_offset=0) {

    constexpr int WARP_NUM = kBlockM * kBlockN / (WARP_M * WARP_N);
    constexpr int WARP_K   = 16;
    constexpr int READ_ONCE_COUNT = 16 * 32;
    constexpr int kHeadDimV_OPT = 256;          // lds 32x32x8x2B == 16KB
    constexpr int V_LDS_LOAD_NUM  = (kHeadDimV_OPT * WARP_K) / READ_ONCE_COUNT;
    constexpr int V_LOAD_REQUESTS = V_LDS_LOAD_NUM / WARP_NUM;
    constexpr int ELEMENT_BYTES   = sizeof(Element);
    static_assert (kBlockK >= 32, "Error: pv gemm kBlockK must be equal or greater than 32");
    static_assert (kBlockM >= WARP_M, "Error: pv gemm kBlockM must be equal or greater than WARP_M");
    static_assert (kBlockN == WARP_N, "Error: pv gemm kBlockN must be equal to WARP_N");
    static_assert (WARP_K == 16 and "Error: To simplify, only WARP_K = 32 is supported!");
    static_assert (WARP_M == 16 and "Error: To simplify, only WARP_M = 16 is supported!");
    static_assert (WARP_N == 256 and "Error: To simplify, only WARP_N = 32 is supported!");

    // 计算 V lds 起始偏移量
    int v_lds_base = reinterpret_cast<size_t>(v_lds);

    int tid = threadIdx.x % 64;
    // 准备 V 寄存器
    union_vec4_f16x2<Element> v_reg[WARP_N / 32];

    // MLS
    vec4_uint v_srsrc;
    v_srsrc[0] = v_ptr[0];
    v_srsrc[1] = v_ptr[1];
    v_srsrc[2] = seqlen_v_stride; // stride
    v_srsrc[3] = 0;

    int index_topk[4];
    index_topk[0] = index_ptr[(n_loop_real * 64) + 0 * 16 + (tid / 4)];
    index_topk[1] = index_ptr[(n_loop_real * 64) + 1 * 16 + (tid / 4)];
    index_topk[2] = index_ptr[(n_loop_real * 64) + 2 * 16 + (tid / 4)];
    index_topk[3] = index_ptr[(n_loop_real * 64) + 3 * 16 + (tid / 4)];

    bool invalid_topk[4];
    invalid_topk[0] = index_topk[0] == -1;
    invalid_topk[1] = index_topk[1] == -1;
    invalid_topk[2] = index_topk[2] == -1;
    invalid_topk[3] = index_topk[3] == -1;

    int fallback_index = v_ptr[2];
    if constexpr (DecodeCLoad) {
        fallback_index = index_ptr[0] == -1 ? 0 : index_ptr[0];
    }
    index_topk[0] = (index_topk[0] == -1) ? fallback_index : index_topk[0];
    index_topk[1] = (index_topk[1] == -1) ? fallback_index : index_topk[1];
    index_topk[2] = (index_topk[2] == -1) ? fallback_index : index_topk[2];
    index_topk[3] = (index_topk[3] == -1) ? fallback_index : index_topk[3];

    int lds_offset = __builtin_amdgcn_readfirstlane((warp_id * 32 * 16) * ELEMENT_BYTES / 4);
    int lds_offset_2 = __builtin_amdgcn_readfirstlane((warp_id * 32 * 16 + 128 * 16) * ELEMENT_BYTES / 4);
    int index_block = index_topk[0] / page_block_size;
    int index_offset = index_topk[0] - index_block * page_block_size;
    int lane_dword = tid % 4 * 4;
    int g_offset_v = lane_dword + (index_block * batch_stride + index_offset * seqlen_v_stride) * ELEMENT_BYTES / 4;
    int g_offset_s = warp_id * 32 * ELEMENT_BYTES / 4;
    int g_offset_s_2 = warp_id * 32 * ELEMENT_BYTES / 4 + 128 * ELEMENT_BYTES / 4;
    using uint4_t = unsigned int __attribute__((ext_vector_type(4)));
    const uint4_t zero4 = {0u, 0u, 0u, 0u};
    flash::wait_all_warp_arrived();
    if constexpr (DecodeCLoad) {
        const int64_t token_base_elem = int64_t(index_block) * batch_stride + int64_t(index_offset) * seqlen_v_stride;
        const int64_t src0_elem = token_base_elem + int64_t(g_offset_s + tid % 4 * 4) * 4 / ELEMENT_BYTES;
        const int64_t src1_elem = token_base_elem + int64_t(g_offset_s_2 + tid % 4 * 4) * 4 / ELEMENT_BYTES;
        const int64_t lane_store_elem = int64_t(tid) * 16 / ELEMENT_BYTES;
        const int64_t dst0_elem = int64_t(lds_offset) * 4 / ELEMENT_BYTES + lane_store_elem;
        const int64_t dst1_elem = int64_t(lds_offset_2) * 4 / ELEMENT_BYTES + lane_store_elem;
        *reinterpret_cast<uint4_t*>(v_lds + dst0_elem) = invalid_topk[0] ? zero4 : *reinterpret_cast<const uint4_t*>(v_ptr_raw + src0_elem);
        *reinterpret_cast<uint4_t*>(v_lds + dst1_elem) = invalid_topk[0] ? zero4 : *reinterpret_cast<const uint4_t*>(v_ptr_raw + src1_elem);
    } else {
        inline_buffer_load_dwordx4_idxen_lds(v_lds, v_ptr, lds_offset, index_topk[0], g_offset_s, lane_dword);
        inline_buffer_load_dwordx4_idxen_lds(v_lds, v_ptr, lds_offset_2, index_topk[0], g_offset_s_2, lane_dword);
    }

    int lds_stage_id = 1;

    for(int total_loop = 1; total_loop < (kHeadDimV / kBlockN) * 4; ++total_loop) {
            
        {
            index_block = index_topk[total_loop / 2] / page_block_size;
            index_offset = index_topk[total_loop / 2] - index_block * page_block_size;
            lane_dword = tid % 4 * 4;
            g_offset_v = lane_dword + (index_block * batch_stride + index_offset * seqlen_v_stride) * ELEMENT_BYTES / 4;
            lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * WARP_N + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
            lds_offset_2 = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * WARP_N + warp_id * 32 * 16 + 128 * 16) * ELEMENT_BYTES / 4);
            g_offset_s = (total_loop % 2) * WARP_N * ELEMENT_BYTES / 4 + warp_id * 32 * ELEMENT_BYTES / 4;
            g_offset_s_2 = (total_loop % 2) * WARP_N * ELEMENT_BYTES / 4 + warp_id * 32 * ELEMENT_BYTES / 4 + 128 * ELEMENT_BYTES / 4;
            flash::wait_all_warp_arrived();
            if constexpr (DecodeCLoad) {
                const int64_t token_base_elem = int64_t(index_block) * batch_stride + int64_t(index_offset) * seqlen_v_stride;
                const int64_t src0_elem = token_base_elem + int64_t(g_offset_s + tid % 4 * 4) * 4 / ELEMENT_BYTES;
                const int64_t src1_elem = token_base_elem + int64_t(g_offset_s_2 + tid % 4 * 4) * 4 / ELEMENT_BYTES;
                const int64_t lane_store_elem = int64_t(tid) * 16 / ELEMENT_BYTES;
                const int64_t dst0_elem = int64_t(lds_offset) * 4 / ELEMENT_BYTES + lane_store_elem;
                const int64_t dst1_elem = int64_t(lds_offset_2) * 4 / ELEMENT_BYTES + lane_store_elem;
                const bool invalid_index = invalid_topk[total_loop / 2];
                *reinterpret_cast<uint4_t*>(v_lds + dst0_elem) = invalid_index ? zero4 : *reinterpret_cast<const uint4_t*>(v_ptr_raw + src0_elem);
                *reinterpret_cast<uint4_t*>(v_lds + dst1_elem) = invalid_index ? zero4 : *reinterpret_cast<const uint4_t*>(v_ptr_raw + src1_elem);
            } else {
                inline_buffer_load_dwordx4_idxen_lds(v_lds, v_ptr, lds_offset, index_topk[total_loop / 2], g_offset_s, lane_dword);
                inline_buffer_load_dwordx4_idxen_lds(v_lds, v_ptr, lds_offset_2, index_topk[total_loop / 2], g_offset_s_2, lane_dword);
            }
        }

        // 不对称MLS指令
        if constexpr (DecodeCLoad) {
            flash::wait_all_warp_arrived();
        } else {
            flash::wait_buffer_data_arrived<true>(V_LOAD_REQUESTS);
        }

        lds_stage_id ^= 1;
        int stage_id = 0;

        // K DS  
        {
            int v_lds_load_offset = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 0 * 16 * 64) * ELEMENT_BYTES;
            int v_lds_load_offset_2 = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 1 * 16 * 64) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(v_lds_load_offset, v_reg[stage_id * 2].f16, v_reg[stage_id * 2 + 1].f16, false);
            DS_READ_MATRIX_32X32_B16(v_lds_load_offset_2, v_reg[4 + stage_id * 2].f16, v_reg[4 + stage_id * 2 + 1].f16, false);
        }

        // K DS PRE
        stage_id ^= 1;
        {
            int v_lds_load_offset = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 0 * 16 * 64 + 16 * 128) * ELEMENT_BYTES;
            int v_lds_load_offset_2 = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 1 * 16 * 64 + 16 * 128) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(v_lds_load_offset, v_reg[stage_id * 2].f16, v_reg[stage_id * 2 + 1].f16, false);
            DS_READ_MATRIX_32X32_B16(v_lds_load_offset_2, v_reg[4 + stage_id * 2].f16, v_reg[4 + stage_id * 2 + 1].f16, false);
        }

        // Wait DS
        flash::wait_lds_data_arrived<false>(6);
        // flash::raise_priority();

        // MMAC 
        stage_id ^= 1;
        { 
            int min_tile_nk = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = lds_stage_id * 8 + 0;
                    int v_tile_id = stage_id * 2 + min_tile_nk;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[(total_loop - 1) / 4][((total_loop - 1) / 2 ) % 2].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_nk = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = lds_stage_id * 8 + 1;
                    int v_tile_id = stage_id * 2 + min_tile_nk;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[(total_loop - 1) / 4][((total_loop - 1) / 2 ) % 2].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        // flash::lower_priority();
        flash::wait_lds_data_arrived<false>(4);
        // flash::raise_priority();

        { 
            int min_tile_nk = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = lds_stage_id * 8 + 2;
                    int v_tile_id = 4 + stage_id * 2 + min_tile_nk;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[(total_loop - 1) / 4][((total_loop - 1) / 2 ) % 2].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_nk = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = lds_stage_id * 8 + 3;
                    int v_tile_id = 4 + stage_id * 2 + min_tile_nk;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[(total_loop - 1) / 4][((total_loop - 1) / 2 ) % 2].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        // flash::lower_priority();
        flash::wait_lds_data_arrived<false>(2);
        // flash::raise_priority();

        stage_id ^= 1;
        { 
            int min_tile_nk = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = lds_stage_id * 8 + 4;
                    int v_tile_id = stage_id * 2 + min_tile_nk;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[(total_loop - 1) / 4][((total_loop - 1) / 2 ) % 2].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_nk = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = lds_stage_id * 8 + 5;
                    int v_tile_id = stage_id * 2 + min_tile_nk;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[(total_loop - 1) / 4][((total_loop - 1) / 2 ) % 2].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        // flash::lower_priority();
        flash::wait_lds_data_arrived<false>(0);
        // flash::raise_priority();

        { 
            int min_tile_nk = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = lds_stage_id * 8 + 6;
                    int v_tile_id = 4 + stage_id * 2 + min_tile_nk;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[(total_loop - 1) / 4][((total_loop - 1) / 2 ) % 2].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_nk = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = lds_stage_id * 8 + 7;
                    int v_tile_id = 4 + stage_id * 2 + min_tile_nk;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[(total_loop - 1) / 4][((total_loop - 1) / 2 ) % 2].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }
        // flash::lower_priority();
        
    }

    // 等回最后的q_panel
    flash::wait_buffer_data_arrived<true>(0);

    lds_stage_id ^= 1;
    int stage_id = 0;

    // K DS  
    {
        int v_lds_load_offset = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 0 * 16 * 64) * ELEMENT_BYTES;
        int v_lds_load_offset_2 = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 1 * 16 * 64) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(v_lds_load_offset, v_reg[stage_id * 2].f16, v_reg[stage_id * 2 + 1].f16, false);
        DS_READ_MATRIX_32X32_B16(v_lds_load_offset_2, v_reg[4 + stage_id * 2].f16, v_reg[4 + stage_id * 2 + 1].f16, false);
    }

    // K DS PRE
    stage_id ^= 1;
    {
        int v_lds_load_offset = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 0 * 16 * 64 + 16 * 128) * ELEMENT_BYTES;
        int v_lds_load_offset_2 = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 1 * 16 * 64 + 16 * 128) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(v_lds_load_offset, v_reg[stage_id * 2].f16, v_reg[stage_id * 2 + 1].f16, false);
        DS_READ_MATRIX_32X32_B16(v_lds_load_offset_2, v_reg[4 + stage_id * 2].f16, v_reg[4 + stage_id * 2 + 1].f16, false);
    }

    // Wait DS
    flash::wait_lds_data_arrived<false>(6);
    // flash::raise_priority();

    // MMAC 
    stage_id ^= 1;
    { 
        int min_tile_nk = 0;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = lds_stage_id * 8 + 0;
                int v_tile_id = stage_id * 2 + min_tile_nk;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][1].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    { 
        int min_tile_nk = 1;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = lds_stage_id * 8 + 1;
                int v_tile_id = stage_id * 2 + min_tile_nk;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][1].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    // flash::lower_priority();
    flash::wait_lds_data_arrived<false>(4);
    // flash::raise_priority();

    { 
        int min_tile_nk = 0;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = lds_stage_id * 8 + 2;
                int v_tile_id = 4 + stage_id * 2 + min_tile_nk;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][1].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    { 
        int min_tile_nk = 1;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = lds_stage_id * 8 + 3;
                int v_tile_id = 4 + stage_id * 2 + min_tile_nk;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][1].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    // flash::lower_priority();
    flash::wait_lds_data_arrived<false>(2);
    // flash::raise_priority();

    stage_id ^= 1;
    { 
        int min_tile_nk = 0;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = lds_stage_id * 8 + 4;
                int v_tile_id = stage_id * 2 + min_tile_nk;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][1].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    { 
        int min_tile_nk = 1;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = lds_stage_id * 8 + 5;
                int v_tile_id = stage_id * 2 + min_tile_nk;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][1].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    // flash::lower_priority();
    flash::wait_lds_data_arrived<false>(0);

    // int abc[1];
    // int index_topk_qk = index_ptr[(((n_loop_real+1) % 16) * 64) + warp_id * 16];
    // int offset_m = index_topk_qk * seqlen_k_stride;
    // auto g_abc = (reinterpret_cast<uint64_t>(k_faker + offset_m)); 
    // inline_s_load_dword(abc[0], g_abc, 0); 

    // flash::raise_priority();

    { 
        int min_tile_nk = 0;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = lds_stage_id * 8 + 6;
                int v_tile_id = 4 + stage_id * 2 + min_tile_nk;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][1].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    { 
        int min_tile_nk = 1;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = lds_stage_id * 8 + 7;
                int v_tile_id = 4 + stage_id * 2 + min_tile_nk;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][1].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }
    // flash::lower_priority();

}

// Old topk=2048 prefill fast path. Keep separate from the generic paged/fallback variant.
template<bool NeedIndexGuard, bool PREFETCH_K, int kHeadDim, int kHeadDimV, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, int STAGES, typename Element, typename ElementAccum, bool Is_even_MN>
__forceinline__ __device__ void pv_gemm_prefetch_k_mls_ds_576_512_nopage_64_new_999_topk2048_fast(
        Element* k_faker,
        vec4_uint k_ptr,
        vec4_uint v_ptr,
        Element* q_lds,
        Element* k_lds,
        Element* v_lds,
        union_vec2_f16x2<Element> p_reg[(WARP_M / 16) * (kBlockK / 32)][2],
        vec4_Accum<ElementAccum> pv_reg[(kHeadDimV / kBlockN) * (WARP_M / 16) * (kBlockN / 32)][2],
        int warp_id,
        int seqlen_q_stride,
        int seqlen_k_stride,
        int seqlen_v_stride,
        int* index_ptr,
        int batch_stride,
        int n_loop_real,
        int max_seq_q_offset=0,
        int max_seq_kv_offset=0) {

    constexpr int WARP_NUM = kBlockM * kBlockN / (WARP_M * WARP_N);
    constexpr int WARP_K   = 16;
    constexpr int READ_ONCE_COUNT = 16 * 32;
    constexpr int kHeadDimV_OPT = 256;          // lds 32x32x8x2B == 16KB
    constexpr int V_LDS_LOAD_NUM  = (kHeadDimV_OPT * WARP_K) / READ_ONCE_COUNT;
    constexpr int V_LOAD_REQUESTS = V_LDS_LOAD_NUM / WARP_NUM;
    constexpr int ELEMENT_BYTES   = sizeof(Element);
    static_assert (kBlockK >= 32, "Error: pv gemm kBlockK must be equal or greater than 32");
    static_assert (kBlockM >= WARP_M, "Error: pv gemm kBlockM must be equal or greater than WARP_M");
    static_assert (kBlockN == WARP_N, "Error: pv gemm kBlockN must be equal to WARP_N");
    static_assert (WARP_K == 16 and "Error: To simplify, only WARP_K = 32 is supported!");
    static_assert (WARP_M == 16 and "Error: To simplify, only WARP_M = 16 is supported!");
    static_assert (WARP_N == 256 and "Error: To simplify, only WARP_N = 32 is supported!");

    // 计算 V lds 起始偏移量
    int v_lds_base = reinterpret_cast<size_t>(v_lds);

    int tid = threadIdx.x % 64;
    // 准备 V 寄存器
    union_vec4_f16x2<Element> v_reg[WARP_N / 32];

    // MLS
    vec4_uint v_srsrc;
    v_srsrc[0] = v_ptr[0];
    v_srsrc[1] = v_ptr[1];
    v_srsrc[2] = seqlen_v_stride; // stride
    v_srsrc[3] = 0;

    int index_topk[4];
    index_topk[0] = index_ptr[(n_loop_real * 64) + 0 * 16 + (tid / 4)];
    index_topk[1] = index_ptr[(n_loop_real * 64) + 1 * 16 + (tid / 4)];
    index_topk[2] = index_ptr[(n_loop_real * 64) + 2 * 16 + (tid / 4)];
    index_topk[3] = index_ptr[(n_loop_real * 64) + 3 * 16 + (tid / 4)];

    if constexpr (NeedIndexGuard) {
        int fallback_index = index_ptr[0] == -1 ? 0 : index_ptr[0];
        index_topk[0] = (index_topk[0] == -1) ? fallback_index : index_topk[0];
        index_topk[1] = (index_topk[1] == -1) ? fallback_index : index_topk[1];
        index_topk[2] = (index_topk[2] == -1) ? fallback_index : index_topk[2];
        index_topk[3] = (index_topk[3] == -1) ? fallback_index : index_topk[3];
    }

    int lds_offset = __builtin_amdgcn_readfirstlane((warp_id * 32 * 16) * ELEMENT_BYTES / 4);
    int lds_offset_2 = __builtin_amdgcn_readfirstlane((warp_id * 32 * 16 + 128 * 16) * ELEMENT_BYTES / 4);
    int g_offset_v = tid % 4 * 4 + index_topk[0] * seqlen_v_stride * ELEMENT_BYTES / 4;
    int g_offset_s = warp_id * 32 * ELEMENT_BYTES / 4;
    int g_offset_s_2 = warp_id * 32 * ELEMENT_BYTES / 4 + 128 * ELEMENT_BYTES / 4;
    flash::wait_all_warp_arrived();
    inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, g_offset_s, g_offset_v); 
    inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_2, g_offset_s_2, g_offset_v); 

    int lds_stage_id = 1;

    for(int total_loop = 1; total_loop < (kHeadDimV / kBlockN) * 4; ++total_loop) {
            
        {
            g_offset_v = tid % 4 * 4 + index_topk[total_loop / 2] * seqlen_v_stride * ELEMENT_BYTES / 4;
            lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * WARP_N + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
            lds_offset_2 = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * WARP_N + warp_id * 32 * 16 + 128 * 16) * ELEMENT_BYTES / 4);
            g_offset_s = (total_loop % 2) * WARP_N * ELEMENT_BYTES / 4 + warp_id * 32 * ELEMENT_BYTES / 4;
            g_offset_s_2 = (total_loop % 2) * WARP_N * ELEMENT_BYTES / 4 + warp_id * 32 * ELEMENT_BYTES / 4 + 128 * ELEMENT_BYTES / 4;
            flash::wait_all_warp_arrived();
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, g_offset_s, g_offset_v); 
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_2, g_offset_s_2, g_offset_v); 
        }

        // 不对称MLS指令
        flash::wait_buffer_data_arrived<true>(V_LOAD_REQUESTS);

        lds_stage_id ^= 1;
        int stage_id = 0;

        // K DS  
        {
            int v_lds_load_offset = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 0 * 16 * 64) * ELEMENT_BYTES;
            int v_lds_load_offset_2 = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 1 * 16 * 64) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(v_lds_load_offset, v_reg[stage_id * 2].f16, v_reg[stage_id * 2 + 1].f16, false);
            DS_READ_MATRIX_32X32_B16(v_lds_load_offset_2, v_reg[4 + stage_id * 2].f16, v_reg[4 + stage_id * 2 + 1].f16, false);
        }

        // K DS PRE
        stage_id ^= 1;
        {
            int v_lds_load_offset = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 0 * 16 * 64 + 16 * 128) * ELEMENT_BYTES;
            int v_lds_load_offset_2 = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 1 * 16 * 64 + 16 * 128) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(v_lds_load_offset, v_reg[stage_id * 2].f16, v_reg[stage_id * 2 + 1].f16, false);
            DS_READ_MATRIX_32X32_B16(v_lds_load_offset_2, v_reg[4 + stage_id * 2].f16, v_reg[4 + stage_id * 2 + 1].f16, false);
        }

        // Wait DS
        flash::wait_lds_data_arrived<false>(6);
        // flash::raise_priority();

        // MMAC 
        stage_id ^= 1;
        { 
            int min_tile_nk = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = lds_stage_id * 8 + 0;
                    int v_tile_id = stage_id * 2 + min_tile_nk;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[(total_loop - 1) / 4][((total_loop - 1) / 2 ) % 2].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_nk = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = lds_stage_id * 8 + 1;
                    int v_tile_id = stage_id * 2 + min_tile_nk;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[(total_loop - 1) / 4][((total_loop - 1) / 2 ) % 2].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        // flash::lower_priority();
        flash::wait_lds_data_arrived<false>(4);
        // flash::raise_priority();

        { 
            int min_tile_nk = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = lds_stage_id * 8 + 2;
                    int v_tile_id = 4 + stage_id * 2 + min_tile_nk;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[(total_loop - 1) / 4][((total_loop - 1) / 2 ) % 2].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_nk = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = lds_stage_id * 8 + 3;
                    int v_tile_id = 4 + stage_id * 2 + min_tile_nk;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[(total_loop - 1) / 4][((total_loop - 1) / 2 ) % 2].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        // flash::lower_priority();
        flash::wait_lds_data_arrived<false>(2);
        // flash::raise_priority();

        stage_id ^= 1;
        { 
            int min_tile_nk = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = lds_stage_id * 8 + 4;
                    int v_tile_id = stage_id * 2 + min_tile_nk;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[(total_loop - 1) / 4][((total_loop - 1) / 2 ) % 2].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_nk = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = lds_stage_id * 8 + 5;
                    int v_tile_id = stage_id * 2 + min_tile_nk;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[(total_loop - 1) / 4][((total_loop - 1) / 2 ) % 2].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        // flash::lower_priority();
        flash::wait_lds_data_arrived<false>(0);
        // flash::raise_priority();

        { 
            int min_tile_nk = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = lds_stage_id * 8 + 6;
                    int v_tile_id = 4 + stage_id * 2 + min_tile_nk;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[(total_loop - 1) / 4][((total_loop - 1) / 2 ) % 2].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }

        { 
            int min_tile_nk = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    int pv_tile_id = lds_stage_id * 8 + 7;
                    int v_tile_id = 4 + stage_id * 2 + min_tile_nk;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[(total_loop - 1) / 4][((total_loop - 1) / 2 ) % 2].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
            }
        }
        // flash::lower_priority();
        
    }

    // 等回最后的q_panel
    flash::wait_buffer_data_arrived<true>(0);

    lds_stage_id ^= 1;
    int stage_id = 0;

    // K DS  
    {
        int v_lds_load_offset = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 0 * 16 * 64) * ELEMENT_BYTES;
        int v_lds_load_offset_2 = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 1 * 16 * 64) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(v_lds_load_offset, v_reg[stage_id * 2].f16, v_reg[stage_id * 2 + 1].f16, false);
        DS_READ_MATRIX_32X32_B16(v_lds_load_offset_2, v_reg[4 + stage_id * 2].f16, v_reg[4 + stage_id * 2 + 1].f16, false);
    }

    // K DS PRE
    stage_id ^= 1;
    {
        int v_lds_load_offset = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 0 * 16 * 64 + 16 * 128) * ELEMENT_BYTES;
        int v_lds_load_offset_2 = v_lds_base + (lds_stage_id * WARP_N * WARP_K + 1 * 16 * 64 + 16 * 128) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(v_lds_load_offset, v_reg[stage_id * 2].f16, v_reg[stage_id * 2 + 1].f16, false);
        DS_READ_MATRIX_32X32_B16(v_lds_load_offset_2, v_reg[4 + stage_id * 2].f16, v_reg[4 + stage_id * 2 + 1].f16, false);
    }

    // Wait DS
    flash::wait_lds_data_arrived<false>(6);
    // flash::raise_priority();

    // MMAC 
    stage_id ^= 1;
    { 
        int min_tile_nk = 0;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = lds_stage_id * 8 + 0;
                int v_tile_id = stage_id * 2 + min_tile_nk;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][1].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    { 
        int min_tile_nk = 1;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = lds_stage_id * 8 + 1;
                int v_tile_id = stage_id * 2 + min_tile_nk;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][1].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    // flash::lower_priority();
    flash::wait_lds_data_arrived<false>(4);
    // flash::raise_priority();

    { 
        int min_tile_nk = 0;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = lds_stage_id * 8 + 2;
                int v_tile_id = 4 + stage_id * 2 + min_tile_nk;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][1].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    { 
        int min_tile_nk = 1;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = lds_stage_id * 8 + 3;
                int v_tile_id = 4 + stage_id * 2 + min_tile_nk;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][1].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    // flash::lower_priority();
    flash::wait_lds_data_arrived<false>(2);
    // flash::raise_priority();

    stage_id ^= 1;
    { 
        int min_tile_nk = 0;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = lds_stage_id * 8 + 4;
                int v_tile_id = stage_id * 2 + min_tile_nk;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][1].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    { 
        int min_tile_nk = 1;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = lds_stage_id * 8 + 5;
                int v_tile_id = stage_id * 2 + min_tile_nk;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][1].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    // flash::lower_priority();
    flash::wait_lds_data_arrived<false>(0);

    int abc[1];
    int index_topk_qk = index_ptr[(((n_loop_real+1) % 16) * 64) + warp_id * 16];
    int offset_m = index_topk_qk * seqlen_k_stride;
    auto g_abc = (reinterpret_cast<uint64_t>(k_faker + offset_m)); 
    inline_s_load_dword(abc[0], g_abc, 0); 

    // flash::raise_priority();

    { 
        int min_tile_nk = 0;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = lds_stage_id * 8 + 6;
                int v_tile_id = 4 + stage_id * 2 + min_tile_nk;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][1].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }

    { 
        int min_tile_nk = 1;
        #pragma unroll
        for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                int pv_tile_id = lds_stage_id * 8 + 7;
                int v_tile_id = 4 + stage_id * 2 + min_tile_nk;
                pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                    p_reg[1][1].f16x4,
                    v_reg[v_tile_id].f16x4[min_tile_n],
                    pv_reg[pv_tile_id][min_tile_n].f32);
        }
    }
    // flash::lower_priority();

}

template<bool PREFETCH_K, int kHeadDim, int kHeadDimV, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, int STAGES, typename Element, typename ElementAccum, bool Is_even_MN>
__forceinline__ __device__ void pv_gemm_prefetch_k_mls_ds_576_512_nopage_64_new_2(
        vec4_uint q_ptr,
        vec4_uint k_ptr,
        vec4_uint v_ptr,
        Element* q_lds,
        Element* k_lds,
        Element* v_lds,
        union_vec2_f16x2<Element> p_reg[(WARP_M / 16) * (kBlockK / 32)][2],
        vec4_Accum<ElementAccum> pv_reg[(kHeadDimV / kBlockN) * (WARP_M / 16) * (kBlockN / 32)][2],
        int warp_id,
        int seqlen_q_stride,
        int seqlen_k_stride,
        int seqlen_v_stride,
        int* index_ptr,
        int batch_stride,
        int n_loop_real,
        int max_seq_q_offset=0,
        int max_seq_kv_offset=0) {

    constexpr int WARP_NUM = kBlockM * kBlockN / (WARP_M * WARP_N);
    constexpr int WARP_K   = 16;
    constexpr int READ_ONCE_COUNT = 32 * 16;
    constexpr int kHeadDimV_OPT = 128;          // lds 32x32x8x2B == 16KB
    constexpr int V_LDS_LOAD_NUM  = (kHeadDimV_OPT * WARP_K) / READ_ONCE_COUNT;
    constexpr int V_LOAD_REQUESTS = V_LDS_LOAD_NUM / WARP_NUM;
    constexpr int ELEMENT_BYTES   = sizeof(Element);
    static_assert (kBlockK >= 32, "Error: pv gemm kBlockK must be equal or greater than 32");
    static_assert (kBlockM >= WARP_M, "Error: pv gemm kBlockM must be equal or greater than WARP_M");
    static_assert (kBlockN == WARP_N, "Error: pv gemm kBlockN must be equal to WARP_N");
    // static_assert (WARP_K == 32 and "Error: To simplify, only WARP_K = 32 is supported!");
    static_assert (WARP_M == 16 and "Error: To simplify, only WARP_M = 16 is supported!");
    static_assert (WARP_N == 32 and "Error: To simplify, only WARP_N = 32 is supported!");

    // 计算 V lds 起始偏移量
    int v_lds_base = reinterpret_cast<size_t>(v_lds);

    int tid = threadIdx.x % 64;
    // 准备 V 寄存器
    union_vec4_f16x2<Element> v_reg[STAGES * (16 * WARP_N) / (32 * 32) * 2];

    // MLS
    vec4_uint v_srsrc;
    v_srsrc[0] = v_ptr[0];
    v_srsrc[1] = v_ptr[1];
    v_srsrc[2] = seqlen_v_stride; // stride
    v_srsrc[3] = 0;

    int lds_stage_id = 1;
    for (int n_loop = 1; n_loop < (kBlockK / WARP_K); ++n_loop) {
        // prefetch same warpk, next 32x256 G2S
        {   
            int n_load = 1;
            int n_loop_ = n_loop - 1;
            // *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + n_load * WARP_NUM * 32) * ELEMENT_BYTES);
            // if constexpr (true) {
            //     int nm_filter     = inline_min_max<0, 32>(n_loop_ * WARP_K + 32 - max_seq_kv_offset);
            //     v_srsrc[3]        = max_seq_kv_offset % kBlockK == 0 ? 0: nm_filter << 8;
            // }
            // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
            // flash::wait_all_warp_arrived();
            // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

            int index_topk_1 = index_ptr[n_loop_ * 16 + n_loop_real * 64 + (tid / 4)];
            // int index_topk_2 = index_ptr[n_loop_real * 64 + (tid / 4) + 16];

            int lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
            int g_offset_v = n_load * WARP_NUM * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_1 * seqlen_v_stride * ELEMENT_BYTES / 4;
            // int lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            // int g_offset_v_add = n_load * WARP_NUM * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_2 * seqlen_v_stride * ELEMENT_BYTES / 4;
            flash::wait_all_warp_arrived();
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
            // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
            // g_offset_v += WARP_NUM * 32 * ELEMENT_BYTES / 4;
            // g_offset_v_add += WARP_NUM * 32 * ELEMENT_BYTES / 4;
            // lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
            // lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
            // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
            // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
        }
        
        // DS
        lds_stage_id ^= 1;
        int stage_id = 0;
        flash::wait_buffer_data_arrived<true>(V_LOAD_REQUESTS);

        int lds_load_offset = v_lds_base + (0/*k_loop*/ * 32 * 16 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X16_B16(lds_load_offset, v_reg[stage_id].f16, false/*transpose*/);

        stage_id ^= 1;
        for (int k_loop = 1; k_loop < (kHeadDimV / kBlockN); ++k_loop) {

            // Wait for special headdim
            if ((k_loop & 3) == 0x0) {
                flash::wait_buffer_data_arrived<true>(0);   
                lds_stage_id ^= 1;
            }

            int lds_load_offset = v_lds_base + ((k_loop & 3) * 32 * 16 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X16_B16(lds_load_offset, v_reg[stage_id].f16, false/*transpose*/);
            flash::wait_lds_data_arrived<false>(1);

            // MMAC
            flash::raise_priority();
            stage_id ^= 1;
            {
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[(n_loop - 1)/2][(n_loop - 1)%2].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::lower_priority();

            // MLS for special headdimV
            if ((k_loop & 3) == 0x0) {
                int n_loop_ = n_loop;
                lds_stage_id ^= 1;
                // if constexpr (Is_even_MN) {
                //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
                // } else {
                //     int nm_filter_max = n_loop_ * WARP_K + 32 - max_seq_kv_offset;
                //     int real_mls_loop = nm_filter_max >= 32 ? 0: n_loop_; // 如果全越界了, 则只访问 n_loop = 0 的那波数据
                //     int nm_filter     = inline_min_max<0, 32>(real_mls_loop * WARP_K + 32 - max_seq_kv_offset); // 重新计算 nm_filter
                //     v_srsrc[3]        = nm_filter << 8;
                //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (real_mls_loop * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
                // }
                // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
                // flash::wait_all_warp_arrived(); // 预防有 warp 还没算完7,还在读 v lds, 若是此时写 v lds,则 data cover
                // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

                int index_topk_1 = index_ptr[(n_loop - 1) * 16 + k_loop / 12 * 16 + n_loop_real * 64 + (tid / 4)];
                // int index_topk_2 = index_ptr[k_loop / 12 * 32 + n_loop_real * 64 + (tid / 4) + 16];

                int lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
                int g_offset_v = ((k_loop + 4) & 15) * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_1 * seqlen_v_stride * ELEMENT_BYTES / 4;
                // int lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
                // int g_offset_v_add = ((k_loop + 4) & 15) * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_2 * seqlen_v_stride * ELEMENT_BYTES / 4;
                flash::wait_all_warp_arrived();
                inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
                // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
                // g_offset_v += WARP_NUM * 32 * ELEMENT_BYTES / 4;
                // g_offset_v_add += WARP_NUM * 32 * ELEMENT_BYTES / 4;
                // lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
                // lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
                // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
                // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
                lds_stage_id ^= 1;
            }
        }
        stage_id ^= 1;
        // Wait DS
        flash::wait_lds_data_arrived<false>(0);
        // last mmac
        flash::raise_priority();
        {
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[(n_loop - 1)/2][(n_loop - 1)%2].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::lower_priority();
    }

    {
        constexpr int n_loop = kBlockK / WARP_K;
        // MLS for special headdimV
        {
            constexpr int n_loop_ = n_loop - 1;
            int n_load = 1;
            // lds_stage_id ^= 1;
            
            // if constexpr (Is_even_MN) {
            //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + n_load * WARP_NUM * 32) * ELEMENT_BYTES);
            // } else {
            //     int nm_filter_max = n_loop_ * WARP_K + 32 - max_seq_kv_offset;
            //     int real_mls_loop = nm_filter_max >= 32 ? 0: n_loop_; // 如果全越界了, 则只访问 n_loop = 0 的那波数据
            //     int nm_filter     = inline_min_max<0, 32>(real_mls_loop * WARP_K + 32 - max_seq_kv_offset); // 重新计算 nm_filter
            //     v_srsrc[3]        = nm_filter << 8;
            //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (real_mls_loop * WARP_K * seqlen_v_stride + warp_id * 32 + n_load * WARP_NUM * 32) * ELEMENT_BYTES);
            // }
            // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
            // flash::wait_all_warp_arrived();
            // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

            int index_topk_1 = index_ptr[n_loop_ * 16 + n_loop_real * 64 + (tid / 4)];
            // int index_topk_2 = index_ptr[n_loop_ * 32 + n_loop_real * 64 + (tid / 4) + 16];

            int lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
            int g_offset_v = n_load * WARP_NUM * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_1 * seqlen_v_stride * ELEMENT_BYTES / 4;
            // int lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            // int g_offset_v_add = n_load * WARP_NUM * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_2 * seqlen_v_stride * ELEMENT_BYTES / 4;
            flash::wait_all_warp_arrived();
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
            // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add);
            // g_offset_v += WARP_NUM * 32 * ELEMENT_BYTES / 4;
            // g_offset_v_add += WARP_NUM * 32 * ELEMENT_BYTES / 4;
            // lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
            // lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
            // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
            // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
        }

        lds_stage_id ^= 1;
        int stage_id = 0;

        flash::wait_buffer_data_arrived<true>(V_LOAD_REQUESTS); // [TODO]更早的预取

        // DS
        int lds_load_offset = v_lds_base + (0/*k_loop*/ * 32 * 16 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X16_B16(lds_load_offset, v_reg[stage_id].f16, false/*transpose*/);

        stage_id ^= 1;
        for (int k_loop = 1; k_loop < (kHeadDimV / kBlockN); ++k_loop) {

            // Wait for special headdim
            if ((k_loop & 3) == 0x0) {
                flash::wait_buffer_data_arrived<true>(0);   
                lds_stage_id ^= 1;
            }

            // DS
            int lds_load_offset = v_lds_base + ((k_loop & 3) * 32 * 16 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X16_B16(lds_load_offset, v_reg[stage_id].f16, false/*transpose*/);
            flash::wait_lds_data_arrived<false>(1);

            // MMAC
            flash::raise_priority();
            stage_id ^= 1;
            {
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[(n_loop - 1)/2][(n_loop - 1)%2].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::lower_priority();

            // MLS for special headdimV
            if (k_loop == 4 || k_loop == 8) {
                lds_stage_id ^= 1;
                // if constexpr (Is_even_MN) {
                //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
                // } else {
                //     int nm_filter_max = n_loop_ * WARP_K + 32 - max_seq_kv_offset;
                //     int real_mls_loop = nm_filter_max >= 32 ? 0: n_loop_; // 如果全越界了, 则只访问 n_loop = 0 的那波数据
                //     int nm_filter     = inline_min_max<0, 32>(real_mls_loop * WARP_K + 32 - max_seq_kv_offset); // 重新计算 nm_filter
                //     v_srsrc[3]        = nm_filter << 8;
                //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (real_mls_loop * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
                // }
                // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
                // flash::wait_all_warp_arrived(); // 预防有 warp 还没算完7,还在读 v lds, 若是此时写 v lds,则 data cover
                // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

                int index_topk_1 = index_ptr[48 + n_loop_real * 64 + (tid / 4)];
                // int index_topk_2 = index_ptr[32 + n_loop_real * 64 + (tid / 4) + 16];

                int lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 16) * ELEMENT_BYTES / 4);
                int g_offset_v = ((k_loop + 4) & 15) * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_1 * seqlen_v_stride * ELEMENT_BYTES / 4;
                // int lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
                // int g_offset_v_add = ((k_loop + 4) & 15) * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_2 * seqlen_v_stride * ELEMENT_BYTES / 4;
                flash::wait_all_warp_arrived();
                inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
                // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
                // g_offset_v += WARP_NUM * 32 * ELEMENT_BYTES / 4;
                // g_offset_v_add += WARP_NUM * 32 * ELEMENT_BYTES / 4;
                // lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
                // lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
                // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
                // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
                lds_stage_id ^= 1;
            }
        }

        stage_id ^= 1;
        flash::wait_lds_data_arrived<false>(0);
        // last mmac
        flash::raise_priority();
        {
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[(n_loop - 1)/2][(n_loop - 1)%2].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::lower_priority();
    }

    
    // 预取Q K
    if constexpr (PREFETCH_K) {
        prefetch_q_to_lds_mls_ds_576_512<kHeadDim, kBlockM, kBlockK, WARP_M, Element, Is_even_MN>(q_ptr, q_lds, warp_id, seqlen_q_stride, max_seq_q_offset);
        prefetch_k_to_lds_mls_ds_576_512<kHeadDim, kBlockK, kBlockN, WARP_NUM, WARP_N, Element, Is_even_MN>(k_ptr, k_lds, warp_id, seqlen_k_stride, max_seq_kv_offset - kBlockK);
    }
}

template<bool PREFETCH_K, int kHeadDim, int kHeadDimV, int kBlockM, int kBlockN, int kBlockK, int WARP_M, int WARP_N, int STAGES, typename Element, typename ElementAccum, bool Is_even_MN>
__forceinline__ __device__ void pv_gemm_prefetch_k_mls_ds_576_512_nopage_64_new_1(
        vec4_uint q_ptr,
        vec4_uint k_ptr,
        vec4_uint v_ptr,
        Element* q_lds,
        Element* k_lds,
        Element* v_lds,
        union_vec2_f16x2<Element> p_reg[(WARP_M / 16) * (kBlockK / 32)][2],
        vec4_Accum<ElementAccum> pv_reg[(kHeadDimV / kBlockN) * (WARP_M / 16) * (kBlockN / 32)][2],
        int warp_id,
        int seqlen_q_stride,
        int seqlen_k_stride,
        int seqlen_v_stride,
        int* index_ptr,
        int batch_stride,
        int n_loop_real,
        int max_seq_q_offset=0,
        int max_seq_kv_offset=0) {

    constexpr int WARP_NUM = kBlockM * kBlockN / (WARP_M * WARP_N);
    constexpr int WARP_K   = 32;
    constexpr int READ_ONCE_COUNT = 32 * 32;
    constexpr int kHeadDimV_OPT = 128;          // lds 32x32x8x2B == 16KB
    constexpr int V_LDS_LOAD_NUM  = (kHeadDimV_OPT * WARP_K) / READ_ONCE_COUNT;
    constexpr int V_LOAD_REQUESTS = V_LDS_LOAD_NUM / WARP_NUM;
    constexpr int ELEMENT_BYTES   = sizeof(Element);
    static_assert (kBlockK >= 32, "Error: pv gemm kBlockK must be equal or greater than 32");
    static_assert (kBlockM >= WARP_M, "Error: pv gemm kBlockM must be equal or greater than WARP_M");
    static_assert (kBlockN == WARP_N, "Error: pv gemm kBlockN must be equal to WARP_N");
    static_assert (WARP_K == 32 and "Error: To simplify, only WARP_K = 32 is supported!");
    static_assert (WARP_M == 16 and "Error: To simplify, only WARP_M = 16 is supported!");
    static_assert (WARP_N == 32 and "Error: To simplify, only WARP_N = 32 is supported!");

    // 计算 V lds 起始偏移量
    int v_lds_base = reinterpret_cast<size_t>(v_lds);

    int tid = threadIdx.x % 64;
    // 准备 V 寄存器
    union_vec4_f16x2<Element> v_reg[STAGES * (32 * WARP_N) / (32 * 32) * 2];

    // MLS
    vec4_uint v_srsrc;
    v_srsrc[0] = v_ptr[0];
    v_srsrc[1] = v_ptr[1];
    v_srsrc[2] = seqlen_v_stride; // stride
    v_srsrc[3] = 0;

    int lds_stage_id = 1;
    for (int n_loop = 1; n_loop < (kBlockK / WARP_K); ++n_loop) {
        // prefetch same warpk, next 32x256 G2S
        {   
            int n_load = 1;
            int n_loop_ = n_loop - 1;
            // *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + n_load * WARP_NUM * 32) * ELEMENT_BYTES);
            // if constexpr (true) {
            //     int nm_filter     = inline_min_max<0, 32>(n_loop_ * WARP_K + 32 - max_seq_kv_offset);
            //     v_srsrc[3]        = max_seq_kv_offset % kBlockK == 0 ? 0: nm_filter << 8;
            // }
            // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
            // flash::wait_all_warp_arrived();
            // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

            int index_topk_1 = index_ptr[n_loop_real * 64 + (tid / 4)];
            int index_topk_2 = index_ptr[n_loop_real * 64 + (tid / 4) + 16];

            int lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            int g_offset_v = n_load * WARP_NUM * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_1 * seqlen_v_stride * ELEMENT_BYTES / 4;
            int lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            int g_offset_v_add = n_load * WARP_NUM * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_2 * seqlen_v_stride * ELEMENT_BYTES / 4;
            flash::wait_all_warp_arrived();
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
            // g_offset_v += WARP_NUM * 32 * ELEMENT_BYTES / 4;
            // g_offset_v_add += WARP_NUM * 32 * ELEMENT_BYTES / 4;
            // lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
            // lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
            // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
            // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
        }
        
        // DS
        lds_stage_id ^= 1;
        int stage_id = 0;
        flash::wait_buffer_data_arrived<true>(V_LOAD_REQUESTS*2);

        int lds_load_offset = v_lds_base + (0/*k_loop*/ * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);
        int k_loop = 1;
        stage_id ^= 1;
        for (; k_loop < 4; ++k_loop) {

            int lds_load_offset = v_lds_base + ((k_loop & 3) * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);
            flash::wait_lds_data_arrived<false>(3);

            // MMAC
            flash::raise_priority();
            stage_id ^= 1;
            {
                constexpr int min_tile_k = 0;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::wait_lds_data_arrived<false>(2);
            {
                constexpr int min_tile_k = 1;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::lower_priority();
        }

        // Wait for special headdim
        flash::wait_buffer_data_arrived<true>(0);   
        lds_stage_id ^= 1;

        lds_load_offset = v_lds_base + ((k_loop & 3) * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);
        flash::wait_lds_data_arrived<false>(3);

        // MMAC
        flash::raise_priority();
        stage_id ^= 1;
        {
            constexpr int min_tile_k = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::wait_lds_data_arrived<false>(2);
        {
            constexpr int min_tile_k = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::lower_priority();

        // MLS for special headdimV
        int n_loop_ = n_loop;
        lds_stage_id ^= 1;
        // if constexpr (Is_even_MN) {
        //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
        // } else {
        //     int nm_filter_max = n_loop_ * WARP_K + 32 - max_seq_kv_offset;
        //     int real_mls_loop = nm_filter_max >= 32 ? 0: n_loop_; // 如果全越界了, 则只访问 n_loop = 0 的那波数据
        //     int nm_filter     = inline_min_max<0, 32>(real_mls_loop * WARP_K + 32 - max_seq_kv_offset); // 重新计算 nm_filter
        //     v_srsrc[3]        = nm_filter << 8;
        //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (real_mls_loop * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
        // }
        // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
        // flash::wait_all_warp_arrived(); // 预防有 warp 还没算完7,还在读 v lds, 若是此时写 v lds,则 data cover
        // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

        int index_topk_1 = index_ptr[k_loop / 12 * 32 + n_loop_real * 64 + (tid / 4)];
        int index_topk_2 = index_ptr[k_loop / 12 * 32 + n_loop_real * 64 + (tid / 4) + 16];

        int lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
        int g_offset_v = ((k_loop + 4) & 15) * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_1 * seqlen_v_stride * ELEMENT_BYTES / 4;
        int lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
        int g_offset_v_add = ((k_loop + 4) & 15) * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_2 * seqlen_v_stride * ELEMENT_BYTES / 4;
        flash::wait_all_warp_arrived();
        inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
        inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
        // g_offset_v += WARP_NUM * 32 * ELEMENT_BYTES / 4;
        // g_offset_v_add += WARP_NUM * 32 * ELEMENT_BYTES / 4;
        // lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
        // lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
        // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
        // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
        lds_stage_id ^= 1;

        k_loop++;

        for (; k_loop < 8; ++k_loop) {

            int lds_load_offset = v_lds_base + ((k_loop & 3) * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);
            flash::wait_lds_data_arrived<false>(3);

            // MMAC
            flash::raise_priority();
            stage_id ^= 1;
            {
                constexpr int min_tile_k = 0;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::wait_lds_data_arrived<false>(2);
            {
                constexpr int min_tile_k = 1;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::lower_priority();
        }

        // Wait for special headdim
        flash::wait_buffer_data_arrived<true>(0);   
        lds_stage_id ^= 1;

        lds_load_offset = v_lds_base + ((k_loop & 3) * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);
        flash::wait_lds_data_arrived<false>(3);

        // MMAC
        flash::raise_priority();
        stage_id ^= 1;
        {
            constexpr int min_tile_k = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::wait_lds_data_arrived<false>(2);
        {
            constexpr int min_tile_k = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::lower_priority();

        // MLS for special headdimV
        n_loop_ = n_loop;
        lds_stage_id ^= 1;
        // if constexpr (Is_even_MN) {
        //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
        // } else {
        //     int nm_filter_max = n_loop_ * WARP_K + 32 - max_seq_kv_offset;
        //     int real_mls_loop = nm_filter_max >= 32 ? 0: n_loop_; // 如果全越界了, 则只访问 n_loop = 0 的那波数据
        //     int nm_filter     = inline_min_max<0, 32>(real_mls_loop * WARP_K + 32 - max_seq_kv_offset); // 重新计算 nm_filter
        //     v_srsrc[3]        = nm_filter << 8;
        //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (real_mls_loop * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
        // }
        // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
        // flash::wait_all_warp_arrived(); // 预防有 warp 还没算完7,还在读 v lds, 若是此时写 v lds,则 data cover
        // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

         index_topk_1 = index_ptr[k_loop / 12 * 32 + n_loop_real * 64 + (tid / 4)];
         index_topk_2 = index_ptr[k_loop / 12 * 32 + n_loop_real * 64 + (tid / 4) + 16];

         lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
         g_offset_v = ((k_loop + 4) & 15) * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_1 * seqlen_v_stride * ELEMENT_BYTES / 4;
         lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
         g_offset_v_add = ((k_loop + 4) & 15) * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_2 * seqlen_v_stride * ELEMENT_BYTES / 4;
        flash::wait_all_warp_arrived();
        inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
        inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
        // g_offset_v += WARP_NUM * 32 * ELEMENT_BYTES / 4;
        // g_offset_v_add += WARP_NUM * 32 * ELEMENT_BYTES / 4;
        // lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
        // lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
        // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
        // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
        lds_stage_id ^= 1;
        
        k_loop++;

        for (; k_loop < 12; ++k_loop) {

            int lds_load_offset = v_lds_base + ((k_loop & 3) * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);
            flash::wait_lds_data_arrived<false>(3);

            // MMAC
            flash::raise_priority();
            stage_id ^= 1;
            {
                constexpr int min_tile_k = 0;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::wait_lds_data_arrived<false>(2);
            {
                constexpr int min_tile_k = 1;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::lower_priority();
        }

        // Wait for special headdim
        flash::wait_buffer_data_arrived<true>(0);   
        lds_stage_id ^= 1;

        lds_load_offset = v_lds_base + ((k_loop & 3) * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);
        flash::wait_lds_data_arrived<false>(3);

        // MMAC
        flash::raise_priority();
        stage_id ^= 1;
        {
            constexpr int min_tile_k = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::wait_lds_data_arrived<false>(2);
        {
            constexpr int min_tile_k = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::lower_priority();

        // MLS for special headdimV
        n_loop_ = n_loop;
        lds_stage_id ^= 1;
        // if constexpr (Is_even_MN) {
        //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
        // } else {
        //     int nm_filter_max = n_loop_ * WARP_K + 32 - max_seq_kv_offset;
        //     int real_mls_loop = nm_filter_max >= 32 ? 0: n_loop_; // 如果全越界了, 则只访问 n_loop = 0 的那波数据
        //     int nm_filter     = inline_min_max<0, 32>(real_mls_loop * WARP_K + 32 - max_seq_kv_offset); // 重新计算 nm_filter
        //     v_srsrc[3]        = nm_filter << 8;
        //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (real_mls_loop * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
        // }
        // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
        // flash::wait_all_warp_arrived(); // 预防有 warp 还没算完7,还在读 v lds, 若是此时写 v lds,则 data cover
        // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

         index_topk_1 = index_ptr[k_loop / 12 * 32 + n_loop_real * 64 + (tid / 4)];
         index_topk_2 = index_ptr[k_loop / 12 * 32 + n_loop_real * 64 + (tid / 4) + 16];

         lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
         g_offset_v = ((k_loop + 4) & 15) * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_1 * seqlen_v_stride * ELEMENT_BYTES / 4;
         lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
         g_offset_v_add = ((k_loop + 4) & 15) * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_2 * seqlen_v_stride * ELEMENT_BYTES / 4;
        flash::wait_all_warp_arrived();
        inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
        inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
        // g_offset_v += WARP_NUM * 32 * ELEMENT_BYTES / 4;
        // g_offset_v_add += WARP_NUM * 32 * ELEMENT_BYTES / 4;
        // lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
        // lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
        // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
        // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
        lds_stage_id ^= 1;
        
        k_loop++;

        for (; k_loop < 16; ++k_loop) {

            int lds_load_offset = v_lds_base + ((k_loop & 3) * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);
            flash::wait_lds_data_arrived<false>(3);

            // MMAC
            flash::raise_priority();
            stage_id ^= 1;
            {
                constexpr int min_tile_k = 0;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::wait_lds_data_arrived<false>(2);
            {
                constexpr int min_tile_k = 1;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::lower_priority();
        }

        // Wait for special headdim
        flash::wait_buffer_data_arrived<true>(0);   
        lds_stage_id ^= 1;

        lds_load_offset = v_lds_base + ((k_loop & 3) * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);
        flash::wait_lds_data_arrived<false>(3);

        // MMAC
        flash::raise_priority();
        stage_id ^= 1;
        {
            constexpr int min_tile_k = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::wait_lds_data_arrived<false>(2);
        {
            constexpr int min_tile_k = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::lower_priority();

        // MLS for special headdimV
        n_loop_ = n_loop;
        lds_stage_id ^= 1;
        // if constexpr (Is_even_MN) {
        //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
        // } else {
        //     int nm_filter_max = n_loop_ * WARP_K + 32 - max_seq_kv_offset;
        //     int real_mls_loop = nm_filter_max >= 32 ? 0: n_loop_; // 如果全越界了, 则只访问 n_loop = 0 的那波数据
        //     int nm_filter     = inline_min_max<0, 32>(real_mls_loop * WARP_K + 32 - max_seq_kv_offset); // 重新计算 nm_filter
        //     v_srsrc[3]        = nm_filter << 8;
        //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (real_mls_loop * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
        // }
        // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
        // flash::wait_all_warp_arrived(); // 预防有 warp 还没算完7,还在读 v lds, 若是此时写 v lds,则 data cover
        // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

         index_topk_1 = index_ptr[k_loop / 12 * 32 + n_loop_real * 64 + (tid / 4)];
         index_topk_2 = index_ptr[k_loop / 12 * 32 + n_loop_real * 64 + (tid / 4) + 16];

         lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
         g_offset_v = ((k_loop + 4) & 15) * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_1 * seqlen_v_stride * ELEMENT_BYTES / 4;
         lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
         g_offset_v_add = ((k_loop + 4) & 15) * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_2 * seqlen_v_stride * ELEMENT_BYTES / 4;
        flash::wait_all_warp_arrived();
        inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
        inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
        // g_offset_v += WARP_NUM * 32 * ELEMENT_BYTES / 4;
        // g_offset_v_add += WARP_NUM * 32 * ELEMENT_BYTES / 4;
        // lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
        // lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
        // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
        // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
        lds_stage_id ^= 1;
        
        k_loop++;

        stage_id ^= 1;
        // Wait DS
        flash::wait_lds_data_arrived<false>(1);
        // last mmac
        flash::raise_priority();
        {
            constexpr int min_tile_k = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::wait_lds_data_arrived<false>(0);
        {
            constexpr int min_tile_k = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::lower_priority();
    }

    {
        constexpr int n_loop = kBlockK / WARP_K;
        // MLS for special headdimV
        {
            constexpr int n_loop_ = n_loop - 1;
            int n_load = 1;
            // lds_stage_id ^= 1;
            
            // if constexpr (Is_even_MN) {
            //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + n_load * WARP_NUM * 32) * ELEMENT_BYTES);
            // } else {
            //     int nm_filter_max = n_loop_ * WARP_K + 32 - max_seq_kv_offset;
            //     int real_mls_loop = nm_filter_max >= 32 ? 0: n_loop_; // 如果全越界了, 则只访问 n_loop = 0 的那波数据
            //     int nm_filter     = inline_min_max<0, 32>(real_mls_loop * WARP_K + 32 - max_seq_kv_offset); // 重新计算 nm_filter
            //     v_srsrc[3]        = nm_filter << 8;
            //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (real_mls_loop * WARP_K * seqlen_v_stride + warp_id * 32 + n_load * WARP_NUM * 32) * ELEMENT_BYTES);
            // }
            // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
            // flash::wait_all_warp_arrived();
            // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

            int index_topk_1 = index_ptr[n_loop_ * 32 + n_loop_real * 64 + (tid / 4)];
            int index_topk_2 = index_ptr[n_loop_ * 32 + n_loop_real * 64 + (tid / 4) + 16];

            int lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            int g_offset_v = n_load * WARP_NUM * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_1 * seqlen_v_stride * ELEMENT_BYTES / 4;
            int lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
            int g_offset_v_add = n_load * WARP_NUM * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_2 * seqlen_v_stride * ELEMENT_BYTES / 4;
            flash::wait_all_warp_arrived();
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
            inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add);
            // g_offset_v += WARP_NUM * 32 * ELEMENT_BYTES / 4;
            // g_offset_v_add += WARP_NUM * 32 * ELEMENT_BYTES / 4;
            // lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
            // lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
            // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
            // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
        }

        lds_stage_id ^= 1;
        int stage_id = 0;

        flash::wait_buffer_data_arrived<true>(V_LOAD_REQUESTS*2); // [TODO]更早的预取

        // DS
        int lds_load_offset = v_lds_base + (0/*k_loop*/ * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
        DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);

        stage_id ^= 1;
        for (int k_loop = 1; k_loop < (kHeadDimV / kBlockN); ++k_loop) {

            // Wait for special headdim
            if ((k_loop & 3) == 0x0) {
                flash::wait_buffer_data_arrived<true>(0);   
                lds_stage_id ^= 1;
            }

            // DS
            int lds_load_offset = v_lds_base + ((k_loop & 3) * 32 * 32 + lds_stage_id * WARP_K * kHeadDimV_OPT) * ELEMENT_BYTES;
            DS_READ_MATRIX_32X32_B16(lds_load_offset, v_reg[stage_id * 2 + 0].f16, v_reg[stage_id * 2 + 1].f16, false/*transpose*/);
            flash::wait_lds_data_arrived<false>(3);

            // MMAC
            flash::raise_priority();
            stage_id ^= 1;
            {
                constexpr int min_tile_k = 0;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::wait_lds_data_arrived<false>(2);
            {
                constexpr int min_tile_k = 1;
                #pragma unroll
                for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                    #pragma unroll
                    for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                        int pv_tile_id = (STAGES == 2) ? k_loop - 1: k_loop;
                        int v_tile_id = stage_id * 2 + min_tile_k;
                        pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                            p_reg[n_loop - 1][min_tile_k].f16x4,
                            v_reg[v_tile_id].f16x4[min_tile_n],
                            pv_reg[pv_tile_id][min_tile_n].f32);
                    }
                }
            }
            flash::lower_priority();

            // MLS for special headdimV
            if (k_loop == 4 || k_loop == 8) {
                lds_stage_id ^= 1;
                // if constexpr (Is_even_MN) {
                //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (n_loop_ * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
                // } else {
                //     int nm_filter_max = n_loop_ * WARP_K + 32 - max_seq_kv_offset;
                //     int real_mls_loop = nm_filter_max >= 32 ? 0: n_loop_; // 如果全越界了, 则只访问 n_loop = 0 的那波数据
                //     int nm_filter     = inline_min_max<0, 32>(real_mls_loop * WARP_K + 32 - max_seq_kv_offset); // 重新计算 nm_filter
                //     v_srsrc[3]        = nm_filter << 8;
                //     *(uint64_t*)&v_srsrc = VA_LIMIT_BITS(*(uint64_t*)&v_ptr + (real_mls_loop * WARP_K * seqlen_v_stride + warp_id * 32 + 0 * 32 * WARP_NUM) * ELEMENT_BYTES);
                // }
                // int lds_offset = (lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES;
                // flash::wait_all_warp_arrived(); // 预防有 warp 还没算完7,还在读 v lds, 若是此时写 v lds,则 data cover
                // inline_matrix_load_32x32_b16_lds<0, 1>(v_lds, v_srsrc, lds_offset, 0);

                int index_topk_1 = index_ptr[32 + n_loop_real * 64 + (tid / 4)];
                int index_topk_2 = index_ptr[32 + n_loop_real * 64 + (tid / 4) + 16];

                int lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
                int g_offset_v = ((k_loop + 4) & 15) * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_1 * seqlen_v_stride * ELEMENT_BYTES / 4;
                int lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + warp_id * 32 * 32) * ELEMENT_BYTES / 4);
                int g_offset_v_add = ((k_loop + 4) & 15) * 16 + warp_id * 16 + tid % 4 * 4 + index_topk_2 * seqlen_v_stride * ELEMENT_BYTES / 4;
                flash::wait_all_warp_arrived();
                inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
                inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
                // g_offset_v += WARP_NUM * 32 * ELEMENT_BYTES / 4;
                // g_offset_v_add += WARP_NUM * 32 * ELEMENT_BYTES / 4;
                // lds_offset = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
                // lds_offset_add = __builtin_amdgcn_readfirstlane((lds_stage_id * WARP_K * kHeadDimV_OPT + 32 * 16 + (WARP_NUM + warp_id) * 32 * 32) * ELEMENT_BYTES / 4);
                // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset, 0, g_offset_v); 
                // inline_buffer_load_dwordx4_lds(v_lds, v_ptr, lds_offset_add, 0, g_offset_v_add); 
                lds_stage_id ^= 1;
            }
        }

        stage_id ^= 1;
        flash::wait_lds_data_arrived<false>(1);
        // last mmac
        flash::raise_priority();
        {
            constexpr int min_tile_k = 0;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::wait_lds_data_arrived<false>(0);
        {
            constexpr int min_tile_k = 1;
            #pragma unroll
            for(int min_tile_n = 0; min_tile_n < 2; ++min_tile_n) {
                #pragma unroll
                for(int min_tile_m = 0; min_tile_m < 1; ++min_tile_m) {
                    int pv_tile_id = (kHeadDimV / kBlockN) - 1;
                    int v_tile_id = stage_id * 2 + min_tile_k;
                    pv_reg[pv_tile_id][min_tile_n].f32 = mmac_4interleave<Element, ElementAccum>(
                        p_reg[n_loop - 1][min_tile_k].f16x4,
                        v_reg[v_tile_id].f16x4[min_tile_n],
                        pv_reg[pv_tile_id][min_tile_n].f32);
                }
            }
        }
        flash::lower_priority();
    }

    
    // 预取Q K
    if constexpr (PREFETCH_K) {
        prefetch_q_to_lds_mls_ds_576_512<kHeadDim, kBlockM, kBlockK, WARP_M, Element, Is_even_MN>(q_ptr, q_lds, warp_id, seqlen_q_stride, max_seq_q_offset);
        prefetch_k_to_lds_mls_ds_576_512<kHeadDim, kBlockK, kBlockN, WARP_NUM, WARP_N, Element, Is_even_MN>(k_ptr, k_lds, warp_id, seqlen_k_stride, max_seq_kv_offset - kBlockK);
    }
}
