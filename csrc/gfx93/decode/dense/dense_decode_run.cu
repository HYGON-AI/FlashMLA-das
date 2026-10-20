#include <torch/extension.h>
#include <cutlass/half.h>

#include "splitkv_mla.h"

namespace gfx93 {

template<typename InputT, int HeadDimK, int HeadDimV>
void run_flash_splitkv_mla_kernel_impl(DenseAttnDecodeParams &params);

template<typename InputT>
void run_flash_splitkv_mla_kernel(DenseAttnDecodeParams &params) {
    if (params.d == 576 && params.d_v == 512) {
        run_flash_splitkv_mla_kernel_impl<InputT, 576, 512>(params);
    } else if (params.d == 512 && params.d_v == 512) {
        run_flash_splitkv_mla_kernel_impl<InputT, 512, 512>(params);
    } else {
        TORCH_CHECK(false, "Unsupported dense decode head dims: d=", params.d, " d_v=", params.d_v);
    }
}

template void run_flash_splitkv_mla_kernel<cutlass::bfloat16_t>(DenseAttnDecodeParams &params);
#ifndef FLASH_MLA_DISABLE_FP16
template void run_flash_splitkv_mla_kernel<cutlass::half_t>(DenseAttnDecodeParams &params);
#endif

}
