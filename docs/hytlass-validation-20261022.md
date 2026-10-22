# Dependency Regression Validation: 2026-10-22

## Scope and Acceptance

The gate is no new correctness failures after replacing the customized CUTLASS
dependency with public HYTLASS. Existing failures reproduced with the previous
dependency are recorded without changing unrelated kernels or tolerances.
This report supersedes the broader release-gate wording in the historical
[2026-10-21 snapshot](hytlass-validation-20261021.md).

Uncommitted experiments outside the dependency migration were backed up and
withdrawn. The active migration extension was rebuilt in a fresh directory;
its production files match the original migration archive. The old experimental
library and build directory were moved outside its active import path.

## Builds and Environment

| Item | Baseline | Migration |
| --- | --- | --- |
| FlashMLA implementation | `4529ac467f0989a4d73fe8e373fea15bb43a33b9` | `2e6278ce1967e9a87ba9c6fa7d0b6d986a0d46da` |
| Dependency | CUTLASS `33e45645599f371c2382e67920085498f5905955` | HYTLASS `4fad709bb75d1854daca5c3343886b4e2cc2da74` |
| Build | Original successful isolated build | Fresh successful 29-unit build and link |

The standalone ABI test include fix is `29101ef`; it does not change runtime
kernel sources. Both extensions use DTK 26.04 / AICC-Clang 18, GCC 11.4,
Python 3.10, and PyTorch 2.10.0 / HIP 6.3.26113 in container `sz_dsa` on nmz27.
Runtime device: BW1100 / gfx938, physical card 6, PCI `0000:ca:00.0`.
The worker checks the actual HIP device PCI address and imported library path.

Before each worker batch, three samples must show VRAM display 0%, HCU 0%,
and no KFD allocation or queue on that physical device. The recorded 3 MiB
driver baseline is below 1% of 147440 MiB. During execution, KFD allocations
and queues are monitored for foreign processes. An earlier card-1 round stopped
on foreign occupancy and is excluded; preliminary harness trials are also
excluded. No other user's process was stopped.

## Coverage

The same 89-case plan, seed 0, original test reference functions and assertions
are used for both builds. Timing is skipped after correctness checks. Legacy
entry points use supported query length 1; quantization entry points use the
existing FP8 test data and reference through a public-API adapter.

| Family | Cases |
| --- | ---: |
| Dense BF16/FP16, dimensions 512/576, heads 16/64/128 | 12 |
| Direct dense FP8 KV and FP8 QKV | 8 |
| Legacy query concatenation, FP8 KV and quantization | 20 |
| Legacy FP8 QKV, concatenation and BF16 query | 10 |
| Sparse FP8 decode, optional sinks and Top-K lengths | 12 |
| Sparse BF16 decode, extra KV, zero lengths and invalid indices | 7 |
| Sparse prefill, dimensions 512/576, heads 16/32/64/128 | 16 |
| DSA MLS prefill shapes | 4 |
| Total per build | 89 |

All 29 compilation units have HYTLASS/HuTe dependencies in a conservative
source include closure. This inventory includes conditional branches and is
not a runtime execution trace or proof that every template is instantiated.
The plan exercises the exported operator families; it is not exhaustive shape
coverage. `FLASH_MLA_ENABLE_ASM=0` selects template paths. The original assembly
artifacts remain unchanged.

## Results

The selected gfx938 dependency-regression gate passed: no new failure or output
change was observed after replacing the dependency.

| Outcome | Baseline | Migration |
| --- | ---: | ---: |
| Passed original correctness assertions | 65 | 65 |
| Returned an assertion failure | 16 | 16 |
| Process terminated: GPU VMFault | 4 | 4 |
| Process terminated: compiled dimension assertion | 4 | 4 |
| Total attempted | 89 | 89 |

All 89 status pairs and failure signatures match. There are zero newly failing
cases, missing cases, changed failure signatures, or invalid included device
rounds. The four VMFault cases are dense dimension 512 with 64/128 query heads
for BF16/FP16. The four compiled assertions are direct dense FP8 KV/QKV dimension
512 cases; both versions assert `params.d == Config::HEAD_DIM_K`. The 16 returned
failures are existing dense and legacy numerical assertions. They remain
recorded limitations and were not fixed as part of this dependency migration.

All 65 passing pairs have bitwise-identical checked outputs: 138 tensor
comparisons, zero differences. This is stronger evidence than matching pass/fail
status for those selected cases. Matching failed cases does not establish
numerical correctness for configurations that already fail the baseline.

For passing pairs, output tensors are compared directly, with SHA-256 and
finite-value differences recorded. BF16 sparse decode and DSA MLS prefill
acceptance covers the output tensor only, matching their original tests;
auxiliary values are not silently added to their original acceptance criteria.
Failed pairs are compared by case and failure signature, including original
assertion location or GPU VMFault classification.

## Follow-up and Evidence

gfx936 runtime validation is still required and will be performed separately.
gfx928/gfx936/gfx938 standalone ABI compilation passed previously; compilation
does not establish runtime correctness on those architectures. No performance
claim is made from this correctness round. Historical performance measurements
lack the strict idle-device evidence and are not part of this gate.

The Downloads evidence files are `FlashMLA-HYTLASS-regression-20261022.json`,
`FlashMLA-HYTLASS-regression-20261022.tar.gz`, and
`FlashMLA-HYTLASS-source-scope-20261022.json`. The bundle contains the comparison,
case plan, source inventory, idle gates, build/test logs, and validation scripts.
CPU tensor captures remain in the isolated remote results directory; hashes
and comparison metrics are included in the report.
Withdrawn experiments are retained separately as
`FlashMLA-withdrawn-extra-changes-20261022-111824` and are not part of this branch.
The PR remains a draft pending the separate gfx936 check and normal review.
