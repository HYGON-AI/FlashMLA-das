# HYTLASS Dependency Impact Review: 2026-10-22

## Conclusion and Limits

No new failing case has been identified in the reviewed gfx936/gfx938 migration
selection. This review traces all 11 exported extension entry points and all 29
build units, checks every modified original application source file, and adds
42 gfx936 configurations plus 12 repeated executions of existing failed cases.
It does not certify numerical correctness for configurations that already fail
the previous dependency, nor exhaust every possible shape or architecture.

The baseline is FlashMLA `4529ac467f0989a4d73fe8e373fea15bb43a33b9` with
CUTLASS `33e45645599f371c2382e67920085498f5905955`. The runtime migration source
remains `2e6278ce1967e9a87ba9c6fa7d0b6d986a0d46da` with unmodified HYTLASS
`4fad709bb75d1854daca5c3343886b4e2cc2da74`. Documentation and the standalone
ABI test include fix are subsequent changes. No production source was changed
for this review, and no previous numerical failure was repaired or hidden.

## Affected Components

| Component | Dependency-sensitive behavior | Review and runtime evidence |
| --- | --- | --- |
| Build and common API types | Submodule/include path, old compiler define, BF16/FP16/FP8 types, typed tensor pointers | Both complete 29-unit extensions build and link; application parameter fields and dispatch formulas are unchanged after type renaming |
| Dense BF16/FP16 decode | QK/PV MMA, shared-memory reads, fragment layout, conversion, softmax and split reduction | Both architectures' original matrix; supplementary gfx936 multi-KV-head, split-KV, noncausal, zero-length and page-edge cases |
| Dense FP8 KV and QKV | Packed FP8 operands, FP16/BF16 intermediate layouts, native/LIT MMAC calls, scaling and conversion | Both original matrices exercise selected direct entry points; existing numerical failures and architecture rejections limit acceptance |
| Legacy decode, query concatenation and quantization | The same affected templates through legacy dispatch, FP8 conversion and concatenation layouts | Original matrices cover all five exported legacy entry points; six failed concatenation configurations repeated on gfx936 |
| Sparse FP8 decode | Model1/v32 persistent variants, MMA/copy layouts, masks, Top-K length and sinks | All 12 original sparse-FP8 selections pass on each architecture, with checked outputs identical |
| Sparse BF16 DSA decode | Shared BF16 pointers and combine conversion; DSA math implementation is not replaced | Original BF16, extra-KV, zero-length and invalid-index tests pass; inherited output-only acceptance is retained |
| Sparse prefill | Template phase-1 MMA/copy, softmax, optional sink and Top-K length; shared parameter types | Original template-prefill selections pass; ten additional gfx936 prefill selections pass, including independently enabled options and all-invalid indices |
| DSA MLS prefill | Shared parameter types and host adapter; its separate math implementation is unchanged | Four original DSA selections pass on each architecture; original output-only acceptance is retained |
| Metadata and combine kernels | Ceil division, scheduling, array conversion and split output/LSE reduction | Executed through decode paths; long-sequence and multi-KV-head supplements add combine/scheduling coverage; metadata padding is not certified bitwise |
| Precompiled assembly | Shared host parameters and dispatch still depend on types; instruction artifacts are unchanged | Source comparison confirms no assembly artifact change; runtime matrices disable assembly to exercise the changed templates and do not claim assembly execution coverage |

Changes in library templates and compiler helpers can also affect generated code
and performance. This review makes no latency, throughput, or performance
equivalence claim.

## Exported Entry Point Inventory

The binding inventory is [api.cpp](../csrc/api/api.cpp). Python interfaces have
no migration diff. Each exported entry point is accounted for below; this is a
source/call-path inventory, not an assertion that every dispatch branch passed.

| Export | Relevant implementation | Runtime selection |
| --- | --- | --- |
| `dense_decode_fwd` | `api/dense_decode.h`, `gfx93/decode/dense`, common combine | Original dense cases and supplementary dense cases |
| `dense_decode_fwd_kvfp8` | `api/dense_decode_kvfp8.h`, `gfx93/decode/dense_kvfp8` | Original `modern_kvfp8` cases |
| `dense_decode_fwd_qkvfp8` | `api/dense_decode_qkvfp8.h`, `gfx93/decode/dense_qkvfp8` | Original `modern_qkvfp8` cases; gfx938-only |
| `sparse_decode_fwd` | `api/sparse_decode.h`, sparse-FP8/BF16 DSA and combine | Original sparse decode cases |
| `sparse_prefill_fwd` | `api/sparse_fwd.h`, template prefill and DSA MLS | Original prefill and supplementary prefill cases |
| `get_mla_decoding_metadata_dense_fp8` | `extension/flash_fwd_mla_metadata.cu` | Legacy decode metadata setup; consumed by downstream operators |
| `fwd_kvcache_mla_nope_pe` | `extension/flash_api.h`, legacy BF16/FP16 templates | `legacy_cat` |
| `fwd_kvcache_mla_fp8` | `extension/flash_api.h`, legacy FP8 templates | `legacy_kvfp8`, `legacy_qkvfp8` |
| `fwd_kvcache_mla_fp8_with_cat` | `extension/flash_api.h`, legacy FP8/concatenation templates | `legacy_kvfp8_cat`, `legacy_qkvfp8_cat`, `legacy_qbf16_cat` |
| `fwd_kvcache_quantization_mla` | `extension/flash_api.h`, legacy conversion/templates | `legacy_quant` |
| `fwd_kvcache_quantization_q_nope_pe_mla` | `extension/flash_api.h`, legacy conversion/concatenation | `legacy_quant_cat` |

## Source and Register Mapping Checks

All 48 modified original C++/HIP application files were compared against the
baseline after explicitly accounting for the namespace/header substitutions,
the local operation tags, and the 35 removals of unit `ValLayoutMNK` arguments.
No additional application computation or dispatch edit was found. New code is
concentrated in [hytlass_ext.h](../csrc/hytlass_ext.h); setup changes replace the
dependency path and remove the old define.

All 21 retained MMA/copy trait definitions match the previous dependency after
the documented names and value-type members are adapted. All 14 locally retained
operations/tags match after compiler builtin/helper adaptations. The seven
release-inherited operations have the same register types and payload sizes.
Their implementations are not textually identical: native MMAC helpers replace
the old architecture-specific builtins. Manual inspection of the gfx936/gfx938
branches preserves operand grouping, accumulator chaining, and result ordering;
the FP8 LIT path preserves its flags. These checks are supported by runtime
comparison, rather than treating register sizes as numerical proof.

A separate host-only executable enumerated actual layouts from both libraries:
18 MMA operations, each with six thread layouts (`1x1x1`, `1x2x1`, `1x4x1`,
`1x8x1`, `2x2x1`, `4x2x1`), plus three copy traits. It enumerates A/B/C atom
layouts, every thread/value-to-element mapping for 108 tiled-MMA combinations,
and all copy source/destination/reference maps. This conservative selection
includes the non-unit thread groupings used by legacy FP8 templates.

The complete 516-line mapping files compare byte-for-byte equal. Each SHA-256 is
`f36d58e1ee97c2fae7bb18cb060fc394060fff87f59bf0670386a10772d498ca`.
These are CPU layout computations, not GPU numerical tests; no card allocation
or timing assertion is needed for this check.

## Supplemental gfx936 Runtime Results

The existing isolated builds in `sz_dsa_gfx936` on bw65 were reused. Every accepted
worker batch required three samples of HCU 0%, displayed VRAM 0%, no KFD
allocation/queue, and runtime monitoring for foreign occupancy, using the same
physical-card checks as the [gfx936 report](hytlass-validation-gfx936-20261022.md).
All included batches have valid environment records and use physical card 1,
PCI `0000:56:00.0`. Original test assertions/tolerances are unchanged; assembly
remains disabled. GPU performance benchmarking was not run.

| Supplement | Cases per build | Baseline / migration result |
| --- | ---: | --- |
| BF16/FP16, dimensions 512/576, KV heads 2/4, causal/noncausal | 16 | All pass |
| BF16/FP16, 64/128 heads, sequence length 8192, causal/noncausal | 8 | Four BF16 pass; four FP16 reproduce numerical assertion failures |
| BF16/FP16, sequence lengths 65/130, with/without zero lengths | 8 | All pass |
| Prefill dimensions 512/576, heads 32/128, sink and Top-K length enabled independently | 8 | All pass |
| Prefill dimensions 512/576, all indices invalid | 2 | Both pass |
| Six existing legacy concatenation failures, each run twice per build | 12 | All reproduce failure |
| Total | 54 | 38 pass, 16 fail, in each build |

All 54 statuses and failure signatures match, with zero newly failing case.
The 38 passing pairs have 86 bitwise-identical captured tensors. The four
failing long-sequence FP16 pairs also have identical output/LSE tensors; their
failure does not establish numerical correctness. These are 42 additional
configurations and 12 repeat runs, not 54 distinct new configurations.

## Failed and Auxiliary Output Review

The earlier passing-output acceptance was deliberately narrower than inspecting
every captured tensor. This review additionally checks hashes for every captured
output, including auxiliary values and numerical assertion failures. All earlier
passing captures, including the auxiliary captures excluded from their original
acceptance, have matching hashes.

There are differences in six previously failing legacy concatenation
configurations (original case IDs 21, 23, 29, 31, 37, 39) on each architecture.
The gfx936 repeats show that both baseline and migration produce differing
output/LSE tensors when the same seeded failed test is repeated. This establishes
instability in the existing baseline test path; it does not establish its root
cause, bound every possible migration effect, or prove failed outputs equivalent.
No unrelated attempt to fix this behavior was made.

The saved gfx938 direct-QKV FP8 cases 18/19 also have different failed-case LSE
hashes. A subsequent [focused gfx938 repeat review](hytlass-qkv-review-gfx938-20261022.md)
ran each case 12 times per build with verified identical inputs and references.
All 12 baseline LSE hashes differ in each case, as do the migration hashes;
outputs also vary within the baseline. All 48 calls still fail output checks.
The original matching output hashes represent all-NaN tensors. This establishes
existing baseline instability and supplies the missing same-build control;
it does not establish the kernel root cause or attribute every cross-build
value difference. These failed branches must not be described as having fully
equivalent or correct outputs. gfx936 rejects this entry point.

## Evidence

Downloads contains `FlashMLA-HYTLASS-impact-audit-20261022.json` with the complete
source/operation/trait and 29-unit inventory, and
`FlashMLA-HYTLASS-impact-regression-gfx936-20261022.json` with supplemental case
results, all captured output comparisons, same-build repeats, and environment
records. `FlashMLA-HYTLASS-impact-evidence-gfx936-20261022.tar.gz` retains the
runtime scripts/logs, host-only layout source, build logs and complete maps.
Its SHA-256 is
`fd3c9ae85831c1239e587650150f81eec180ce39749da57d1ca8c8b72b4673b5`.
Raw tensors remain in `/tmp/flashmla-impact-results-gfx936-20261022` and
`/tmp/flashmla-cutlass-results-gfx936-final-20261022` inside the container.
The focused gfx938 review adds `FlashMLA-HYTLASS-qkv-review-gfx938-20261022.json`
and `FlashMLA-HYTLASS-qkv-evidence-gfx938-20261022.tar.gz`; its report records
the archive hash and all four valid idle-device rounds.

The original [gfx938 report](hytlass-validation-20261022.md) and
[gfx936 report](hytlass-validation-gfx936-20261022.md) retain the original
89-case-per-build selection. The PR remains unmerged. Source inventory,
representative passing cases, and baseline-failure matching support the scoped
migration conclusion; they do not establish exhaustive correctness.
