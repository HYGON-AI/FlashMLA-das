# gfx936 Dependency Regression Validation: 2026-10-22

The selected gfx936 dependency-regression gate passed: no newly failing case,
changed failure signature, or changed checked output was observed after the
HYTLASS replacement. Existing baseline failures were recorded without changing
production kernels or tolerances. Together with the [gfx938 comparison](hytlass-validation-20261022.md),
this completes the requested two-architecture correctness comparison for the
selected cases; it is not exhaustive correctness coverage.

## Builds

| Item | Baseline | Migration |
| --- | --- | --- |
| FlashMLA implementation | `4529ac467f0989a4d73fe8e373fea15bb43a33b9` | `2e6278ce1967e9a87ba9c6fa7d0b6d986a0d46da` |
| Dependency | CUTLASS `33e45645599f371c2382e67920085498f5905955` | HYTLASS `4fad709bb75d1854daca5c3343886b4e2cc2da74` |
| Compilation units and link | 29, passed | 29, passed |
| Checked application source files | 226, no mismatches | 228, no mismatches |

Host: `bw65`; container: `sz_dsa_gfx936`. Toolchain: DTK 26.04, AICC/Clang 18
revision `e616ff58038c2e136bf33600b27dc1cab6ebb440`, GCC 11.4, Python 3.10,
PyTorch 2.10.0 / HIP 6.3.26113. Both builds use code object version 5 and the
original configured gfx938/gfx936/gfx928 offload targets. The standalone gfx936
register ABI compilation also passed, using the HIP runtime include fix from
`29101ef` outside the application source trees.

The complete source archives have the same SHA-256 as the gfx938 input archives.
Dependency provenance is covered by those verified archives; post-build file
comparison covers application runtime sources and excludes generated version
metadata. No unrelated source fix was applied.

The migration build uses an isolated directory under
`/home/work/shenzhe/flashmla-open-source-validation-gfx936-20261022-a28979dc`.
The accepted baseline build uses
`/tmp/flashmla-open-source-validation-gfx936-20261022-a28979dc/baseline`.
An initial baseline preparation on the NFS home directory was stopped during
filesystem waiting and replaced by the local build; it produced no included
runtime results. The original user project was not overwritten.

## Device Checks

Runtime device: gfx936, HCU/HIP index 1, PCI `0000:56:00.0`, driver unique ID
`00159ae000022101`, total VRAM 65520 MiB. The worker checks the actual HIP PCI
address, gfx936 architecture, and the imported library's isolated directory.
These identifiers are saved before executing an operator, including cases whose
process later terminates.

Before every worker batch, three samples require HCU utilization 0%, displayed
VRAM utilization 0%, and no KFD memory allocation or queue on that device.
The approximately 3 MiB driver baseline is recorded explicitly. Utilization
and memory are read from PCI-matched driver sysfs attributes; the HCU/HIP-to-PCI
mapping was established with `hy-smi`. DRM card numbers are not assumed to be
HCU/HIP indices. The initial full-device `hy-smi` query timed out before starting
any worker, so that attempt contributes no runtime result.

KFD allocations and queues are monitored while each worker runs. All included
rounds have valid environment records with no detected foreign occupancy.
No other user's process was stopped, and no card was reset or reclocked.

## Results

The [same 89-case selection](hytlass-validation-20261022.md#coverage), seed 0,
reference functions, and original correctness assertions were used for both
builds. `FLASH_MLA_ENABLE_ASM=0` selects the affected template paths. Timing
was skipped after correctness checks; no performance claim is made.

| Outcome | Baseline | Migration |
| --- | ---: | ---: |
| Passed original correctness assertions | 55 | 55 |
| Returned numerical assertion failure | 16 | 16 |
| Rejected gfx936: selected gfx938-only entry points | 12 | 12 |
| Process terminated: dense GPU VMFault | 4 | 4 |
| Process terminated: compiled dimension assertion | 2 | 2 |
| Total attempted | 89 | 89 |

All 89 case statuses and failure signatures match. There are zero newly failing
cases, missing cases, changed failure signatures, or invalid included rounds.
The 12 architecture rejections are four direct FP8 QKV selections and eight
legacy FP8 QKV/concatenation selections. The four VMFaults reproduce with dense
dimension 512 and 64/128 heads for BF16/FP16. The two compiled assertions are
FP8 KV dimension-512 selections and match `params.d == Config::HEAD_DIM_K`.
These baseline limitations were not repaired or counted as migration regressions.

The 55 passing pairs have 118 bitwise-identical checked output tensors and zero
output differences. All 20 selected sparse-prefill/DSA cases and all 19 selected
sparse-decode cases pass in both versions. BF16 sparse decode and DSA prefill
output acceptance follows their original output-only assertions; auxiliary
values are not added to that acceptance criterion. Matching failed cases does
not establish numerical correctness for their configurations.

## Evidence

Downloads contains `FlashMLA-HYTLASS-regression-gfx936-20261022.json` and the
matching `.tar.gz`. They retain per-case outcomes, output hashes and differences,
device checks, source-archive and library hashes, compilation command inventory,
build logs, the ABI result, and validation scripts. CPU tensor captures remain
in `/tmp/flashmla-cutlass-results-gfx936-final-20261022` inside the container.
The downloaded bundle SHA-256 is
`e7d848d8310fa450082b38c0e4361e96eee716962517c80c56e8f2fd79c498a3`.

The requested gfx936 and gfx938 migration comparisons are complete. The PR
remains unmerged for normal review. Historical author-email work remains with
the reviewers, as previously agreed.
