#pragma once

#include "hytlass_ext.h"

#include <hytlass/numeric_types.h>
#include <hytlass/arch/barrier.h>
#include <hute/tensor.hpp>
#include <kerutils/kerutils.cuh>
#include <tuple>

#include "defines.h"
#include "params.h"

using namespace hute;

namespace gfx93::decode::sparse_fp8 {

template<ModelType MODEL_TYPE, int NUM_HEADS, bool HAVE_TOPK_LENGTH>
class KernelTemplate {
public:

    static_assert(NUM_HEADS == 64 || NUM_HEADS == 128 || NUM_HEADS == 16);
    // todo only support tp8
    static constexpr int BLOCK_M = 16;
    static constexpr int NUM_M_BLOCKS = NUM_HEADS / BLOCK_M;
    static constexpr bool Is_causal = false;
    static constexpr int HEAD_DIM_K = MODEL_TYPE == ModelType::V32 ? 576 : 512;
    static constexpr int HEAD_DIM_V = 512;
    static constexpr int HEAD_DIM_ROPE = 64;
    static constexpr int HEAD_DIM_NOPE = HEAD_DIM_K - HEAD_DIM_ROPE;

    static constexpr int NUM_SCALES = MODEL_TYPE == ModelType::V32 ? 4 : 8;  // For MODEL1: 7 fp8_e4m3 + 1 padding

    static constexpr int NUM_THREADS = 256;
    static constexpr int TOPK_BLOCK_SIZE = 64;

    typedef unsigned int __hip_fp8x4_storage_t;
    typedef unsigned short int __hip_fp8x2_storage_t;
    typedef unsigned char __hip_fp8_storage_t;
    typedef __fp16 __fp16x8_t __attribute__((ext_vector_type(8)));
    typedef __fp16 __fp16x4_t __attribute__((ext_vector_type(4)));

    union Fp8_storage {
        __fp16x8_t data_128;
        __hip_fp8x4_storage_t fp8_array[4];
    };

    union bf16_storage {
        uint32x4_t data_128;
        uint16_t data_array[8];
    };

    // V32：一个 topk block 的 K/V 载荷（寄存器）
    struct PfKV {
        Fp8_storage kA[4];      // k_idx 4..7 (dims 256..511)
        Fp8_storage kB[4];      // k_idx 0..3 (dims 0..255)
        bf16_storage rope0, rope1;
        float scales[NUM_SCALES];
    };

    // 本次请求的调度信息
    struct MainloopArgs {
        int start_block_idx, end_block_idx;
        bool is_no_split;

        // The following fields are only valid for MODEL1
        int topk_length, extra_topk_length, num_orig_kv_blocks;
    };

    using elem_type = hytlass::bfloat16_t;
    using MMA_Atom_Arch = std::conditional_t<
        std::is_same_v<elem_type, hytlass::half_t>,
        MMA_Atom<flash_mla::hytlass_ext::GFX928_16x16x64_F32F16F16F32_NT>,
        MMA_Atom<flash_mla::hytlass_ext::GFX928_16x16x64_F32BF16BF16F32_NT>
    >;
    static constexpr int kNWarps = 4;
    using ValLayoutMNK = Layout<Shape<_1, _1, _1>>;
    using TiledMma = TiledMMA<
        MMA_Atom_Arch,
        Layout<Shape<_1, Int<kNWarps>, _1>>>;

    using MMA_Atom_Arch_16_16_32 = std::conditional_t<
        std::is_same_v<elem_type, hytlass::half_t>,
        MMA_Atom<flash_mla::hytlass_ext::GFX928_16x16x32_F32F16F16F32_NN>,
        MMA_Atom<flash_mla::hytlass_ext::GFX928_16x16x32_F32BF16BF16F32_NN>
    >;
    using TiledMma_16_16_32 = TiledMMA<
        MMA_Atom_Arch_16_16_32,
        Layout<Shape<_1, Int<kNWarps>, _1>>>;

    using MMA_Atom_Arch_16x32_NT = std::conditional_t<
        std::is_same_v<elem_type, hytlass::half_t>,
        MMA_Atom<flash_mla::hytlass_ext::GFX928_16x32x16_F32F16F16F32_NT>,
        MMA_Atom<flash_mla::hytlass_ext::GFX928_16x32x16_F32BF16BF16F32_NT>
    >;
    using TiledMma_O = TiledMMA<
        MMA_Atom_Arch_16x32_NT,
        Layout<Shape<_1, Int<kNWarps>, _1>>>;

    using SmemLayoutAtomK = decltype(composition(
        Swizzle<3, 3, 3>{},
        Layout<Shape<Int<8>, Int<32>>, Stride<Int<32>, _1>>{}));
    using SmemLayoutK = decltype(tile_to_shape(
        SmemLayoutAtomK{},
        Shape<Int<TOPK_BLOCK_SIZE>, Int<8 * 32>>{}));

    using SmemLayoutAtomV = SmemLayoutAtomK;   
    using SmemLayoutV = decltype(tile_to_shape(
        SmemLayoutAtomV{},
        Shape<Int<TOPK_BLOCK_SIZE>, Int<512>>{}));

    using SmemLayoutVtransposed = decltype(
        composition(SmemLayoutV{}, make_layout(Shape<Int<512>, Int<TOPK_BLOCK_SIZE>>{}, GenRowMajor{})));

    using SmemLayoutAtomP = Layout<Shape<Int<4*16*16>>, Stride<Int<1>>>;
    using SmemLayoutP = decltype(tile_to_shape(
        SmemLayoutAtomP{},
        Shape<Int<4*16*16>>{}));
    using SmemLayoutRow = Layout<Shape<_128>, Stride<_1>>; 

    using Element = hytlass::bfloat16_t;
    using ElementAccum = float;
    struct SharedMemoryPlan {
        union {
            struct {
                hute::array_aligned<Element, hute::cosize_v<SmemLayoutV>> smem_v;
            };
            struct {
                // cute::array_aligned<typename Kernel_traits::Element, cute::cosize_v<typename Kernel_traits::SmemLayoutV_tmp>> smem_v_tmp;  // Double buffer
                hute::array_aligned<Element, hute::cosize_v<SmemLayoutP>> smem_p;
                hute::array_aligned<ElementAccum, hute::cosize_v<SmemLayoutRow>> smem_row_sum;
                hute::array_aligned<ElementAccum, hute::cosize_v<SmemLayoutRow>> smem_row_max;

            };
        };
    };

    static __device__ __forceinline__ std::tuple<Element, Element, Element, Element>
    dequant_fp8_to_bf16(const Fp8_storage& data0, float kv_scale, int idx);

    static __device__ __forceinline__ PfKV
    issue_kv_loads(const SparseAttnDecodeParams& params, int token_index, int col_idx, bool is_extra);

    static __device__ __forceinline__ void
    lds_direct_copy_q(const Element* q_ptr, const SparseAttnDecodeParams& params, Element* s_q,
                    int head_block_idx, int lane_idx, int warp_idx, int k_idx, int offset_k);

    static __device__ __forceinline__ MainloopArgs
    get_cur_req_info(const SparseAttnDecodeParams& params, const DecodingSchedMeta& sched_meta, int batch_idx);

    static __device__ __forceinline__ uint16_t
    float2bf16(float s);

    static __device__ __forceinline__ void
    compute_attn_1rowblock_splitkv_sparse_mla_fp8(const SparseAttnDecodeParams &params, const DecodingSchedMeta& sched_meta, int batch_idx);

    static __device__ __forceinline__ void
    devfunc(const SparseAttnDecodeParams &params);

    static __device__ __forceinline__ void
    devfunc_fixed_split(const SparseAttnDecodeParams &params);

    static void run(const SparseAttnDecodeParams &params);

    static void run_fixed_split(const SparseAttnDecodeParams &params);

};

}  // namespace gfx93::decode::sparse_fp8
