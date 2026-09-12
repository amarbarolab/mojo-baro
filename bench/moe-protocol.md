# MoE engine wiring protocol

This protocol records W0-W4 predictions before each step is built. Each step
gets its own preregistration commit and a result section after its gate.

## W0: model profile

### Question

Can the existing qwen35 engine move its scattered model constants into a
build-selected profile while preserving the default qwen35 behavior and
rejecting the megakernel for qwen35moe? Inputs, compiler, pack, prompt set,
and default runtime behavior remain fixed.

### Treatment

Add `serve/model_qwen35.mojo` and `serve/model_qwen35moe.mojo`, select with
`BARO_MODEL` at build time, and route registry, attention, and SSM dimensions
through the selected profile. No kernel arithmetic or default qwen35 model
weights change.

### Method

Build the default engine and the qwen35moe profile in the same lane. Run the
existing `./run-tests.sh`, the 20-prompt `bench/force-ab.sh` teacher-forced
gate between a main-built reference and the W0 build, and
`.work/kernel-census --check`. Record binary hashes, prompt agreement, census
status, and compile results. No speed claim is made in W0.

### Registered prediction

- Default qwen35: 20/20 prompts pass the teacher-forced A/B gate, with every
  prompt at 64/64, and `./run-tests.sh` exits 0.
- qwen35moe: profile compilation exits 0, with H=2048, QF=8192, KV=512,
  N_LAYERS=40, N_SSM=30, and N_ATT=10 visible in the build receipt.
- `BARO_MEGA=1` under qwen35moe is rejected with the registered clear error.
- `kernel-census --check` exits 0.

Confidence ordering: default qwen35 identity, qwen35moe compile, census,
then megakernel refusal.

### Scoring

W0 passes only if every listed gate passes. Any compile failure, A/B void,
teacher-forced mismatch, census failure, or silent megakernel acceptance fails
W0. No partial pass is reported as done.

### Failure meanings

- Default identity failure means profile routing changed qwen35 behavior.
- qwen35moe compile failure means the profile interface is incomplete or
  incompatible with current Mojo.
- Census failure means reachability or generated kernel documentation is stale.
- Megakernel acceptance means the safety refusal is not enforced.

### Outputs

Durable outputs are this protocol, the W0 report in
`exchange/lane-MOE-report.md`, and gate receipts under `.work/moe-w0/`.
No output is written to `/tmp`.

### Result

W0 passed on 2026-09-12. Preregistration commit: `f90e351`. The final code
commit is recorded in the lane report. Default engine build and qwen35moe
build both exited 0. The profile probe printed H 2048, QF 8192, KV 512,
N_LAYERS 40, N_SSM 30, N_ATT 10, and MEGA_ALLOWED False. The final
`./run-tests.sh` gate exited 0. Final `bench/force-ab.sh` used distinct
binary hashes and passed 20/20 prompts, 64/64 each, min 100.0%, mean 100.0%,
void none. The qwen35moe runtime refusal gate exited 1 as required and
reported `BARO_MEGA=1 is not supported by the qwen35moe model profile`.
`kernel-census --check` passed inside `run-tests.sh`.

Operational deviation: the first test attempt lacked the lane-local q4 pack
and failed before tests; a symlink to the existing main q4 pack was added in
`.work`, then the unchanged test gate was rerun successfully. The first
direct build also failed because it bypassed gpu-wait; all GPU builds and
runtime gates after that were run through gpu-wait.

## W1: qwen35moe pack

### Question

Can the qwen35moe GGUF be packed into the engine layout without changing
tensor values beyond the registered quantization bounds and while remaining
at or below 21.5 GB?

### Treatment

Add `--arch qwen35moe` to `tools/engine-pack.py`. Copy Q8_0 tensors into the
engine q8 layout, copy Q4_K expert blocks raw, requantise only
`output.weight` from Q6_K to q8, and copy F32 tensors unchanged. Fix and
document tensor index order. Source is
`~/Models/RegesCore-1.0-35/RegesCore-1.0-35B-UD-Q4_K_S-BARO.gguf`.

### Method

Run the packer once into `.work/moe-w1/pack`, then compare every packed tensor
after dequantisation with gguf-py's source dequantisation. Q8_0 and Q4_K
copies must be exact at the source block level. The Q6_K head must satisfy
the q8 rounding bound. Record source and pack byte counts, tensor counts, and
any excluded tensors. Outputs remain under `.work/moe-w1/`.

### Registered prediction

The pack completes with every source tensor represented, no excluded expert
tensors, exact Q8_0 and Q4_K block copies, Q6_K head error within q8 rounding,
and total pack size no greater than 21.5 GB. Confidence ordering: tensor
coverage, exact raw-copy checks, Q6_K bound, then size.

### Scoring

W1 passes only if all tensors are covered, all exact-copy checks pass, the
Q6_K bound passes, and pack size is at most 21.5 GB. Any missing tensor,
wrong index order, failed comparison, or size overage fails W1.

### Failure meanings

- Missing tensors mean the architecture inventory or pack order is incomplete.
- Raw-copy mismatch means the source offsets or block representation changed.
- Q6_K bound failure means the head requantisation is wrong or too lossy.
- Size overage means the q4 expert representation is not being retained.

### Outputs

Durable outputs are the pack, comparison receipt, this protocol, and the lane
report. No output is written to `/tmp`.

### Result

W1 passed on 2026-09-12. Packer output contains 733/733 tensors at
21,005,191,680 bytes (19.56 GiB). Raw-copy verification passed 732/732
non-head tensors and the Q6_K output head had 0 values over the registered
bound. The final `./run-tests.sh` gate exited 0. The final teacher-forced A/B
passed 20/20 prompts at 64/64, min 100.0%, mean 100.0%, void none. Arm hashes
were `38478b34aa4aaf4d` and `a81f2c583ae876e5`.

Operational deviation: W1 reused the W0 engine binary because W1 changes
only the packer and pack output. The engine regression was rerun unchanged.

## W3: host wiring, non-mega decode

### Question

Can the qwen35moe engine load the raw expert pack by named tensor semantics,
execute one m=1 MoE block with both routed and shared experts, and serve a
teacher-forced decode through the existing Rust front?

### Preregistration

This W3 gate is frozen before any W3 source build. The loader lane owns
`serve/harness.mojo` and its loader module. This lane owns
`serve/window.mojo`, `serve/engine.mojo`, and the protocol and report.

Gate 1 requires the loader probe to resolve all 733 packed tensors by name,
with expert, layer, projection, row range, dtype, and byte offset matching
the W2 semantic map. One real layer-0-to-3 block must then reproduce the
reference hidden output with max relative error at most `5e-3`; the call must
include at least one routed expert and the shared expert before summation.

Gate 2 requires the qwen35moe non-mega m=1 engine to pass the existing GPU
test suite, teacher-forced agreement on all 20 `bench/mtp-prompts` prompts at
64/64 tokens against llama.cpp, and one Rust-front
`/v1/chat/completions` request with `BARO_PACK` set to the qwen35moe pack
returning a non-empty assistant answer. No prefill, batching, MTP window, or
performance threshold is part of W3.

### Result

Gate 1 passed on 2026-09-12 using the loader commits integrated unchanged
from `lane-MOE-LOADER` and the real `.work/moe-w1/pack`. The gate binary was
built with `-D BARO_MODEL=qwen35moe`; `load_pack` loaded the 21,005,191,680
byte blob, and `parse_moe_index` plus `resolve_expert` selected every weight
by tensor name. Router, routed Q4_K gate/up/down, shared Q8_0 gate/up/down,
and the summed output all read from `Pack.wbuf`.

| layer | ids | router max_rel | routed max_rel | shared max_rel | summed y max_rel |
|---:|---:|---:|---:|---:|---:|
| 0 | 8/8 exact | 1.935e-7 | 8.789e-8 | 1.303e-4 | 1.333e-4 |
| 1 | 8/8 exact | 2.345e-7 | 1.345e-7 | 1.836e-7 | 1.663e-7 |
| 2 | 8/8 exact | 3.065e-7 | 1.234e-7 | 1.104e-7 | 1.465e-7 |
| 3 | 8/8 exact | 3.234e-7 | 1.483e-6 | 2.000e-7 | 1.598e-6 |

All four layers pass the frozen `5e-3` bound, and each call includes routed
and shared experts before summation. Gate 1: PASS. Receipt:
`.work/moe-w3/gate1.txt`.
Implementation commit: `142d2c9`.

## W2: Q4_K expert kernels

### Question

Can the routed and shared expert GEMVs consume raw ggml Q4_K blocks on gfx1100
and match the MoE oracle on real blk.0 and one attention-layer weights while
keeping q4 dequantisation within the preregistered performance band?

### Treatment

Add `amar_moe_gate_up_q4k` and `amar_moe_down_q4k` with the existing bf16 MoE
interfaces and fused Q4_K dequantisation. Expert tensors remain raw Q4_K on
the GPU. Extend `test_moe_block` to exercise the q4 path.

### Method

Use `tools/moe-ref.py --gguf` on real blk.0 and one full-attention block as the
numeric reference. Gate expert ids exactly and outputs within 5e-3 of the
oracle after the established bf16 intermediate. Run all GPU tests and timing
through gpu-wait. Timing uses rotating disjoint expert sets whose aggregate
working set exceeds the 96 MB Infinity Cache. Record the full timing spread,
clock and declared VRAM in `.work/moe-w2/`.

### Registered prediction

Both real-weight cases produce exact 8/8 routed expert ids and output error at
or below 5e-3. The q4 routed and shared calls compile and pass the extended
block test. Rotating-cache timing is 55 to 100 us per token per layer, with
the q4 path below the existing 92 to 102 us bf16 feasibility range.

### Scoring

W2 passes only with exact ids, max output error at most 5e-3 for both real
weight cases, an extended block test exit 0, and a reported rotating-cache
timing. A failed parity case or a second failed gate attempt closes W2.

### Failure meanings

- ID mismatch means router or expert-index ordering is wrong.
- Output error over 5e-3 means Q4_K dequantisation or accumulation is wrong.
- Test failure means the host launch interface is incomplete.
- Timing above the registered range means dequant ALU cost erased the byte
  reduction and the kernel does not carry the expected speed.

### Outputs

Durable outputs are the kernel test receipt, parity receipt, timing receipt,
this protocol, and the lane report. No output is written to `/tmp`.

### Result

W2 passed on 2026-09-12 against preregistration `3bd08d6`. The raw Q4_K
decoder vector was exact on the real GGUF block format. Real layer 0 and
layer 3 cases both selected the exact 8/8 expert ids and stayed below the
5e-3 output bound. Layer 0 q4 routed and q4 y max relative errors were
`8.789e-8` and `1.333e-4`; layer 3 values were `1.483e-6` and `1.598e-6`.
The extended `test_moe_block` exited 0, and `./run-tests.sh` exited 0.

The rotating-cache timing receipt used eight disjoint expert arms. It
measured bf16 `90.27 us/token/layer` and q4k `213.43 us/token/layer`, with
14.16 MB q4k expert traffic per token/layer. This falsifies the registered
55 to 100 us q4k performance prediction, but does not fail the correctness
gate because timing was registered as a measurement rather than a hard
threshold.

The inherited W0 engine A/B binaries were not a valid W2 regression target:
the qwen35moe candidate rejected its compiled mega setting, and with
`BARO_MEGA=0` it faulted with illegal instruction before producing agreement
lines. This is recorded in the lane report; the dedicated W2 kernel and full
GPU test gates remain passing.

Implementation commit: `b5293b9`.

## W3 Gate 2 fix 5: attention inner width

The single-token per-layer oracle localizes the first material divergence to
layer 3, the first full-attention layer. Sampled relative L2 error is 0.42% at
layer 2 output and 23.2% after layer 3 attention. Layer 3 projections remain
close to llama.cpp: sampled `Qcur_full`, `attn_pregate`, and gate values agree
within the expected accumulated quantization drift.

The engine then truncates an impossible shape. RegesCore attention produces
`NQH * HD = 4096` values for both the attention result and its gate, while the
decode path allocates and multiplies only `H = 2048`, then invokes the output
projection as `H x H`. llama.cpp reports `blk.3.attn_output.weight` as
`4096 x 2048`.

Registered prediction: sizing the gate and gated attention buffers to
`NQH * HD`, multiplying all 4096 elements, and invoking the output projection
with K=4096 makes layer 3 the same low-error continuation seen through layer 2.
The full 20-prompt teacher-forced mean will exceed 45/64. Before scoring, an
absurd attention bypass must move the single-token output, proving this path is
live. The fix is accepted only after a committed-tree rebuild.

## W3 Gate 2 fix 6: YaRN ramp ordering

Fix 5 moved p01 from 32/64 to 53/64. The 13-token p01 oracle then localized
the first context-dependent divergence to layer 3 RoPE. Sampled pre-RoPE Q
and K values agree within 1.8% to 4.5%, while post-RoPE sampled relative error
reaches 1.50. This confirms the YaRN ramp inversion already recorded for phase
3 is an active gate 2 blocker, so that correction moves ahead of gate closure.

Registered prediction: matching llama.cpp's ramp direction improves p01 above
53/64 and makes the 20-prompt mean exceed 45/64. If the mean does not exceed
45/64 after this second distinct fix, the W3 falsifier fires and iteration
stops with the first oracle divergence reported. The correction is scored only
from a committed-tree rebuild with distinct arm hashes.

## W3 Gate 2 amendment: qwen35moe m=1 prefill replay

The adopted W3 plan explicitly excludes m>1 MoE prefill: “Prefill runs the
same sequence per row (m>1 MoE is W5); correctness first.” Gate 2 therefore
forces prefill replay at m=1 for the `qwen35moe` profile only. The dense path
keeps its existing batched prefill unchanged; this is proven by the required
20/20 `bench/force-ab.sh` regression against a main-built dense engine.

Expected cost is accepted in advance: a 59-token prompt becomes 58 sequential
prefill steps. W4 must label the resulting qwen35moe prefill measurement as a
deliberately slow correctness path and must not compare it with llama.cpp's
batched prefill as though it were the real MoE prefill path.

Pass condition is unchanged: qwen35moe non-mega m=1 engine passes the GPU test
suite on a clean fixture, reaches 20/20 prompts at 64/64 teacher-forced
agreement against llama.cpp, and serves one non-empty Rust-front
`/v1/chat/completions` answer with `BARO_PACK` set to the MoE pack. Falsifier:
if the nine long prompts leave 0/64 but do not reach 64/64 after replay is
forced, m>1 was not the only remaining defect; stop and report without further
iteration.

## W3 round: f32 router input

Frozen before the change is written.

CLAIM. The MoE router's input passes through bf16 and loses precision the
routing decision is sensitive to. `rmsc_k` writes the post-attention norm as
bf16 into `curb_d`; `moe_ffn` then widens that bf16 back to f32 (`X2` from
`p_h_d`) and feeds the router. The widen cannot restore what the cast
dropped. bf16 carries 8 mantissa bits, 2^-8 = 0.39% relative, and the
measured per-layer floor against llama.cpp is 0.44%.

Routing is a DISCRETE top-8-of-256 choice, so unlike a GEMM it does not
average the error away: a perturbation near a boundary flips an expert and
changes that token's output substantially. This is the one mechanism that
plausibly converts a 0.4% activation error into whole-token divergence.

CHANGE. Compute the norm a second time in f32 (`rms_h2`, the existing
amar_rmsnorm f32-in/f32-out) straight from the f32 residual `Xm`, into
scratch, and feed the router from that. The expert GEMMs keep reading the
bf16 `CurBm`, so the extra cost is one norm pass and one H-wide f32 buffer
per layer, not a precision change to the matmuls.

PREDICTION. Teacher-forced agreement over the 20-prompt set rises above the
53.20 measured at `dcdf4a2`. A rise of even 1 token per prompt is meaningful
here: the dense path's own ceiling on a quant-matched arm is 51.90, so this
would put MoE clearly above the engine's demonstrated ceiling.

FALSIFIER. If the mean does not move (within +-0.5), bf16 on the ROUTER is
not the limiter, and the change is reverted rather than kept "because it is
more correct". A no-op that costs a norm pass per layer is a regression.

PASS CONDITIONS. Measured on the resident gate (`bench/moe-gate-resident.sh`,
one process, same 20 prompts, same llama reference ids), with the engine sha
printed by the run. The dense path must be unaffected: the change is inside
`moe_ffn`, which only the MoE profile reaches, and `bench/force-ab.sh` must
still be 20/20 at 64/64 against a main-built dense engine.

NOT IN THIS ROUND. Widening the expert GEMMs, the SSM path, or attention to
f32. Those are a separate and much larger question about the engine's whole
accuracy/speed tradeoff (PROTOCOL-RULES P14 records the engine-wide 0.44%
floor); this round tests one mechanism on one path.
