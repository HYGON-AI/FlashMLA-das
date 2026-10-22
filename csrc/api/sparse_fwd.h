#pragma once

#include <cstdlib>

#include "common.h"

#include "params.h"

#include "gfx9/decode/combine/combine_bf16_dsa.h"
#include "gfx93/prefill/sparse/dsa_mls/fwd.h"
#include "gfx93/prefill/sparse/phase1.h"


enum class FwdFeatures : int {
    HEAD_16,
    HEAD_32,
    HEAD_64,
    HEAD_128,

    HEAD_DIM_576,
    HEAD_DIM_512,

    ATTN_SINK,
    SINK_LSE,
    TOPK_LENGTH
};

class FwdImplBase : public ImplBase<
    SparseAttnFwdParams,
    FwdFeatures
> {};

class Fwd_Sm90_Impl : public FwdImplBase {
public:
    explicit Fwd_Sm90_Impl(bool enable_dsa_mls_prefill)
        : enable_dsa_mls_prefill_(enable_dsa_mls_prefill) {}

    DECLARE_SUPPORTED_FEATURES(
        FwdFeatures::HEAD_16,
        FwdFeatures::HEAD_32,
        FwdFeatures::HEAD_64,
        FwdFeatures::HEAD_128,
        FwdFeatures::HEAD_DIM_512,
        FwdFeatures::HEAD_DIM_576,
        FwdFeatures::ATTN_SINK,
        FwdFeatures::SINK_LSE,
        FwdFeatures::TOPK_LENGTH
    )

protected:
    void run_(const SparseAttnFwdParams &params, const std::vector<FeatureT> &required_features) override {
        const bool disable_dsa_mls_prefill = std::getenv("FLASH_MLA_DISABLE_DSA_MLS_PREFILL") != nullptr;
        if (enable_dsa_mls_prefill_ &&
            !disable_dsa_mls_prefill &&
            ((std::getenv("FLASH_MLA_FORCE_DSA_MLS_PREFILL") != nullptr && gfx93::fwd::dsa_mls::can_run(params)) ||
             gfx93::fwd::dsa_mls::should_run(params))) {
            gfx93::fwd::dsa_mls::run(params);
            return;
        }

        DISPATCH_HEAD_DIM(params.d_qk, HEAD_DIM_QK, [&]() {
            DISPATCH_BOOLEAN_FLAG(params.topk_length != nullptr, HAVE_TOPK_LENGTH, [&]() {
                gfx93::fwd::run_fwd_phase1_kernel<HEAD_DIM_QK, HAVE_TOPK_LENGTH>(params);
            });
        });
    }

private:
    bool enable_dsa_mls_prefill_;
};

static std::vector<at::Tensor> sparse_attn_prefill_interface(
    const at::Tensor &q,
    const at::Tensor &kv,
    const at::Tensor &indices,
    float sm_scale,
    int d_v,
    const std::optional<at::Tensor> &attn_sink,
    const std::optional<at::Tensor> &topk_length
) {
    using bf16 = hytlass::bfloat16_t;
    
    Arch arch = Arch();
    if (!arch.is_gfx93x()) {
        TORCH_CHECK(false, "Dense decode MLA is only supported on gfx936 or gfx938 architecture");
    }
    KU_CHECK_NDIM(q, 3);
    KU_CHECK_NDIM(kv, 3);
    KU_CHECK_NDIM(indices, 3);
    KU_CHECK_NDIM(attn_sink, 1);
    KU_CHECK_NDIM(topk_length, 1);

    int s_q = q.size(0);
    int s_kv = kv.size(0);
    int h_q = q.size(1);
    int h_kv = kv.size(1);
    int d_qk = q.size(2);
    int topk = indices.size(2);
    bool have_topk_length = topk_length.has_value();

    TORCH_CHECK(d_qk == 576 || d_qk == 512, "Invalid d_qk: ", d_qk);
    TORCH_CHECK(d_v == 512, "Invalid d_v", d_v);
    
    KU_CHECK_DEVICE(q);
    KU_CHECK_DEVICE(kv);
    KU_CHECK_DEVICE(indices);
    KU_CHECK_DEVICE(attn_sink);
    KU_CHECK_DEVICE(topk_length);
    
    KU_CHECK_DTYPE(q, torch::kBFloat16);
    KU_CHECK_DTYPE(kv, torch::kBFloat16);
    KU_CHECK_DTYPE(indices, torch::kInt32);
    KU_CHECK_DTYPE(attn_sink, torch::kFloat32);
    KU_CHECK_DTYPE(topk_length, torch::kInt32);
    
    KU_CHECK_SHAPE(q, s_q, h_q, d_qk);
    KU_CHECK_SHAPE(kv, s_kv, h_kv, d_qk);
    KU_CHECK_SHAPE(indices, s_q, h_kv, topk);
    KU_CHECK_SHAPE(attn_sink, h_q);
    KU_CHECK_SHAPE(topk_length, s_q);
    
    KU_CHECK_LAST_DIM_CONTIGUOUS(q);
    KU_CHECK_LAST_DIM_CONTIGUOUS(kv);
    KU_CHECK_LAST_DIM_CONTIGUOUS(indices);
    KU_CHECK_LAST_DIM_CONTIGUOUS(attn_sink);
    KU_CHECK_LAST_DIM_CONTIGUOUS(topk_length);
    
    // Allocate results and buffers
    at::cuda::CUDAGuard device_guard{(char)q.get_device()};
    auto opts = q.options();
    
    at::Tensor out = torch::empty({s_q, h_q, d_v}, opts);
    at::Tensor lse = torch::empty({s_q, h_q}, opts.dtype(torch::kFloat));
    at::Tensor max_logits = torch::empty({s_q, h_q}, opts.dtype(torch::kFloat));
    KU_CHECK_CONTIGUOUS(out);
    KU_CHECK_CONTIGUOUS(lse);
    KU_CHECK_CONTIGUOUS(max_logits);
    bool print_param = false;
    if (const char* val = std::getenv("FLASH_MLA_PRINT_PARAM")) {
        print_param = (std::string(val) == "1");
    }
    if (print_param) {
        fprintf(stderr, "[FlashMLA] [sparse_attn_prefill_interface] [%s] "
            "s_q = %d s_kv = %d h_q = %d h_kv = %d d_qk = %d "
            "topk = %d have_topk_length = %d \n",
            arch.archName.c_str(), 
            s_q, s_kv, h_q, h_kv, d_qk,
            topk, have_topk_length
        );
    }
    SparseAttnFwdParams params = {
        s_q, s_kv, h_q, h_kv, d_qk, d_v, topk,
        sm_scale, sm_scale * LOG_2_E,

        (bf16*)q.data_ptr(),
        (bf16*)kv.data_ptr(),
        (int*)indices.data_ptr(),
        ku::get_optional_tensor_ptr<float>(attn_sink),
        ku::get_optional_tensor_ptr<int>(topk_length),

        int64_stride_to_int(q.stride(0)), int64_stride_to_int(q.stride(1)),
        int64_stride_to_int(kv.stride(0)), int64_stride_to_int(kv.stride(1)),
        int64_stride_to_int(indices.stride(0)), int64_stride_to_int(indices.stride(1)),

        (bf16*)out.data_ptr(),
        (float*)max_logits.data_ptr(),
        (float*)lse.data_ptr(),

        arch.num_sms,
        at::cuda::getCurrentCUDAStream().stream(),

        0, 0, 0, 0, 0,
        nullptr,
        nullptr,
        0, 0,
        0, 0, 0,
        false
    };

    const bool disable_small_d576_splitkv = std::getenv("FLASH_MLA_DISABLE_PREFILL_SPLITKV_SMALL") != nullptr;
    const bool use_small_d576_splitkv = (
        !disable_small_d576_splitkv &&
        arch.is_gfx936() &&
        s_q <= 48 &&
        h_kv == 1 &&
        (h_q == 64 || h_q == 128) &&
        d_qk == 576 &&
        d_v == 512 &&
        topk == 2048 &&
        !attn_sink.has_value() &&
        !topk_length.has_value()
    );
    if (use_small_d576_splitkv) {
        constexpr int requested_num_splits = 2;
        int split_partition_size = (topk + requested_num_splits - 1) / requested_num_splits;
        split_partition_size = std::max(64, split_partition_size);
        split_partition_size = ((split_partition_size + 63) / 64) * 64;

        at::Tensor lse_accum = torch::empty({requested_num_splits, s_q, h_q}, opts.dtype(torch::kFloat));
        at::Tensor out_accum = torch::empty({requested_num_splits, s_q, h_q, d_v}, opts.dtype(torch::kFloat));
        params.split_b = 1;
        params.split_num_splits = requested_num_splits;
        params.split_partition_size = split_partition_size;
        params.split_stride_q_b = 0;
        params.split_stride_indices_b = 0;
        params.split_lse_accum = lse_accum.data_ptr<float>();
        params.split_o_accum = out_accum.data_ptr<float>();
        params.split_stride_lse_accum_split = int64_stride_to_int(lse_accum.stride(0));
        params.split_stride_lse_accum_s_q = int64_stride_to_int(lse_accum.stride(1));
        params.split_stride_o_accum_split = int64_stride_to_int(out_accum.stride(0));
        params.split_stride_o_accum_s_q = int64_stride_to_int(out_accum.stride(1));
        params.split_stride_o_accum_h_q = int64_stride_to_int(out_accum.stride(2));
        params.split_decode_c_load = false;

        gfx93::fwd::run_fwd_phase1_splitkv_kernel<576, false>(params);

        CombineParams combine_params = {
            1, s_q, h_q, d_v,

            (float*)lse.data_ptr(),
            out.data_ptr(),
            s_q * h_q, int64_stride_to_int(lse.stride(0)),
            s_q * h_q * d_v, int64_stride_to_int(out.stride(0)), int64_stride_to_int(out.stride(1)),

            lse_accum.data_ptr<float>(),
            out_accum.data_ptr<float>(),
            int64_stride_to_int(lse_accum.stride(0)), int64_stride_to_int(lse_accum.stride(1)),
            int64_stride_to_int(out_accum.stride(0)), int64_stride_to_int(out_accum.stride(1)), int64_stride_to_int(out_accum.stride(2)),

            nullptr,
            nullptr,
            requested_num_splits,

            nullptr,
            at::cuda::getCurrentCUDAStream().stream(),

            true,
            requested_num_splits,
            nullptr,
            0
        };
        gfx9::decode::bf16_dsa::run_flash_mla_combine_kernel<hytlass::bfloat16_t>(combine_params);
        return {out, max_logits, lse};
    }

    std::vector<FwdFeatures> required_features;
    if (h_q <= 16) {
        required_features.push_back(FwdFeatures::HEAD_16);
    } else if (h_q == 32) {
        required_features.push_back(FwdFeatures::HEAD_32);
    } else if (h_q == 64) {
        required_features.push_back(FwdFeatures::HEAD_64);
    } else if (h_q == 128) {
        required_features.push_back(FwdFeatures::HEAD_128);
    } else {
        TORCH_CHECK(false, "Unsupported h_q: ", h_q);
    }
    if (d_qk == 576) {
        required_features.push_back(FwdFeatures::HEAD_DIM_576);
    } else if (d_qk == 512) {
        required_features.push_back(FwdFeatures::HEAD_DIM_512);
    } else {
        TORCH_CHECK(false, "Unsupported d_qk: ", d_qk);
    }
    if (attn_sink.has_value()) {
        required_features.push_back(FwdFeatures::ATTN_SINK);
    }
    if (have_topk_length) {
        required_features.push_back(FwdFeatures::TOPK_LENGTH);
    }

    if (arch.is_gfx93x()) {
        Fwd_Sm90_Impl fwd_impl(arch.is_gfx938());
        fwd_impl.run(params, required_features);
    } else {
        TORCH_CHECK(false, "Unsupported architecture");
    }

    return {out, max_logits, lse};
}
