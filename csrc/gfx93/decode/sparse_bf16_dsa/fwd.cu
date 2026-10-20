// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
// SPDX-License-Identifier: MIT

#include "fwd.h"

#include <ATen/cuda/CUDAContext.h>
#include <c10/cuda/CUDAGuard.h>
#include <torch/extension.h>

#include <algorithm>
#include <cstdlib>
#include <cstring>
#include <limits>
#include <optional>
#include <tuple>

#include "kerutils/supplemental/torch_tensors.h"
#include "gfx93/prefill/sparse/dsa_mls/dispatch.h"
#include "gfx93/prefill/sparse/phase1.h"
#include "gfx9/decode/combine/combine_bf16_dsa.h"

namespace gfx93::decode::sparse_bf16_dsa {

static constexpr float LOG_2_E = 1.44269504f;

struct LocalArch {
    int num_sms;
    std::string arch_name;

    LocalArch() {
        auto* props = at::cuda::getCurrentDeviceProperties();
        num_sms = props->multiProcessorCount;
        arch_name = props->gcnArchName;
    }

    bool is_gfx93x() const {
        const auto base = arch_name.substr(0, arch_name.find(':'));
        return base == "gfx936" || base == "gfx938";
    }

    bool is_gfx936() const {
        const auto base = arch_name.substr(0, arch_name.find(':'));
        return base == "gfx936";
    }

    bool is_gfx938() const {
        const auto base = arch_name.substr(0, arch_name.find(':'));
        return base == "gfx938";
    }
};

static int int64_stride_to_int(int64_t stride) {
    TORCH_CHECK(stride <= std::numeric_limits<int>::max(), "DSA BF16 sparse decode stride exceeds int32 limit: ", stride);
    return static_cast<int>(stride);
}

static int default_num_splits(int b, int s_q, int h_q, int topk, int extra_topk, bool decode_use_c_load) {
    const int64_t decode_tasks = static_cast<int64_t>(b) * s_q;
    if (extra_topk > 0) {
        const int total_topk = topk + extra_topk;
        if (topk < 512) {
            if (h_q == 64) {
                if (decode_use_c_load) {
                    if (total_topk > 4096) {
                        if (decode_tasks <= 1) return 32;
                        if (decode_tasks <= 8) return 16;
                        if (decode_tasks <= 64) return 8;
                        return 4;
                    }
                    if (decode_tasks <= 1) return 16;
                    if (decode_tasks <= 8) return 8;
                    if (decode_tasks <= 32) return 4;
                    return 1;
                } else if (total_topk > 4096) {
                    if (decode_tasks <= 8) return 32;
                    if (decode_tasks <= 16) return 8;
                    if (decode_tasks <= 64) return 4;
                    return 1;
                }
                if (decode_tasks <= 1) return 32;
                if (decode_tasks <= 8) return 8;
                if (decode_tasks <= 16) return 4;
                if (decode_tasks <= 64) return 2;
                return 1;
            }
            if (decode_tasks <= 4) return 16;
            if (decode_tasks <= 16) return 8;
            return 1;
        }
        if (h_q == 64) {
            if (total_topk > 1024 && decode_tasks <= 1) return 32;
            if (decode_tasks <= 4) return 16;
            if (decode_tasks <= 8) return 8;
            if (total_topk > 1024 && decode_tasks <= 16) return 8;
            if (decode_tasks <= 32) return 4;
            if (decode_tasks <= 64) return 2;
            return 1;
        }
        if (decode_tasks <= 2) return 16;
        if (decode_tasks <= 4) return 8;
        if (total_topk > 1024 && decode_tasks <= 8) return 8;
        if (decode_tasks <= 16) return 4;
        if (decode_tasks <= 32) return 2;
        return 1;
    }

    if (topk < 512) {
        if (h_q == 64) {
            if (decode_use_c_load && decode_tasks <= 32) return 2;
        }
        return 1;
    }

    if (topk == 512) {
        if (h_q == 64) {
            if (decode_tasks <= 8) return 8;
            if (decode_tasks <= 16) return 4;
            if (decode_tasks <= 32) return 2;
            return 1;
        }
        if (decode_tasks <= 1) return 16;
        if (decode_tasks <= 4) return 8;
        if (decode_tasks <= 8) return 4;
        if (decode_tasks <= 16) return 2;
        return 1;
    }
    if (topk == 1024) {
        if (h_q == 64) {
            if (decode_tasks <= 4) return 16;
            if (decode_tasks <= 8) return 8;
            if (decode_tasks <= 32) return 4;
            if (decode_tasks <= 64) return 2;
            return 1;
        }
        if (decode_tasks <= 2) return 16;
        if (decode_tasks <= 4) return 8;
        if (decode_tasks <= 16) return 4;
        if (decode_tasks <= 32) return 2;
        return 1;
    }
    if (topk > 1024) {
        if (h_q == 64) {
            if (decode_tasks <= 1) return 32;
            if (decode_tasks <= 4) return 16;
            if (decode_tasks <= 16) return 8;
            if (decode_tasks <= 32) return 4;
            if (decode_tasks <= 64) return 2;
            return 1;
        }
        if (decode_tasks <= 2) return 16;
        if (decode_tasks <= 8) return 8;
        if (decode_tasks <= 16) return 4;
        if (decode_tasks <= 32) return 2;
        return 1;
    }
    return 1;
}

static int default_num_splits_gfx936_decode(int b, int s_q, int h_q, int topk, int extra_topk) {
    if (h_q != 64) {
        return default_num_splits(b, s_q, h_q, topk, extra_topk, false);
    }

    const int64_t decode_tasks = static_cast<int64_t>(b) * s_q;
    const int total_topk = topk + extra_topk;

    if (total_topk <= 256) {
        if (decode_tasks <= 4) return 4;
        if (decode_tasks <= 32) return 2;
        return 1;
    }
    if (total_topk <= 512) {
        if (decode_tasks <= 8) return 8;
        if (decode_tasks <= 16) return 4;
        if (decode_tasks <= 32) return 2;
        return 1;
    }
    if (total_topk <= 1024) {
        if (decode_tasks <= 2) return 16;
        if (decode_tasks <= 8) return 8;
        if (decode_tasks <= 16) return 4;
        if (decode_tasks <= 32) return 2;
        return 1;
    }

    if (decode_tasks <= 1) return 32;
    if (decode_tasks <= 4) return 16;
    if (decode_tasks <= 8) return 8;
    if (decode_tasks <= 16) return 4;
    if (decode_tasks <= 32) return 2;
    return 1;
}

static std::optional<int> force_num_splits_for_tuning() {
    const char* env = std::getenv("FLASH_MLA_BF16_DSA_FORCE_SPLITS");
    if (env == nullptr || env[0] == '\0') {
        return std::nullopt;
    }
    const int value = std::atoi(env);
    TORCH_CHECK(value > 0, "FLASH_MLA_BF16_DSA_FORCE_SPLITS must be positive when set");
    return value;
}

static void check_optional_extra(
    const std::optional<at::Tensor>& extra_kv,
    const std::optional<at::Tensor>& extra_indices,
    const std::optional<at::Tensor>& extra_topk_length) {
    if (extra_kv.has_value()) {
        TORCH_CHECK(extra_indices.has_value(), "extra_indices_in_kvcache must be provided when extra_k_cache is provided");
    } else {
        TORCH_CHECK(!extra_indices.has_value(), "extra_indices_in_kvcache must not be provided when extra_k_cache is not provided");
        TORCH_CHECK(!extra_topk_length.has_value(), "extra_topk_length must not be provided when extra_k_cache is not provided");
    }
}

static std::tuple<at::Tensor, at::Tensor, std::optional<at::Tensor>, std::optional<at::Tensor>>
run_gfx936_prefill_kernel_decode(
    const at::Tensor& q,
    const at::Tensor& kv,
    const at::Tensor& indices,
    const std::optional<at::Tensor>& topk_length,
    const std::optional<at::Tensor>& attn_sink,
    std::optional<at::Tensor>& tile_scheduler_metadata,
    std::optional<at::Tensor>& num_splits,
    const std::optional<at::Tensor>& extra_kv,
    const std::optional<at::Tensor>& extra_indices,
    const std::optional<at::Tensor>& extra_topk_length,
    int d_v,
    float sm_scale,
    const LocalArch& arch) {
    KU_CHECK_NDIM(q, 4);
    KU_CHECK_NDIM(kv, 4);
    KU_CHECK_NDIM(indices, 3);

    const int b = q.size(0);
    const int s_q = q.size(1);
    const int h_q = q.size(2);
    const int d_qk = q.size(3);
    const int page_block_size = kv.size(1);
    const int h_kv = kv.size(2);
    const int topk = indices.size(2);

    TORCH_CHECK(!extra_kv.has_value() && !extra_indices.has_value() && !extra_topk_length.has_value(),
                "gfx936 BF16 DSA decode via prefill kernel does not support extra_kv yet");
    TORCH_CHECK(b > 0 && s_q > 0 && h_q > 0, "Invalid q shape for gfx936 BF16 DSA decode");
    TORCH_CHECK(h_kv == 1, "gfx936 BF16 DSA decode only supports h_kv == 1");
    TORCH_CHECK(h_q == 32 || h_q == 64 || h_q == 128,
                "gfx936 BF16 DSA decode only supports h_q == 32, 64 or 128");
    TORCH_CHECK(d_qk == 512, "gfx936 BF16 DSA decode only supports d_qk == 512");
    TORCH_CHECK(d_v == 512, "gfx936 BF16 DSA decode only supports d_v == 512");
    TORCH_CHECK(topk > 0, "topk must be positive");

    KU_CHECK_DEVICE(q);
    KU_CHECK_DEVICE(kv);
    KU_CHECK_DEVICE(indices);
    KU_CHECK_DEVICE(topk_length);
    KU_CHECK_DEVICE(attn_sink);
    KU_CHECK_DEVICE(tile_scheduler_metadata);
    KU_CHECK_DEVICE(num_splits);

    KU_CHECK_DTYPE(q, torch::kBFloat16);
    KU_CHECK_DTYPE(kv, torch::kBFloat16);
    KU_CHECK_DTYPE(indices, torch::kInt32);
    KU_CHECK_DTYPE(topk_length, torch::kInt32);
    KU_CHECK_DTYPE(attn_sink, torch::kFloat32);
    KU_CHECK_DTYPE(tile_scheduler_metadata, torch::kInt32);
    KU_CHECK_DTYPE(num_splits, torch::kInt32);

    KU_CHECK_LAST_DIM_CONTIGUOUS(q);
    KU_CHECK_LAST_DIM_CONTIGUOUS(kv);
    KU_CHECK_LAST_DIM_CONTIGUOUS(indices);
    KU_CHECK_CONTIGUOUS(topk_length);
    KU_CHECK_CONTIGUOUS(attn_sink);

    KU_CHECK_SHAPE(q, b, s_q, h_q, d_qk);
    KU_CHECK_SHAPE(kv, kv.size(0), page_block_size, h_kv, d_qk);
    KU_CHECK_SHAPE(indices, b, s_q, topk);
    KU_CHECK_SHAPE(topk_length, b);
    KU_CHECK_SHAPE(attn_sink, h_q);

    const bool flatten_h32_decode = h_q == 32;
    if (flatten_h32_decode) {
        TORCH_CHECK(!extra_kv.has_value() && !extra_indices.has_value() && !extra_topk_length.has_value(),
                    "gfx936 BF16 DSA decode h_q == 32 does not support extra_kv yet");
    }

    c10::cuda::CUDAGuard device_guard{q.device()};
    at::Tensor q_kernel = q;
    at::Tensor indices_kernel = indices;
    if (flatten_h32_decode) {
        if (q.stride(0) != s_q * q.stride(1)) {
            q_kernel = q.contiguous();
        }
        if (indices.stride(0) != s_q * indices.stride(1)) {
            indices_kernel = indices.contiguous();
        }
    }
    auto opts = q.options();
    at::Tensor out = torch::empty({b, s_q, h_q, d_v}, opts);
    at::Tensor lse_tmp = torch::empty({b, s_q, h_q}, opts.dtype(at::kFloat));
    at::Tensor max_logits = torch::empty({b, s_q, h_q}, opts.dtype(at::kFloat));
    at::Tensor lse;

    int requested_num_splits = default_num_splits_gfx936_decode(b, s_q, h_q, topk, 0);
    if (auto forced_num_splits = force_num_splits_for_tuning(); forced_num_splits.has_value()) {
        requested_num_splits = forced_num_splits.value();
    }
    if (flatten_h32_decode) {
        requested_num_splits = 1;
    }
    TORCH_CHECK(requested_num_splits >= 1 && requested_num_splits <= arch.num_sms,
                "gfx936 BF16 DSA decode requires 1 <= num_splits <= num_sms");
    constexpr int64_t kGfx936BufferLoadAddressBytes = 1LL << 32;
    const int64_t padded_k_tokens = static_cast<int64_t>(kv.size(0)) * page_block_size;
    const int64_t padded_k_bytes = padded_k_tokens * d_qk * static_cast<int64_t>(sizeof(cutlass::bfloat16_t));
    const bool decode_use_c_load = padded_k_bytes > kGfx936BufferLoadAddressBytes;
    TORCH_CHECK(!(flatten_h32_decode && decode_use_c_load),
                "gfx936 BF16 DSA decode h_q == 32 does not support c-load path yet");

    at::Tensor topk_length_flat;
    int* topk_length_ptr = nullptr;
    if (topk_length.has_value()) {
        if (s_q == 1) {
            topk_length_ptr = topk_length->data_ptr<int>();
        } else {
            topk_length_flat = topk_length->view({b, 1}).expand({b, s_q}).reshape({b * s_q}).contiguous();
            topk_length_ptr = topk_length_flat.data_ptr<int>();
        }
    }

    const int fwd_s_q = flatten_h32_decode ? b * s_q : s_q;
    const int fwd_split_b = flatten_h32_decode ? 0 : b;

    SparseAttnFwdParams fwd_params = {
        fwd_s_q, static_cast<int>(kv.size(0) * page_block_size), h_q, h_kv, d_qk, d_v, topk,
        sm_scale, sm_scale * LOG_2_E,

        reinterpret_cast<cutlass::bfloat16_t*>(q_kernel.data_ptr()),
        reinterpret_cast<cutlass::bfloat16_t*>(kv.data_ptr()),
        reinterpret_cast<int*>(indices_kernel.data_ptr()),
        ku::get_optional_tensor_ptr<float>(attn_sink),
        topk_length_ptr,

        int64_stride_to_int(q_kernel.stride(1)), int64_stride_to_int(q_kernel.stride(2)),
        int64_stride_to_int(kv.stride(1)), int64_stride_to_int(kv.stride(2)),
        int64_stride_to_int(indices_kernel.stride(1)), topk,

        reinterpret_cast<cutlass::bfloat16_t*>(out.data_ptr()),
        max_logits.data_ptr<float>(),
        lse_tmp.data_ptr<float>(),

        arch.num_sms,
        at::cuda::getCurrentCUDAStream().stream(),

        fwd_split_b,
        requested_num_splits,
        topk,
        int64_stride_to_int(q_kernel.stride(0)),
        int64_stride_to_int(indices_kernel.stride(0)),
        nullptr,
        nullptr,
        0, 0,
        0, 0, 0,
        decode_use_c_load
    };

    if (requested_num_splits == 1) {
        if (topk_length.has_value()) {
            if (decode_use_c_load) {
                gfx93::fwd::run_fwd_phase1_c_load_kernel<512, true>(fwd_params);
            } else {
                gfx93::fwd::run_fwd_phase1_kernel<512, true>(fwd_params);
            }
        } else {
            if (decode_use_c_load) {
                gfx93::fwd::run_fwd_phase1_c_load_kernel<512, false>(fwd_params);
            } else {
                gfx93::fwd::run_fwd_phase1_kernel<512, false>(fwd_params);
            }
        }
        lse = lse_tmp.permute({0, 2, 1}).contiguous();
    } else {
        fwd_params.split_partition_size = std::max(64, (topk + requested_num_splits - 1) / requested_num_splits);
        fwd_params.split_partition_size = ((fwd_params.split_partition_size + 63) / 64) * 64;
        at::Tensor lse_accum = torch::empty({b * requested_num_splits, s_q, h_q}, opts.dtype(at::kFloat));
        at::Tensor out_accum = torch::empty({b * requested_num_splits, s_q, h_q, d_v}, opts.dtype(at::kFloat));
        fwd_params.split_lse_accum = lse_accum.data_ptr<float>();
        fwd_params.split_o_accum = out_accum.data_ptr<float>();
        fwd_params.split_stride_lse_accum_split = int64_stride_to_int(lse_accum.stride(0));
        fwd_params.split_stride_lse_accum_s_q = int64_stride_to_int(lse_accum.stride(1));
        fwd_params.split_stride_o_accum_split = int64_stride_to_int(out_accum.stride(0));
        fwd_params.split_stride_o_accum_s_q = int64_stride_to_int(out_accum.stride(1));
        fwd_params.split_stride_o_accum_h_q = int64_stride_to_int(out_accum.stride(2));

        if (topk_length.has_value()) {
            gfx93::fwd::run_fwd_phase1_splitkv_kernel<512, true>(fwd_params);
        } else {
            gfx93::fwd::run_fwd_phase1_splitkv_kernel<512, false>(fwd_params);
        }

        CombineParams combine_params = {
            b, s_q, h_q, d_v,

            lse_tmp.data_ptr<float>(),
            out.data_ptr(),
            int64_stride_to_int(lse_tmp.stride(0)), int64_stride_to_int(lse_tmp.stride(1)),
            int64_stride_to_int(out.stride(0)), int64_stride_to_int(out.stride(1)), int64_stride_to_int(out.stride(2)),

            lse_accum.data_ptr<float>(),
            out_accum.data_ptr<float>(),
            int64_stride_to_int(lse_accum.stride(0)), int64_stride_to_int(lse_accum.stride(1)),
            int64_stride_to_int(out_accum.stride(0)), int64_stride_to_int(out_accum.stride(1)), int64_stride_to_int(out_accum.stride(2)),

            nullptr,
            nullptr,
            requested_num_splits,

            ku::get_optional_tensor_ptr<float>(attn_sink),
            at::cuda::getCurrentCUDAStream().stream(),

            true,
            requested_num_splits,
            nullptr,
            0
        };
        gfx9::decode::bf16_dsa::run_flash_mla_combine_kernel<cutlass::bfloat16_t>(combine_params);
        lse = lse_tmp.permute({0, 2, 1}).contiguous();
    }

    return {out, lse, tile_scheduler_metadata, num_splits};
}

std::tuple<at::Tensor, at::Tensor, std::optional<at::Tensor>, std::optional<at::Tensor>>
run(
    const at::Tensor& q,
    const at::Tensor& kv,
    const at::Tensor& indices,
    const std::optional<at::Tensor>& topk_length,
    const std::optional<at::Tensor>& attn_sink,
    std::optional<at::Tensor>& tile_scheduler_metadata,
    std::optional<at::Tensor>& num_splits,
    const std::optional<at::Tensor>& extra_kv,
    const std::optional<at::Tensor>& extra_indices,
    const std::optional<at::Tensor>& extra_topk_length,
    int d_v,
    float sm_scale) {
    LocalArch arch;
    if (arch.is_gfx936()) {
        return run_gfx936_prefill_kernel_decode(
            q, kv, indices, topk_length, attn_sink,
            tile_scheduler_metadata, num_splits,
            extra_kv, extra_indices, extra_topk_length,
            d_v, sm_scale, arch);
    }
    TORCH_CHECK(arch.is_gfx938(), "DSA BF16 sparse decode is only supported on gfx938");

    KU_CHECK_NDIM(q, 4);
    KU_CHECK_NDIM(kv, 4);
    KU_CHECK_NDIM(indices, 3);
    if (extra_kv.has_value()) KU_CHECK_NDIM(extra_kv, 4);
    if (extra_indices.has_value()) KU_CHECK_NDIM(extra_indices, 3);

    const int b = q.size(0);
    const int s_q = q.size(1);
    const int h_q = q.size(2);
    const int d_qk = q.size(3);
    const int page_block_size = kv.size(1);
    const int h_kv = kv.size(2);
    const int topk = indices.size(2);
    const bool has_extra = extra_kv.has_value() && extra_indices.has_value() &&
                           extra_kv->numel() > 0 && extra_indices->numel() > 0 &&
                           extra_indices->size(2) > 0;
    const int extra_topk = has_extra ? extra_indices->size(2) : 0;

    TORCH_CHECK(b > 0 && s_q > 0 && h_q > 0, "Invalid q shape for DSA BF16 sparse decode");
    TORCH_CHECK(h_kv == 1, "DSA BF16 sparse decode only supports h_kv == 1");
    TORCH_CHECK(h_q == 64 || h_q == 128, "DSA BF16 sparse decode only supports h_q == 64 or 128");
    TORCH_CHECK(d_qk == 512, "DSA BF16 sparse decode only supports d_qk == 512 for now");
    TORCH_CHECK(d_v == 512, "DSA BF16 sparse decode only supports d_v == 512");
    TORCH_CHECK(topk > 0, "topk must be positive");
    if (has_extra) {
        TORCH_CHECK(extra_kv->size(1) > 0, "extra page_block_size must be positive");
        TORCH_CHECK(extra_kv->size(2) == h_kv, "extra_kv h_kv must match kv h_kv");
        TORCH_CHECK(extra_kv->size(3) == d_qk, "extra_kv d_qk must match q d_qk");
    }
    check_optional_extra(extra_kv, extra_indices, extra_topk_length);

    KU_CHECK_DEVICE(q);
    KU_CHECK_DEVICE(kv);
    KU_CHECK_DEVICE(indices);
    KU_CHECK_DEVICE(topk_length);
    KU_CHECK_DEVICE(attn_sink);
    KU_CHECK_DEVICE(tile_scheduler_metadata);
    KU_CHECK_DEVICE(num_splits);
    KU_CHECK_DEVICE(extra_kv);
    KU_CHECK_DEVICE(extra_indices);
    KU_CHECK_DEVICE(extra_topk_length);

    KU_CHECK_DTYPE(q, torch::kBFloat16);
    KU_CHECK_DTYPE(kv, torch::kBFloat16);
    KU_CHECK_DTYPE(indices, torch::kInt32);
    KU_CHECK_DTYPE(topk_length, torch::kInt32);
    KU_CHECK_DTYPE(attn_sink, torch::kFloat32);
    KU_CHECK_DTYPE(tile_scheduler_metadata, torch::kInt32);
    KU_CHECK_DTYPE(num_splits, torch::kInt32);
    KU_CHECK_DTYPE(extra_kv, torch::kBFloat16);
    KU_CHECK_DTYPE(extra_indices, torch::kInt32);
    KU_CHECK_DTYPE(extra_topk_length, torch::kInt32);

    KU_CHECK_LAST_DIM_CONTIGUOUS(q);
    KU_CHECK_LAST_DIM_CONTIGUOUS(kv);
    KU_CHECK_LAST_DIM_CONTIGUOUS(indices);
    KU_CHECK_CONTIGUOUS(topk_length);
    KU_CHECK_CONTIGUOUS(attn_sink);
    KU_CHECK_LAST_DIM_CONTIGUOUS(extra_kv);
    KU_CHECK_LAST_DIM_CONTIGUOUS(extra_indices);
    KU_CHECK_CONTIGUOUS(extra_topk_length);

    KU_CHECK_SHAPE(q, b, s_q, h_q, d_qk);
    KU_CHECK_SHAPE(kv, kv.size(0), page_block_size, h_kv, d_qk);
    KU_CHECK_SHAPE(indices, b, s_q, topk);
    KU_CHECK_SHAPE(topk_length, b);
    KU_CHECK_SHAPE(attn_sink, h_q);
    if (has_extra) {
        KU_CHECK_SHAPE(extra_indices, b, s_q, extra_topk);
        KU_CHECK_SHAPE(extra_topk_length, b);
    }

    at::Tensor indices_for_dsa = indices.unsqueeze(2);
    at::Tensor extra_indices_for_dsa;
    if (has_extra) {
        extra_indices_for_dsa = extra_indices->unsqueeze(2);
    }

    c10::cuda::CUDAGuard device_guard{q.device()};
    auto opts = q.options();
    at::Tensor out = torch::empty({b, s_q, h_q, d_v}, opts);
    at::Tensor lse = torch::empty({b, h_q, s_q}, opts.dtype(at::kFloat));
    at::Tensor scores_memory = torch::empty({2, b, h_kv, s_q * h_q}, opts.dtype(at::kFloat));
    at::Tensor scores_max = scores_memory.select(0, 0);
    at::Tensor scores_sum = scores_memory.select(0, 1);
    constexpr int64_t kBufferLoadPaddedTokenLimit = 32LL * 64 * 1024;
    const int64_t padded_k_tokens = static_cast<int64_t>(kv.size(0)) * page_block_size;
    const int64_t padded_extra_k_tokens = has_extra ? static_cast<int64_t>(extra_kv->size(0)) * extra_kv->size(1) : 0;
    const bool decode_use_c_load = padded_k_tokens > kBufferLoadPaddedTokenLimit ||
                                   padded_extra_k_tokens > kBufferLoadPaddedTokenLimit;
    int requested_num_splits = default_num_splits(b, s_q, h_q, topk, extra_topk, decode_use_c_load);
    if (auto forced_num_splits = force_num_splits_for_tuning(); forced_num_splits.has_value()) {
        requested_num_splits = forced_num_splits.value();
    }
    TORCH_CHECK(requested_num_splits >= 1 && requested_num_splits <= arch.num_sms,
                "DSA BF16 sparse decode requires 1 <= num_splits <= num_sms");

    Flash_fwd_mla_params_dsa params;
    std::memset(&params, 0, sizeof(params));
    params.layout = 1;
    params.b = b;
    params.h = h_kv;
    params.h_k = h_kv;
    params.h_h_k_ratio = 1;
    params.mtp = 1;
    params.ngroups = h_q / h_kv;
    params.topk = topk;
    params.extra_topk = has_extra ? extra_topk : 0;
    params.d = d_qk;
    params.d_v = d_v;
    params.scale_softmax = sm_scale;
    params.scale_softmax_log2 = sm_scale * LOG_2_E;
    params.topk_length = ku::get_optional_tensor_ptr<int>(topk_length);
    params.extra_topk_length = ku::get_optional_tensor_ptr<int>(extra_topk_length);
    params.attn_sink = ku::get_optional_tensor_ptr<float>(attn_sink);
    params.q_ptr = q.data_ptr();
    params.k_ptr = kv.data_ptr();
    params.v_ptr = kv.data_ptr();
    params.extra_k_ptr = has_extra ? extra_kv->data_ptr() : nullptr;
    params.extra_v_ptr = has_extra ? extra_kv->data_ptr() : nullptr;
    params.o_ptr = out.data_ptr();
    params.sparse_indices = reinterpret_cast<int*>(indices_for_dsa.data_ptr());
    params.extra_sparse_indices = has_extra ? reinterpret_cast<int*>(extra_indices_for_dsa.data_ptr()) : nullptr;
    params.softmax_lse_ptr = lse.data_ptr<float>();
    params.scores_max_ptr = scores_max.data_ptr<float>();
    params.scores_sum_ptr = scores_sum.data_ptr<float>();
    params.page_block_size = page_block_size;
    params.extra_page_block_size = has_extra ? extra_kv->size(1) : 0;
    params.is_causal = false;

    params.q_batch_stride = int64_stride_to_int(q.stride(0));
    params.q_token_stride = int64_stride_to_int(q.stride(1));
    params.q_row_stride = int64_stride_to_int(q.stride(2));
    params.q_head_stride = int64_stride_to_int(q.stride(2));
    params.k_batch_stride = int64_stride_to_int(kv.stride(0));
    params.k_row_stride = int64_stride_to_int(kv.stride(1));
    params.k_head_stride = int64_stride_to_int(kv.stride(2));
    params.v_batch_stride = params.k_batch_stride;
    params.v_row_stride = params.k_row_stride;
    params.v_head_stride = params.k_head_stride;
    params.extra_k_batch_stride = has_extra ? int64_stride_to_int(extra_kv->stride(0)) : 0;
    params.extra_k_row_stride = has_extra ? int64_stride_to_int(extra_kv->stride(1)) : 0;
    params.extra_v_batch_stride = params.extra_k_batch_stride;
    params.extra_v_row_stride = params.extra_k_row_stride;
    params.sparse_indices_batch_stride = int64_stride_to_int(indices_for_dsa.stride(0));
    params.sparse_indices_row_stride = int64_stride_to_int(indices_for_dsa.stride(1));
    params.sparse_indices_head_stride = int64_stride_to_int(indices_for_dsa.stride(2));
    params.sparse_indices_topk_stride = int64_stride_to_int(indices_for_dsa.stride(3));
    params.extra_sparse_indices_batch_stride = has_extra ? int64_stride_to_int(extra_indices_for_dsa.stride(0)) : 0;
    params.extra_sparse_indices_row_stride = has_extra ? int64_stride_to_int(extra_indices_for_dsa.stride(1)) : 0;
    params.extra_sparse_indices_head_stride = has_extra ? int64_stride_to_int(extra_indices_for_dsa.stride(2)) : 0;
    params.extra_sparse_indices_topk_stride = has_extra ? int64_stride_to_int(extra_indices_for_dsa.stride(3)) : 0;
    params.o_batch_stride = int64_stride_to_int(out.stride(0));
    params.o_row_stride = int64_stride_to_int(out.stride(1));
    params.o_head_stride = int64_stride_to_int(out.stride(2));
    params.seqlen_q = s_q * params.ngroups;
    params.seqlen_k = kv.size(0) * kv.size(1);
    params.extra_seqlen_k = has_extra ? extra_kv->size(0) * extra_kv->size(1) : 0;
    params.max_seqlen = s_q;
    params.is_bf16 = true;
    params.is_e4m3 = false;
    params.is_int8 = false;
    params.cu_count = arch.num_sms;
    params.seqlenq_ngroups_swapped = true;
    params.is_seqlens_k_cumulative = false;
    params.splitkv_use_meta_dispatch = false;
    params.decode_use_c_load = decode_use_c_load;
    params.num_splits = requested_num_splits;
    params.splitkv_use_fp32_as_accum = params.num_splits > 1;
    params.tile_scheduler_metadata_ptr = nullptr;
    params.num_splits_ptr = nullptr;
    params.num_sm_parts = params.num_splits;
    params.partition_size = topk + params.extra_topk;
    if (params.num_splits > 1) {
        params.partition_size = std::max(64, (params.partition_size + params.num_splits - 1) / params.num_splits);
        params.partition_size = ((params.partition_size + 63) / 64) * 64;
    }

    at::Tensor out_accum;
    at::Tensor lse_accum;
    if (params.num_splits > 1) {
        const int total_num_splits = b * params.num_splits;
        lse_accum = torch::empty({total_num_splits, s_q, h_q}, opts.dtype(at::kFloat));
        out_accum = torch::empty({total_num_splits, s_q, h_q, d_v}, opts.dtype(at::kFloat));
        params.softmax_lse_ptr = lse_accum.data_ptr<float>();
        params.oaccum_ptr = out_accum.data_ptr();
    }

    hipStream_t stream = reinterpret_cast<hipStream_t>(at::cuda::getCurrentCUDAStream().stream());
    gfx93::fwd::dsa_mls::run_dsa_mls_h64_dispatch<BFloat16, 512, 512>(params, stream);

    if (params.num_splits > 1) {
        CombineParams combine_params = {
            b, s_q, h_q, d_v,

            lse.data_ptr<float>(),
            out.data_ptr(),
            int64_stride_to_int(lse.stride(0)), int64_stride_to_int(lse.stride(2)),
            int64_stride_to_int(out.stride(0)), int64_stride_to_int(out.stride(1)), int64_stride_to_int(out.stride(2)),

            lse_accum.data_ptr<float>(),
            out_accum.data_ptr<float>(),
            int64_stride_to_int(lse_accum.stride(0)), int64_stride_to_int(lse_accum.stride(1)),
            int64_stride_to_int(out_accum.stride(0)), int64_stride_to_int(out_accum.stride(1)), int64_stride_to_int(out_accum.stride(2)),

            nullptr,
            nullptr,
            params.num_splits,

            ku::get_optional_tensor_ptr<float>(attn_sink),
            at::cuda::getCurrentCUDAStream().stream(),

            true,
            params.num_splits,
            nullptr,
            0
        };
        gfx9::decode::bf16_dsa::run_flash_mla_combine_kernel<cutlass::bfloat16_t>(combine_params);
    }

    return {out, lse, tile_scheduler_metadata, num_splits};
}

}  // namespace gfx93::decode::sparse_bf16_dsa
