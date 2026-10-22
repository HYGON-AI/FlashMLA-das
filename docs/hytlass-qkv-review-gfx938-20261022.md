# Focused gfx938 FP8 QKV Repeat Review

## Scope

This follow-up investigates the different failed-case LSE hashes in original
direct FP8 QKV cases 18/19. It does not change runtime sources, the dependency,
or the original 89-case selection. Existing failures remain outside the requested
dependency migration fixes.

Both cases use batch 2, query length 2, key length 512, dimension 576,
variable lengths, causal attention and seed 0. Case 18 has 16 query heads;
case 19 has 64. The original dense test generator, reference implementation
and tolerances are reused. Repeated calls retain the same input tensors;
reference checks run on CPU copies after the six-call group. This is a focused
diagnostic, not an additional set of passing correctness cases.

The previous isolated builds are reused in `sz_dsa` on nmz27:

| Build | Application | Dependency |
| --- | --- | --- |
| Baseline | `4529ac467f0989a4d73fe8e373fea15bb43a33b9` | CUTLASS `33e45645599f371c2382e67920085498f5905955` |
| Migration | `2e6278ce1967e9a87ba9c6fa7d0b6d986a0d46da` | HYTLASS `4fad709bb75d1854daca5c3343886b4e2cc2da74` |

## Device Conditions

All four worker processes used physical card 6, PCI `0000:ca:00.0`, with
runtime checks for the PCI address, gfx938 architecture and isolated extension
import. Each process required three samples of HCU 0%, displayed VRAM 0%, and
no KFD allocations/queues. The driver baseline was 3 MiB of 147440 MiB.
Foreign allocations/queues were monitored throughout; all four gate records
are valid and contain no foreign occupancy. Assembly remained disabled.

## Results

Each build ran two independent worker processes. Each process called each case
six times with identical retained inputs, giving 12 calls per case per build,
48 extension calls overall. Input hashes match across both builds and both
processes, remain unchanged after the calls, and reference hashes match.

| Observation | Case 18: 16 heads | Case 19: 64 heads |
| --- | ---: | ---: |
| Baseline output checks passing | 0/12 | 0/12 |
| Migration output checks passing | 0/12 | 0/12 |
| Distinct baseline LSE hashes | 12/12 | 12/12 |
| Distinct migration LSE hashes | 12/12 | 12/12 |
| Largest LSE difference within baseline repeats | 0.96020651 | 0.80623388 |
| Largest LSE difference within migration repeats | 0.96019745 | 0.80620766 |
| Largest LSE difference across builds in these repeats | 0.96028900 | 0.80622387 |

The original saved output hashes matched because every output element was NaN
in both builds: 32768 elements in case 18, 131072 in case 19. Their original
LSE differences were 48/64 and 160/256 elements respectively. Those matching
output hashes were not evidence of numerical correctness.

The repeat captures show variable outputs, including different NaN patterns,
within the baseline itself. LSE reference checks pass intermittently while
output checks fail in every run. The baseline path is therefore already
unstable with identical inputs, before changing CUTLASS to HYTLASS.

This supplies the previously missing same-build gfx938 control. It gives no
evidence of a newly failing configuration caused by the dependency migration.
It does not establish the instability's kernel root cause, prove failed outputs
equivalent, or exclude every possible migration effect in an unstable branch.
Those limits remain alongside the passing-output comparisons in the
[original gfx938 report](hytlass-validation-20261022.md). No unrelated fix was made.

## Evidence

Downloads contains `FlashMLA-HYTLASS-qkv-review-gfx938-20261022.json`, including
all four gate records, input hashes, extension hashes, per-run reference checks,
within-build and cross-build comparisons. Raw tensors, scripts and logs are in
`FlashMLA-HYTLASS-qkv-evidence-gfx938-20261022.tar.gz` (6090640 bytes), SHA-256:

`2d5311facd38654a7ec38181508c051cdbd51bb23492026742e83ca920857686`

The PR remains a draft and has not been merged. No performance benchmark ran.
