# MLU backend - validation status (stage snapshot)

This file records what has actually been run and what has not. It is deliberately conservative:
anything not listed as verified below should be treated as unverified.

## Verified on 2026-11-03 (this provider layout)

Built from a fresh CMake cache against the pinned InfiniTrain content (`c90338c`, v0.7.0) with
GCC 13.4.0, cncc 5.7.6, CMake 4.4.5 and Ninja 1.13.2; targets `mlu_gpt2` and `mlu_op_test`.

| Item | Evidence |
|---|---|
| Fresh configuration and build | `configure` and `build` of `mlu_gpt2` + `mlu_op_test` both succeeded; all **9** BANG C sources were compiled by `cncc` |
| Operator comparison vs CPU (`op_test`) | 35 small-shape FP32 cases: Linear (both weight layouts, bias on/off, non-square 3x5->7), LayerNorm, Softmax, Add broadcast, MulScalar, Transpose, CrossEntropy, Pow domain and Pow(x,3) fwd/bwd. All pass with `abs(got-ref) <= 1e-5 + 1e-4*abs(ref)` (Pow uses 1e-6/1e-5) |
| Negative comparison paths | `--inject-finite` and `--inject-nan` return exit code 1 with `RESULT: FAIL`; the controlled fatal case aborts with the expected marker and no post-fatal work |
| Device math functions (`tests/math_selftest`) | exp / log / tanh / sqrt / rsqrt / pow / identity: 0/1024 mismatches under the tool's combined tolerance (`abs <= 1e-6 + 1e-5*abs(ref)`); the largest absolute error is 4.883e-4 on `exp` at x=8.5, where the reference is 4914.77 (relative 1.19e-7) |
| Example executable | `gpt2 --help` loads and prints usage. **No model training step was run** |
| Absence of stale framework paths | the generated compile database contains no path to the previously used `5a7be78` source tree |

Note: Linear and Matmul currently execute through a **host fallback** - the operator tests above
prove that fallback path, not a device GEMM.

## Verified earlier (historical, pre-migration layout)

These were observed while the backend still lived under `mlu/` next to a separate framework tree.
They are recorded for traceability and were **not** re-executed for this layout change.

| Item | Historical evidence |
|---|---|
| Backend registration | the `--device mlu` validator accepted the backend and kernels dispatched on `kPrivateUse1` |
| Build dependency tracking | touching the launcher header rebuilt all `.mlu` objects; a following build did nothing |

## Not verified

| Item | Status |
|---|---|
| Standard recursive-submodule download | the validation build used an archive of the pinned framework tree plus shallow retrieval of the four dependencies at their pinned commits. File content matched the pinned revisions, but the plain `git submodule update --init --recursive` procedure was **not** exercised |
| Cross-provider regression | no MACA or CUDA build was run. The untouched official files are not evidence of cross-platform regression coverage |
| Device GEMM (CNNL) | not implemented; `src/kernels/linear.cc` does D2H -> host GEMM -> H2D and is marked `NOTE(MLU-FALLBACK)` |
| Full GPT-2 FP32 single-card 10 steps | **not completed**; earlier attempts hit a queue failure at large batch and a slow single-core backward |
| Backward coverage at model scale | partial; small-shape backward cases exist, full-model backward has not finished |
| BF16 | registered in dispatch only; `src/kernels/embedding.mlu` still rounds per token (marked `TODO(BF16-MUST-FIX)`), no BF16 accuracy run |
| Multi-card (CNCL) | not implemented (communication kernels absent) |
| Shared InfiniTrain test suites | not wired; `BUILD_TEST=ON` is rejected on purpose and the MLU regression tools are used instead |
| Performance | kernels run single task / serial (`cnrtFuncTypeBlock`); no multi-core or NRAM vectorisation yet |

## Known platform notes

- `__bang_atomic_add` triggered a queue error in our usage, so `EmbeddingBackward` accumulates
  with a row-partitioned scan instead (deterministic, no atomics).
- Device `powf` works once kernels run single-task/serial with `cnrtFuncTypeBlock`; with the
  earlier multi-task `cnrtFuncTypeUnion1` launch, loop writes to global memory did not persist.
- `MluGuardImpl::Memcpy` must copy through the current stream (`cnrtMemcpyAsync` + queue sync);
  plain `cnrtMemcpy` reads stale data while kernels are in flight.

## Next steps

1. device GEMM via CNNL (with the handle bound to the current stream) and re-run operator tests;
2. locate the large-shape queue failure, then run GPT-2 1 -> 2 -> 10 steps and compare loss
   step by step against a frozen A100 baseline;
3. BF16: FP32 accumulation in embedding, autocast/dtype promotion, softmax/LayerNorm/CE stability;
4. multi-card: CNCL registration and a 2-card DP milestone;
5. wire the shared InfiniTrain test suites and run a MACA/CUDA regression before claiming
   cross-provider compatibility.

## Strict loss acceptance tool (2026-11-03, this provider layout)

`backends/mlu/tools/compare_loss_strict.py` compares a run's per-step loss against the frozen
reference and decides pass/fail/reject on host only. It was migrated from the earlier prototype
tree (`InfiniTrain-Backends/tools/`, kept read-only) and fixed there; the prototype is not part of
this provider.

Verified on 2026-11-03 with the bundled Python (3.14.2) on Windows, no device and no training:

| Item | Result |
|---|---|
| Selftest `backends/mlu/tools/tests/test_compare_loss_strict.py` | `PASS (66/66 cases)`, rc=0, ~9 s. The count grows with added regressions: 54 cases in the first round, 62 after the schema/rank fixes, 66 after the config-type and reference-provenance fixes |
| Formatting | `scripts/format.py --path backends/mlu/tools --check --py <black 26.1.0>` rc=0 (isolated venv, not a repo dependency) |
| Real registry (formal mode) | rc=3 `formal mode rejects unknown_fields=['weights_sha256','data_sha256']` — the raw log hash, the single-case hash, the case derivation and the 10 registered steps are all validated before that gate, and the run then stops because the A100 asset hashes are still unknown |
| Reference provenance | the single-case file must be byte-identical to the segment cut from the raw log at the unique `Running: gpt2_1 (fp32)` title; a duplicate title, a tampered case file or a missing raw log are rejected |

Notes on the decision contract:

- `criterion_source=user_pdf_and_a100_log` (FP32 `max_abs<=1e-5`, BF16 `max_rel<=1e-2`) and
  `comparison_policy_source=program_convention` (error denominator, zero reference, `<=` boundary)
  are reported separately in the terminal output and in the JSON.
- Formal mode never falls back to registry numbers: the registry `steps` only cross-check the
  parsed log values and must match exactly.
- Schema and identity formats are validated before any comparison: `source_commit` must be a full
  40-hex token on both the actual metadata and the registered reference case, `binary_sha256` and
  the asset hashes a full 64-hex token (trailing characters are rejected), the actual metadata /
  registry / config / `unknown_fields` must have the documented container types, and a `--rank`
  run refuses to mix tagged and untagged loss records. Config fields that are numeric by meaning
  (`batch_size`, `sequence_length`, `total_batch_size`, `learning_rate`) are type-checked on both
  sides before any comparison, so a bool/string/`null` there is a rejection rather than a silent
  coercion. Structural or type errors are reported as `REJECTED` with rc=3, never as a traceback.
- Diagnostic mode prints `DIAGNOSTIC_MATCH`/`DIAGNOSTIC_FAIL` only, with `acceptance_ready=false`.
- A BF16 row with a zero reference and a non-zero actual yields `rel_diff = inf`, so the JSON
  contains the non-standard token `Infinity`. It never raises, but strict JSON parsers reject it;
  the output contract is left unchanged on purpose.
- The A100 log and its single-case derivation are redistributed under the upstream MIT license
  (`references/LICENSE.InfiniTrain-Test`, `InfiniTensor/InfiniTrain-Test@5a0f27a5`).
- This tool only proves the acceptance logic. It is **not** evidence that GPT-2 FP32 ten steps or
  any accuracy target has passed; the assets (`weights_sha256`, `data_sha256`) are still unknown.

## Key backward cases in `op_test` (source prepared; build/device pending)

Added on 2026-11-03 under 007-P1 v2 / 007-P2 v1. **Nothing here has been compiled or run** on this
Windows workspace; the MLU build and device execution need a separate, explicitly authorized
server batch. No PASS result for these new cases exists yet.

- New entry point: `op_test --backward-group a|b|all`. Default behaviour is unchanged: without that
  flag the existing suite still runs exactly as before. An unknown group value, or combining the
  flag with `--comparator-selftest` / `--debug-status-test` / `--probe-case`, exits with rc=2 before
  the backend is registered.
- Group A: `EmbeddingBackward` (repeated tokens, unused rows must stay exactly zero),
  `CrossEntropyBackward` (`[8,32]` and `[1,32]`, scalar upstream gradient `g=0.5`),
  `AccumulateGrad` (in place, `rate=+0.5` for gradient accumulation and `rate=-0.5` for the SGD
  update role; kernel-level semantics, not the training accumulation rate).
- Group B: `SoftmaxBackward` (`dim=1`, finite / `-inf` mask / `float32_lowest` mask, every row keeps
  at least one unmasked logit; masked columns must have probability and gradient **exactly 0** and
  finite; both the CPU and the MLU forward outputs are guards-checked and finiteness-checked before
  they are fed to a backward call, and a non-finite forward output records a failure and skips that
  mask instead of polluting the gradient), `LayerNormBackward` (3D input `[1,2,4]`, `mean`/`rstd`
  must be FP32 `[1,2]`, three gradients checked separately against both the CPU kernel and the
  upstream expected values), `MatmulBackwardInput/Other` (2D and batched, dA and dB separately).
- Comparison: existing `Compare(name, ref, got, atol, 0.0, allow_special_ref=false)` — absolute
  threshold only, `rtol=0`, no special-value allowance for the new cases. Every CPU and MLU return
  value (including intermediate `mean`/`rstd`, the softmax forward output used as a backward input,
  and the in-place target after an `AccumulateGrad` call on either device) is checked for
  null/shape/dtype before it is read or fed to the next kernel; size and analytic-reference
  finiteness (including the double→float cast) are checked before `Compare`, and any failure sets
  the failure flag without touching the data, so the process exits non-zero.
- Data movement: the blocking `ToHost` helper is used for every device-to-host read, inside an
  explicit `DeviceGuard` for the MLU device. `ToHost` returns a `std::vector<float>`; the void
  return that cannot report its own exit code is the inner `MluGuardImpl::Memcpy`
  (`cnrtMemcpyAsync` on the current queue followed by `cnrtQueueSync`, failures raised by
  `CNRT_CHECK`). Each MLU case logs its own `[bwd] case=... device=... stream=...
  sync=blocking_Memcpy_current_queue host_read_after_tohost_returned` line only **after** the
  relevant read-backs have returned (LayerNorm logs after all three gradients were copied out).
  `Tensor::To(kCPU)` is deliberately **not** used: its D2H path only enqueues the copy.
- Negative paths: `--inject-finite` / `--inject-nan` apply to a copy of the compared result vector
  and must still end in a non-zero exit; they never modify the CPU or analytic reference.
- Not formatted: `clang-format-16` is not available in this workspace, so the new C++ has **not**
  been format-checked yet; this must be done before the server build.

## GPT-2 single-card follow-up (2026-11-06)

- FP32 completed all 10 training steps on one MLU. With the gradient accumulation
  optimization, the median gap between logged steps fell from about 47.8 s to
  23.9 s, and all 10 reported losses matched the previous MLU run exactly.
  The comparison against the A100 reference remains diagnostic and exceeds the
  FP32 acceptance threshold.
- BF16 autocast completed the forward pass after parallelizing Cast. Backward
  stopped at a gradient merge in Function::BackwardPartial because an FP32
  gradient was being added to a BF16 buffer. A complete BF16 step remains open.
- These are staged-run observations from the corresponding changes. The branch
  keeps the existing InfiniTrain submodule revision and the original accuracy
  thresholds.


## 2026-11-09: backward-group cases executed on device + GPT-2 FP32 10 steps with a correctly aligned checkpoint

Environment: aisoft-node2 (Cambricon MLU590), docker `cambricon-base/pytorch:v26.06.0-torch2.12.0-torchmlu1.33.1-ubuntu24.04-py312`,
cncc 5.7.2, GCC 13.3.0, CMake 3.30, Ninja 1.13, fresh build dir `build-collab` at this commit (ea5d11c),
submodule at the pinned `c90338c` (v0.7.0).

### op_test (previously "source prepared; build/device pending")

| Item | Result |
|---|---|
| Default suite (35 FP32 small-shape cases) | `RESULT: PASS` (re-confirmed on this server) |
| `op_test --backward-group all` (EmbeddingBackward, CrossEntropyBackward, AccumulateGrad, SoftmaxBackward x3 masks, LayerNormBackward, Matmul backward 2D + batched) | `RESULT: PASS` — **first device execution**; every case PASS with max_abs <= 9.6e-7 |

### Checkpoint layout: the loader expects the grouped layout, NOT llm.c interleaved

`LoadFromLLMC` reads parameters grouped by type across layers
(`ln_1.weight` for all layers, then `ln_1.bias` for all layers, then `c_attn.weight` for all layers, ...),
not llm.c's per-layer interleaved order. Feeding an llm.c-interleaved export silently misaligns every
parameter after `h0.ln_1.weight` (the bias row is read from inside `h0.qkvw`). Observed symptom:
GPT-2 step-1 loss 18.21 instead of ~4.96, identical on CPU and MLU (backend kernels are not at fault).

Diagnosis path that may save others the same three hours: run the example with
`--precision_check "level=1,save_tensors=true,output_path=<dir>"` (dumps one .npy per module),
then compare against a NumPy reference forward; the first divergent module was
`transformer.h.0.ln_1_forward`, and fitting `out = x_norm * w + b` per channel recovered the
exact file offset the loader had misread.

`backends/mlu/tools/export_gpt2_llmc_grouped.py` (numpy-only) produces the layout the loader
expects from a HF `model.safetensors`; verified against HF `openai-community/gpt2` (124M).

### GPT-2 124M FP32, single card, 10 steps (batch 4 x seq 64, total batch 256, SGD lr 1e-4, overfit single batch)

Data: standard llm.c tiny_shakespeare train split, 301,966 tokens. This is NOT the frozen
A100 reference asset (305,260 tokens), so per-step comparison against that baseline remains
diagnostic only; the acceptance below is cross-device agreement on the identical batch.

| step | MLU loss | CPU loss | abs diff |
|---|---|---|---|
| 1 | 4.961767 | 4.961770 | 3e-06 |
| 2 | 5.113737 | 5.113658 | 8e-05 |
| 3 | 5.463838 | 5.463693 | 1.5e-04 |
| 4 | 5.076122 | 5.076038 | 8e-05 |
| 5 | 5.159688 | 5.159536 | 1.5e-04 |
| 6 | 5.120875 | 5.120900 | 3e-05 |
| 7 | 4.988027 | 4.987971 | 6e-05 |
| 8 | 5.156721 | 5.156620 | 1e-04 |
| 9 | 4.860516 | 4.860461 | 6e-05 |
| 10 | 5.000969 | 5.000990 | 2e-05 |

- MLU completed all 10 steps without divergence, peak mem pool 1517 MB, ~650 s/step
  (Linear/Matmul still on the host-fallback GEMM path).
- Full logs: server `~/gpt2_mlu_10step_grouped.log`, `~/gpt2_cpu_10step_grouped.log` (not redistributed here).

### Still open

- Strict per-step acceptance against the frozen A100 reference (1e-5) requires the original
  InfiniTrain-Test@5a0f27a5 data asset; GitHub was unreachable from the server during this run.
- Device GEMM (CNNL) and BF16 backward remain as before.
