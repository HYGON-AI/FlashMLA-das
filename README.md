# FlashMLA-das

FlashMLA-das 面向海光 HCU gfx936/gfx938 平台，提供 MLA 注意力计算、稀疏 prefill/decode、KV cache 及 Python 接口。

## 上游来源与修改说明

本项目基于 DeepSeek FlashMLA，面向 Hygon HCU 平台进行适配与优化。

- 上游项目：FlashMLA
- 上游仓库：[deepseek-ai/FlashMLA](https://github.com/deepseek-ai/FlashMLA)
- 上游基线分支：`main`
- 上游基线 Commit：`48c6dc426f045cb7743b18f5c7329f35f1b7ed79`
- 上游许可证：MIT
- 本仓库许可证：[MIT](LICENSE)

Modified by Hygon Information Technology Co., Ltd.

Copyright (c) 2026 Hygon Information Technology Co., Ltd.

HYGON 的原创修改包括：

- gfx936/gfx938 平台适配及相关构建工具链适配。
- BF16/FP8 MLA 算子、KV cache 及 Python 接口适配。
- sparse MLA prefill/decode 与 DSA/MLS 路径的功能与性能优化，包括 split-KV、索引排序、边界保护、extra KV 和 `topk_length` 支持。
- 与上述平台适配相关的测试、基准测试和构建流程调整。

HYGON 版权声明仅适用于其原创贡献，不替代或覆盖 DeepSeek 及其他上游作者的版权声明。原有版权声明及 MIT 许可文本完整保留。

第三方组件、固定版本及仍需补充的来源信息见 [Third-Party Notices](THIRD_PARTY_NOTICES.md)。

## Introduction

FlashMLA-das provides attention kernels adapted and optimized for Hygon HCU gfx936/gfx938. This repository contains the following implementations:

**Sparse Attention Kernels**

- Token-level sparse attention for the prefill stage
- Token-level sparse attention for the decoding stage, with FP8 KV cache
- DSA MLS sparse prefill and DSA BF16 sparse decoding on Hygon HCU gfx93

**Dense Attention Kernels**

- Dense attention for the decoding stage

## Tests and Benchmarks

#### Test & benchmark MLA decoding (Sparse & Dense):

```bash
python tests/test_flash_mla_dense_decoding.py
python tests/test_flash_mla_sparse_decoding.py
FLASH_MLA_DECODE_BF16=1 python tests/test_flash_mla_sparse_decoding.py
```

#### Test & benchmark MLA prefill (Sparse):

```bash
python tests/test_flash_mla_sparse_prefill.py
```

Run these scripts in the Hygon HCU environment. Correctness and performance results depend on the input configuration, software environment, and device load.

## Requirements

- Linux with Hygon HCU gfx936/gfx938 hardware.
- Hygon DTK/AICC toolchain and a matching HCU-enabled PyTorch environment. FP8 paths and tests require the corresponding FP8 data types.
- A host C++ compiler with GCC 9 or later and C++20 support.
- The pinned HYTLASS submodule described below.

Support matrix:

| Kernel | HCU Architecture | Attention Mode | KV Cache Format |
| :---: | :---: | :---: | :---: |
| Dense Decoding | gfx936 / gfx938 | MQA | BF16 / FP16 |
| Sparse Decoding | gfx936 / gfx938 | MQA | FP8 with scales |
| DSA BF16 Sparse Decoding | gfx936 / gfx938 | MQA | BF16 |
| Sparse Prefill | gfx936 / gfx938 | MQA | BF16 |

MQA denotes Multi-Query Attention. The sparse paths use one KV head. Supported head counts, head dimensions, and optional parameters vary by kernel; refer to the API checks and tests for the selected path.

For FP8 KV cache layouts, see the usage notes below and [tests/quant.py](tests/quant.py).

## Installation

```bash
git clone -b main https://github.com/HYGON-AI/FlashMLA-das.git flashmla
cd flashmla
git submodule update --init --recursive
pip install -v .
```

The [HYTLASS dependency](https://github.com/HYGON-AI/hytlass) is pinned at commit
`4fad709bb75d1854daca5c3343886b4e2cc2da74` in `csrc/hytlass`, with branch
`release` configured in `.gitmodules`. If the submodule is missing, `setup.py`
will try to initialize it before compiling. Existing checkouts should run
`git submodule sync --recursive` followed by `git submodule update --init --recursive`.
FlashMLA-specific register layouts and operation tags are in `csrc/hytlass_ext.h`;
the HYTLASS submodule itself is used without local modifications.

When running tests directly from the source tree, prefer an in-place build so
the local `flash_mla` package can find its compiled HCU extension:

```bash
python setup.py build_ext --inplace
python tests/test_flash_mla_sparse_prefill.py
FLASH_MLA_DECODE_BF16=1 python tests/test_flash_mla_sparse_decoding.py
```

If you install the package separately, avoid launching tests from a different
unbuilt source checkout, because Python may import that checkout's `flash_mla/`
directory instead of the installed package and fail to load the compiled extension.

## Usage

### MLA Decoding

To use the MLA decoding kernels, call get_mla_metadata once before the decoding loop to get the tile scheduler metadata. Then, call flash_mla_with_kvcache in each decoding step. For example:

```python
from flash_mla import get_mla_metadata, flash_mla_with_kvcache

tile_scheduler_metadata, num_splits = get_mla_metadata()

for i in range(num_layers):
    ...
    o_i, lse_i = flash_mla_with_kvcache(
        q=q_i,
        k_cache=kvcache_i,
        block_table=block_table,
        cache_seqlens=cache_seqlens,
        head_dim_v=512,
        tile_scheduler_metadata=tile_scheduler_metadata,
        num_splits=num_splits,
        causal=is_causal,
        is_fp8_kvcache=is_fp8_kvcache,
        indices=indices,
    )
    ...
```

Reuse the scheduling metadata only while input shapes and the relevant sequence-length values remain unchanged. Create fresh metadata when these change. For sparse decoding, set `causal=False`; `block_table` and `cache_seqlens` may be `None` because `indices` contains absolute KV cache positions.

Where

- `s_q` is the number of q tokens per q sequence. If MTP (speculative decoding) is disabled, it should be 1.
- `h_kv` is the number of key-value heads.
- `h_q` is the number of query heads.

**FP8 KV Cache:**
If `is_fp8_kvcache` is set to `True`, the kernel reads the KV cache in the "FP8 with scale" format (described below). It dequantizes the cache to bfloat16 and performs attention computation in bfloat16. The output is also in bfloat16.

**BF16 Sparse Decode on gfx93:**
This branch also supports the DSA BF16 sparse decode path when
`is_fp8_kvcache=False` and `k_cache` / `extra_k_cache` are `torch.bfloat16`.
The test suite enables this path with `FLASH_MLA_DECODE_BF16=1`.

For the FP8 sparse layout with `head_dim_k=576` and `head_dim_v=512`, each token's KV cache is 656 bytes, structured as:
-   **First 512 bytes:** The "quantized NoPE" part, containing 512 `float8_e4m3` values.
-   **Next 16 bytes:** Scale factors, containing 4 `float32` values. The first `float32` is the scale for the first 128 `float8_e4m3` values, the second for the next 128, and so on.
-   **Last 128 bytes:** The "RoPE" part, containing 64 `bfloat16` values. This part is not quantized for accuracy.

See `tests/quant.py` for quantization and dequantization details.

**Sparse Attention (`indices` tensor):**
The `indices` tensor (if provided) enables token-level sparse attention by instructing the kernel to compute attention only for specified tokens.

-   **Shape:** `indices` should be a 3D tensor of shape `(batch_size, seq_len_q, topk)`.
-   **Format:** `indices_in_kvcache[i][j][k] = (the index of the page block where token t resides) * page_block_size + (the offset of token t within the page block)`, where `t` is the k-th token for the j-th query sequence in the i-th batch. Since the index of the page block has already been encoded into `indices_in_kvcache`, the kernel does not require the `block_table` parameter.
-   **Invalid entries:** Set invalid indices to `-1`.

**Return Values:**
The kernel returns `(out, lse)`, where:
-   `out` is the attention result.
-   `lse` is the log-sum-exp value of the attention scores for each query head.

See [tests/test_flash_mla_sparse_decoding.py](tests/test_flash_mla_sparse_decoding.py) and [tests/test_flash_mla_dense_decoding.py](tests/test_flash_mla_dense_decoding.py) for complete examples.

### Sparse MLA Prefill

For the sparse MLA prefill kernel, call `flash_mla_sparse_fwd` directly with the following parameters:
-   `q`: Query tensor of shape `[s_q, h_q, d_qk]`
-   `kv`: Key-Value tensor of shape `[s_kv, h_kv, d_qk]`
-   `indices`: Indices tensor of shape `[s_q, h_kv, topk]`
-   `sm_scale`: A scalar value

**Note on batching:** This kernel does not support a batch dimension. For multi-batch inference, reshape the input tensors and adjust the `indices` parameter to simulate batch processing.

**Invalid indices:** Set invalid entries in `indices` to `-1` or any number `>= s_kv`.

**Return Values and Equivalent PyTorch Code:**
The kernel returns `(out, max_logits, lse)`. This is equivalent to the following PyTorch operations:

```python
Q: [s_q, h_q, d_qk], bfloat16
kv: [s_kv, h_kv, d_qk], bfloat16
indices: [s_q, h_kv, topk], int32

kv = kv.squeeze(1)  # [s_kv, d_qk], h_kv must be 1
indices = indices.squeeze(1)    # [s_q, topk]
focused_kv = kv[indices]    # For the i-th sequence (s_q), the corresponding KV tokens are selected from the KV cache based on indices[i, :]. This operation results in a tensor of shape [s_q, topk, d_qk].

P = (Q @ focused_kv.transpose(-1, -2)) * sm_scale * math.log2(math.e)    # [s_q, h_q, topk]
max_logits = P.max(dim=-1) # [s_q, h_q]
lse = log2sumexp2(P, dim=-1, base=2)   # [s_q, h_q]，"log2sumexp2" means that the exponentiation and logarithm are base-2
S = exp2(P - lse)      # [s_q, h_q, topk]
out = S @ focused_kv  # [s_q, h_q, d_qk]

return (out, max_logits, lse)
```

See [tests/test_flash_mla_sparse_prefill.py](tests/test_flash_mla_sparse_prefill.py) for a complete example.

## Acknowledgement

We acknowledge the authors of the upstream FlashMLA project and the HYTLASS contributors. Source attribution and third-party license information are recorded in [Third-Party Notices](THIRD_PARTY_NOTICES.md).

## Hygon HCU Resources

- [Hygon Developer](https://developer.sourcefind.cn/)
- [FlashMLA-das repository](https://github.com/HYGON-AI/FlashMLA-das)
- [HYTLASS dependency](https://github.com/HYGON-AI/hytlass)

## Citation

```bibtex
@misc{flashmla2025,
      title={FlashMLA: Efficient Multi-head Latent Attention Kernels},
      author={Jiashi Li, Shengyu Liu},
      year={2025},
      publisher = {GitHub},
      howpublished = {\url{https://github.com/deepseek-ai/FlashMLA}},
}
```
