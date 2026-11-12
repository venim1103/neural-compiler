# Project direction: LLM-as-compiler + native execution bridge (2026-11-11)

Goal as stated by the user:
> The LLM, within its own weights and as efficiently as possible, compiles things it can then run
> (maybe directly binary, or a middle level that is then compiled to full binary). A "bridge"
> connects that output directly to the CPU for execution, and the result feeds back into the model's
> inference. Fine-tuning is allowed.

This document answers **what the best approach is**. It draws on:
- four experiments run for this review on the target model (Qwen3.5-4B, local RTX A3000 12 GB);
- three verified literature sweeps;
- an independent critique of a first draft, folded in below.

The second-round whitepaper review is in [WHITEPAPER_REVIEW_ROUND2.md](WHITEPAPER_REVIEW_ROUND2.md).

---

## 0. Decision in one paragraph

Make the **LLM the compiler from intent to program**, and make the **bridge the compiler from program
to machine code**.

- **The model** writes the *most compact correct program* it can.
- **The bridge** is a small trusted host component. It lowers, validates and sandboxes the program,
  runs it on the CPU, and prefills the result into the **same live KV/recurrent cache**. Decoding then
  resumes.
- **Fine-tuning** (SFT, then RL with an execution reward) teaches Qwen3.5-4B when to compute, how to
  write programs for this bridge, and how to use the results.

**Start with Python**, the most compact form and the most accurate zero-shot. **Add C** for compute-heavy
work.

**Research track — the user's "middle level":** a compact, typed surface language with shared
intrinsics (bignum, math), which the bridge compiles to Wasm or native code in milliseconds. Compare it
against direct emission of a Wasm dialect.

**Raw binary is not the primary path.** Its structural costs (tokens, time, safety, portability) hold
whatever the training. Its accuracy after fine-tuning is **untested**; §3 says what evidence would
change this.

---

## 1. What "compile within its own weights" can mean

| Meaning | Example | Evidence | Verdict |
|---|---|---|---|
| (a) A compiler *program* runs inside the weights | Qwenx86 `qcc`; the whitepaper's "Tier 1" | Qwenx86's own demo: compiling and running a C program that prints 6*7 took **169,293 machine tokens, 71.2 s**. Host: `tcc` compiles in 1.6 ms; wasmtime compiles a module in ≈0.7 ms (E2). | ❌ 10⁴–10⁵× slower; no upside when the CPU is available |
| (b) **The LLM *is* the compiler** from intent to an executable program | Tool-integrated reasoning (PAL, ToRA, ReTool, rStar2) | Real interpreter vs LM "executing" its own code: GSM8K 72.0 vs 23.2 (PAL, 2211.10435). E3: 6/6 answers zero-shot through our bridge. | ✅ This is where "in-weights" adds value |
| (c) A program is baked *into* weights | Percepta "first Futamura projection" | Only useful when execution happens inside the network | ➖ Not needed for CPU execution |
| (d) Hidden states → machine code with fewer or no autoregressive steps (parallel/blockwise emission) | — | Untested; no evidence either way. Multi-token prediction (Qwen3.5 ships one MTP layer) is the proven way to cut sequential steps. | ➖ Not a starting point |

So the question becomes: **what form should the model emit, and how much of the lowering should the
bridge do?**

---

## 2. Evidence

### E1 — Token cost of each representation (12 tasks, Qwen3.5 tokenizer)

Script: [experiments/exp_tokens.py](experiments/exp_tokens.py). The 12 tasks are written as idiomatic
Python, plain-loop Python and freestanding C.

- **Executed and cross-checked (0 mismatches):** both Python versions, the gcc-native C, and both
  clang wasm builds.
- **Assembly and machine-code sizes:** taken from **unlinked** gcc objects of the same C
  (`.text + .rodata + .data`). They are approximate sizes, not runnable artifacts.

| Representation the model would emit | Tokens | × idiomatic Python | × C program |
|---|---:|---:|---:|
| Python, idiomatic (stdlib, bignum) | 530 | **1.00** | 0.32 |
| Python, plain loops | 1,036 | 1.95 | 0.62 |
| C, full program (`main` + `printf`) | 1,673 | 3.16 | 1.00 |
| x86-64 machine code, raw bytes (1 token/byte, approx.) | 1,288 | 2.43 | 0.77 |
| WAT with a 1-token-per-opcode vocabulary (estimate) | 1,844 | 3.48 | 1.10 |
| wasm binary, raw bytes | 2,246 | 4.24 | 1.34 |
| x86-64 machine code as hex (approx.) | 2,482 | 4.68 | 1.48 |
| x86-64 assembly text (gcc -O2) | 3,676 | 6.94 | 2.20 |
| WAT text (clang -Oz) | 6,281 | 11.85 | 3.75 |

How to read the table:
- **Compiler outputs are reference points, not minimum-token programs.** In E3 the model's own WAT and
  asm attempts were longer still.
- **Idiomatic Python's advantage comes largely from its library primitives** (`math.comb`, `pow`,
  bignum), which the freestanding forms lack.
- So token cost is driven mostly by **abstraction level and available intrinsics**, not by "binary vs
  text". It also implies that a low-level IR given the *same* intrinsics would shrink. That is the
  research track below.

### E2 — Cost of the bridge itself (medians over the 12 tasks)

Script: [experiments/exp_bridge.py](experiments/exp_bridge.py). The jailed worker is in
[experiments/sandbox.py](experiments/sandbox.py); it is a prototype, see its docstring.

| Bridge step | Cost |
|---|---|
| wasmtime compile (Cranelift) from WAT / from binary | 0.75 ms / 0.64 ms |
| wasmtime instantiate / instantiate+run (with fuel) | 12 µs / 54 µs (max 4.3 ms) |
| Warm Python worker, unjailed / inside bubblewrap (no net, read-only FS) | 0.21 ms / **0.07 ms** per exec (trivial program) |
| Cold `python -c` / cold bubblewrap spawn | 10 ms / 16 ms |
| C: `tcc` compile-only / `tcc -run` | 1.6 ms / 1.7 ms |
| C: clang C→wasm32 -O2 / `gcc -O2` | **45.8 ms** / 31.4 ms |
| Loop-heavy task (double palindromes): Python worker / wasm / native exec | 30–75 ms / 4.3 ms / 1.5 ms |

### E3 — The model itself (Qwen3.5-4B, bf16, greedy, thinking off, zero-shot)

Script: [experiments/exp_loop.py](experiments/exp_loop.py). Every program was executed: bubblewrap,
wasmtime with fuel, or the unicorn emulator for raw bytes. C was re-checked with the production
toolchains and with ASan/UBSan.

| Target | Correct | Failure modes | Mean tokens |
|---|---:|---|---:|
| Python | **10/12** | 2 wrong (one printed the count, not the sum) | **70** |
| C | **10/12** gcc · 9/12 clang C99 / tcc · **8/12 strict** | 1 int overflow; 1 truncated; 1 relies on a GCC nested function; 1 out-of-bounds write (ASan) | 257 |
| WAT | 0/12 | Invented ops (`i32.sqrt`); i32/i64 stack-type errors; 10/12 looped on `(local $tempN …)` until the 900-token cap | 852 |
| x86-64 asm (GAS) | 0/12 | NASM directives in GAS; operand-size mismatches; undefined symbols | 653 |
| Raw x86-64 hex | 0/12 | 7 not even valid hex; 5 crashed on unmapped memory | 600 (all at cap) |

This is one greedy sample, n=12, zero-shot. It shows **today's starting point**, not what each
representation could reach after training.

**In-decode-loop bridge, Part C (6 tasks, code use requested by the system prompt).** The model
writes a program, generation pauses, a warm jailed worker runs it, the output is prefilled into the
same cache, and decoding resumes.
- **6/6 final answers correct; 5/6 programs correct.** The LCG program sampled x0..x50 instead of
  x1..x51 and got the right median by luck.
- Execution totalled **0.13 %** of program-generation time (180 ms vs 138.7 s across the 6 tasks).
- This is a smoke test of the mechanism. It says nothing about autonomous tool selection.
- It used an in-band ```output fence, not Qwen3.5's native `<tool_response>` turn.

**E3b — return-path cost.** Script: [experiments/exp_prefill.py](experiments/exp_prefill.py). Kernels
are warm, and only last-position logits are computed, as in serving:

| Context | Decode step | Prefill 16–64 result tokens into live cache | Re-prefill whole context, no prefix cache |
|---:|---:|---:|---:|
| 256 | 63 ms | 78–81 ms | 157–179 ms |
| 1k | 66 ms | 82–84 ms | 440–449 ms |
| 4k | 63 ms | 99–123 ms | **1,489–1,514 ms** |

What the timings mean:
- Absolute speeds are slow here: HF eager, laptop GPU under WSL, and decode varied from 63 to
  137 ms/token across runs. The first prefill of a new shape also paid ≈13 s of one-off Triton
  autotuning; production engines must pre-warm or capture graphs.
- **Host-side bridge work** for small programs with warm executors is 0.05–2 ms on the wasm, tcc and
  warm-Python paths (clang→wasm adds ≈46 ms). That is less than one decode step on current GPUs: even
  an H100 must read ≈8.4 GB of bf16 weights per step, ≥2.5 ms at batch 1.
- **Returning the result** costs ≈1.2–2 decode steps of prefill.
- **Prefix caching changes the comparison.** A stateless request that hits a prefix cache does not
  re-prefill everything. Hybrid caches can resume from saved recurrent-state checkpoints; see the
  literature below.

### Literature (verified on primary sources)

**Direct low-level emission is weak unaided:**
- C→x86, 33 % IO-correct (2108.07639).
- Claude-3.5 direct-to-assembly success@1 28–35 % (2511.04132). Most of that paper's *error
  diagnostics* are assembler-stage; that counts error instances, not failed programs.
- Base 1.5–3B coders score ≈0 % on assembly translation (2506.14606).

**It becomes strong only with heavy scaffolding.** These are different tasks from ours:
- About 1M compiler-made pairs: 93–99 % on easy -O0 asm *translation*, but 15–50 % at -O2.
- RL with an execution reward: SuperCoder, 61→95 %, *optimizing* existing asm (2505.11480).
- Decomposition plus ≤5 repair rounds: LEGO-Compiler (2505.20356).

No paper evaluates LLMs *emitting* WAT/Wasm or bytecode.

**Execute-and-feed-back works at small scale only after training:**
- An untrained 4B made 0.07 tool calls and *lost* accuracy (Trice, 2605.06326).
- PAL-prompted CodeLlama-7B scored 16.6 on MATH, vs 44.6 after tool SFT (ToRA).
- The converged recipe is a small SFT on real trajectories, then RL with an outcome reward and the
  tool output masked from the loss (ReTool 2504.11536, ToRL 2503.23383, SimpleTIR 2509.02479,
  rStar2-Agent 2508.20722).

**Serving:**
- Treating a tool call as a new request with recomputation costs 37–40 % of forward time (InferCept
  2402.01869).
- Qwen3.5's 24 Gated-DeltaNet layers hold recurrent state that cannot be *truncated* like KV. It can
  be checkpointed or restored at exact boundaries: SGLang's `extra_buffer` mode, and vLLM's hybrid
  prefix caching (marked experimental).
- So there are two candidate designs: **live pause/resume**, or **prefix-cached resubmission**.
  Test both early.

**Constrained decoding** cuts syntax errors by 96 % (SynCode) and compile errors by 52–75 %
(type-constrained, 2504.09246), at µs-per-token mask cost (XGrammar).

---

## 3. Why raw binary is not the primary path (and what would change that)

1. **Accuracy (zero-shot evidence only).** 0/12 here; ≈0 % for base models in the literature. Errors
   concentrate exactly where binary is hardest: ModRM/REX encodings, rel32 offsets, ABI, stack and
   addressing. Its potential after fine-tuning is **untested**.
2. **No token saving.** Even compiler-written machine code costs 2.4× idiomatic Python (E1). Most of
   that gap is missing intrinsics, which a host library could supply to *any* representation.
3. **No time saving.** The step it skips costs 0.6–1.6 ms (wasmtime compile, `tcc`), less than one
   decode token.
4. **Unsafe by construction.** Arbitrary machine code can issue any syscall. It needs an OS jail around
   everything, or a NaCl-style instruction validator. Wasm provides software fault isolation with a
   simple, fast validator.
5. **Not portable.** It is ISA-specific, and so is its training data.

**What would change the verdict:** a *matched* comparison, with equal fine-tuning budget, constrained
decoding and repair rounds, in which binary or IR emission reaches parity in accuracy at a **lower wall
time per correct answer** than the Python/C tiers. Reasons 2–5 make that unlikely, but it is a testable
claim, and P4 below is where it gets tested.

---

## 4. Recommended architecture

```
 GPU: inference engine (Qwen3.5-4B, fine-tuned)        Host: bridge (separate jailed process)
┌──────────────────────────────────────────────┐ ids  ┌────────────────────────────────────────────┐
│ … <tool_call>  (single token 248058)         │─────►│ Stream monitor (per sequence)              │
│ <function=run><parameter=code> program …     │8 B/  │  · optional constrained-decoding mask      │
│ </tool_call>   (248059) → pause THIS sequence│token │  · streams/parses the program as it arrives│
│                                              │      │ Pre-warmed executor pool                   │
│ prefill turn boundary + <tool_response>…     │◄─────│  · python: CPython in bwrap/nsjail+seccomp │
│ into the SAME live KV + GDN state → resume   │ ids  │  · c: tcc / clang→wasm, compiled IN the jail│
│ (other sequences in the batch keep decoding) │      │  · wasm/WAT: wasmtime+Cranelift, fuel/epoch│
└──────────────────────────────────────────────┘      │ Result formatter: truncate, localize errors│
                                                      └────────────────────────────────────────────┘
```

| Concern | Choice | Why |
|---|---|---|
| Protocol | Qwen3.5's native `<tool_call>…</tool_call>`, with the response as a proper chat-template turn (`<\|im_end\|>`, user `<tool_response>…</tool_response>`, new assistant turn) | Delimiters are single tokens (248058/248059/248066/248067). The model already knows the format. Detection is a token-ID compare. |
| Default language | Python with a curated stdlib (math, fractions, itertools, bignum) | 1.0× tokens; 10/12 zero-shot |
| Fast path | C → `tcc` (1.6 ms) or clang→wasm (≈46 ms), compiled inside the jail | 7–32× faster than CPython on the loop-heavy tasks in E2 (≈1–3× on tiny ones). C is 8–10/12 zero-shot, depending on toolchain strictness. |
| Research path (the "middle level") | **(R1)** a compact *typed* surface language (e.g. a statically typed Python subset or small AST/DSL) with host intrinsics, compiled by the bridge to Wasm/native. **(R2)** direct "LLM-WAT" emission with incremental-validator-constrained decoding. Both lower via Cranelift. | R1 aims at Python-like brevity *and* native speed and safety. R2 is valid by construction but token-heavy. Candidate R1 compilers (LPython, Codon, Numba, mypyc) were **not evaluated here**. |
| Isolation | Out-of-process jail (namespaces + seccomp + rlimits/cgroups, no network, read-only FS) *and* Wasm SFI where used. Caps on size, time, memory and output. **Compile inside the jail too:** C `#include "/any/host/file"` and asm `.incbin` read host files at compile time and leak them through error messages. | Every sandbox class has had escapes. LLM-app code-exec CVEs are common (LangChain, llama_index and smolagents scored CVSS 9.8–10). |
| Deadlines | Fork-per-request (or per-session child) with an outer wall-clock deadline that kills and reaps. Control channel unreachable from guest code. | The prototype's warm worker bounds only the first byte; guest code can stall or forge replies (critique, reproduced) |
| State | Per-session namespaces (REPL semantics) with structured statuses (`ok` / `error` / `timeout`) | Enables "toolmaking": define once, call cheaply later. The prototype is stateless and reports exceptions as `ok`. |
| Return path | Text tokens prefilled into the live cache, or a prefix-cache hit | ≈1–2 decode steps; exact. Embedding injection needs a trained adapter and buys nothing for small outputs. |
| GPU↔CPU link | None special: sampled IDs already reach the host every step | The whitepaper's pinned-MMIO bridge saves µs against ms-scale costs |
| Speed levers, in priority order | (1) fewer tokens: high-level language + intrinsics; (2) fewer failed attempts: fine-tuning, constrained decoding, localized errors; (3) faster decode: Qwen3.5's MTP head for speculative decoding, quantization; (4) live resume or prefix-cache hits; (5) warm executors | Follows from E1–E3 |

---

## 5. Fine-tuning plan

| Stage | What | Notes |
|---|---|---|
| Data | Problems with checkable answers (math, number theory, combinatorics, algorithms, strings), held out **by task family**, plus text-only data (10–30 %). Randomized instances per family. | Avoid memorizable classics. Randomization catches "right for the wrong reason" (E3 Part C's LCG). |
| SFT (cold start) | 3k–16k **real, executed** trajectories in the native tool format. Teacher: a larger Qwen3.5 or rejection sampling from the 4B, run through **the same bridge**. | Real trajectories beat stitched ones: AIME24 33.2 vs 4.4 (2510.11701) |
| RL | GRPO with a binary outcome reward; tool-output tokens masked from the loss; drop void turns; 5–10 call cap; same bridge, formatting and timeouts as serving | ReTool, ToRL, SimpleTIR, rStar2 |
| Research track (R1/R2) | R1: SFT on (task → typed-DSL) programs, from translated Python solutions verified by execution. R2: SFT on (task/C → LLM-WAT) pairs from clang -O1 → wasm2wat → normalizer. Then RL. | The literature needed ~10⁶ pairs for asm; budget accordingly |
| Hardware | SFT: LoRA/QLoRA of the 4B is likely to fit on 12 GB at ≤2k tokens (to verify). Fast iteration on Qwen3.5-0.8B/2B. RL: rent ≥24–80 GB, since local HF decode (63–137 ms/token across our runs) is too slow for rollouts. | Use vLLM/SGLang for rollouts; Qwen3.5 recipes exist |

---

## 6. Roadmap with go/no-go gates

**Primary metric everywhere:** wall time (or GPU-seconds) **per correct answer**, with confidence
intervals, on held-out task families.

**Baselines, always reported:**
- the no-tool model;
- the zero-shot Python-tool model;
- the current best tier.

| Phase | Deliverable | Gate |
|---|---|---|
| P0 (≈1–2 wk) | Bridge MVP in the repo, ported from `experiments/`: native tool protocol with correct turn boundaries; fork-per-request executors with real deadlines and structured statuses; eval harness (~200 tasks, randomized instances). **Serving spike:** live pause/resume vs prefix-cached resubmission on Qwen3.5's hybrid state. | Host-side bridge work ≤1 decode step at p95. Result return ≤2 decode steps. Both serving designs measured. |
| P1 (≈1 wk) | Hardening: nsjail/bwrap + seccomp + cgroups, compile-in-jail, caps, watchdog. Red-team suite: fork/memory bombs, infinite loops, `#include`/`.incbin` exfiltration, `/proc`, huge output, network, forged replies. | 100 % contained |
| P2 (≈2 wk) | SFT cold start | Time per correct answer and accuracy beat both baselines (CI-separated); no text regression beyond noise; recovery from tool errors demonstrated |
| P3 (2–4 wk, bigger GPU) | RL with execution reward | Time per correct answer improves on P2 (token count may rise if accuracy pays for it) |
| P4 (research, after P1) | R1 typed DSL and/or R2 LLM-WAT, with constrained decoding and SFT/RL | Beats the Python/C tiers on time per correct answer for at least one task class at equal accuracy; **otherwise stop** |
| P5 | vLLM/SGLang production integration (chosen serving design, MTP speculation, batching) | p95 tool-call overhead ≤2 decode steps under load |

---

## 7. What happens to the current repo

- **The NeuroVM whitepaper.** In-weights *execution* is not needed for this goal, so archive it as
  background, marked as superseded. The parts worth keeping are §6.1 (the IR question, re-framed) and
  §7.2 (the bridge, redone safely).
- **The scaffold.** `snap_bipolar` and `gdn_exact_*` are not used by this direction. Proposed layout:
  `src/neural_compiler/bridge/` (protocol, monitor, sandbox, `executors/{python,c,wasm}`) and
  `src/neural_compiler/eval/`. The prototypes in `experiments/` are the starting point; they are
  **not hardened**.
- **New dependencies:** now part of the devcontainer (see
  [.devcontainer/README.md](../../.devcontainer/README.md#compile-and-execute-toolchain)):
  - `wasmtime` and `unicorn` in all locks;
  - `bubblewrap`, `clang`, `lld`, `tcc` and `wabt` via apt;
  - `flash-linear-attention` + `fla-core` in the CUDA lock, for Qwen3.5 speed. HF falls back to slow
    reference kernels without them.
  - `nsjail` is not packaged for Ubuntu 24.04; add it in P1 if chosen over bubblewrap.

---

## Appendix — reproducing the experiments

All dependencies are part of the devcontainer; see
[.devcontainer/README.md](../../.devcontainer/README.md#compile-and-execute-toolchain). The GPU
experiments need a CUDA profile, which provides the fla kernels.

```bash
cd docs/review/experiments
python exp_tokens.py    # E1 (+ writes exp_tokens_results.json used by E3)
python exp_bridge.py    # E2
python exp_loop.py      # E3 (CUDA profile; downloads Qwen/Qwen3.5-4B, ~25 min on an RTX A3000)
python exp_prefill.py   # E3b (CUDA profile)
```

Notes:
- Raw results are in `experiments/exp_*_results.json`. E3 stores every generated program with its
  execution status.
- `exp_loop.py` has since been patched for a failure-path bug (a duplicate token feed when the budget
  runs out), which never triggered in the recorded run.
- E3b was re-run with `logits_to_keep=1`. The first version computed full-vocabulary logits for every
  prefix position, which inflated all timings.

## Implementation audit (2026-11-12)

The architecture above is a **target**, not a description of a completed product. The revised
whitepaper and README previously overstated the implemented protocol, isolation, and latency.

### Verified issues and repairs

| Finding | Evidence | Repair |
|---|---|---|
| Python exceptions were reported as success | `raise ValueError(...)` returned `("ok", "ValueError: ...")` | Host-supervised process exit determines status; stdout is never a control reply |
| Warm-worker timeout covered only the first byte | A partial response took 301 ms despite a 50 ms timeout, then raised `JSONDecodeError` | Replace the guest-sharing worker with per-request execution; deadline covers all output and process exit; kill and reap on timeout |
| Compilation could read host files and was unbounded | C/asm invoked host gcc before entering bubblewrap | Compile in a writable private work directory inside the jail; compile and execution share one wall-clock budget; C uses strict C99 |
| Wasm/unicorn ran inside the supervisor | Fuel/instruction limits did not bound native runtime memory or compilation time | Separate jailed processes with an outer deadline and resource limits; Wasm linear memory and tables are bounded |
| Invalid hex was silently rewritten | `b82a000000c3xyz` was accepted as a program returning 42 | Reject non-hex text; permit whitespace only between bytes; require the emulator actually reaches the return sentinel |
| Experimental result handling assumed the old statuses | New resource/isolation failures could not be counted | E3 now records `output_limit`/`sandbox_error` and requires successful execution for program correctness |

The reusable Python API and CLI are in [execution.py](../../src/neural_compiler/bridge/execution.py)
and [cli.py](../../src/neural_compiler/cli.py). Regression coverage includes deadlines with partial
output/closed pipes, process reaping, output caps, explicit failures, host-file isolation, strict C99,
and Wasm fuel/memory/signature errors.

**Deliberate tradeoff:** cold per-request isolation replaces the unsafe warm Python worker.
The historical 0.07 ms measurement does **not** describe this executor. Recorded JSON results are
kept unchanged as historical evidence; E3 reruns use the new executors and last-position logits.
The E2 trusted-reference microbenchmarks are not a hardened-bridge latency gate.
On the audit host, 30 `print(6 * 7)` calls through the already-loaded Python API measured
**23.92 ms p50 / 25.38 ms p95**, including jail/interpreter startup. A partial-output timeout
returned `timeout` in 101.46 ms against a 100 ms deadline, instead of blocking for the guest's
whole response. These shared-host measurements exclude CLI/model startup and do not establish
an H100 or concurrent-serving SLO.

### Approach risks and the next development gates

1. **Keep Python first, but keep the conclusion provisional.** E1 compares handwritten programs
   with compiler output and unmatched libraries. Twelve fixed tasks and six prompted tool calls
   do not establish autonomous tool selection, held-out-family accuracy, or an advantage over
   the no-tool model. Use randomized instances, matched intrinsics/budgets, and both baselines.
2. **Finish containment before training or exposing a service.** Namespaces and rlimits alone
   are insufficient: seccomp, per-request cgroups/PID caps, an import policy, and an independent
   containment review remain prerequisites. A finite test suite cannot prove universal containment.
3. **Native protocol/cache-correct continuation now has a P0 implementation.** See the continuation
   below. A prefix-cache serving spike is still outstanding; do not assume live pause/resume wins.
4. **Measure the real objective.** Record full prompt-to-answer time, including isolation startup,
   compilation, result prefill, failed attempts, and repair turns; report p50/p95 and time per
   correct answer with uncertainty. Add warm pooling only after correctness and containment.
5. **Defer DSL/RL investment until these gates pass.** A typed DSL with arbitrary-precision host
   intrinsics is research, not an implemented low-latency compiler. Grammar/type validity is not
   semantic correctness.

### P0 continuation: native tool turns and live hybrid state

Implemented [protocol.py](../../src/neural_compiler/bridge/protocol.py) and
[session.py](../../src/neural_compiler/bridge/session.py):

- Token IDs are derived from the tokenizer and checked for single-token, distinct delimiters.
  Each sequence owns its own bounded monitor. Only one `run(code: str)` call is accepted at a
  time; malformed, nested, partial, and oversized calls fail before execution.
- Return turns are derived from the installed chat template, including assistant thinking
  boundaries. The real template includes an empty `<think>` block when thinking is disabled;
  the old whitepaper's handwritten transition omitted it.
- Results are JSON with status/stdout/stderr/returncode; angle brackets are escaped so guest
  output cannot become chat-control tokens. Response turns have a 2,048-token cap. Shortened
  output carries `truncated: true`; an envelope that cannot fit fails explicitly.
- Stop/EOS tokens remain pending and are prefilled once with the result. If a generation budget
  is exhausted, all sampled tokens are already cached and none are replayed.
- Offline tests exercise two serial calls on a real, tiny Qwen3.5 model with one linear-attention
  and one full-attention layer. Incremental logits match full-prefill reference logits within
  `atol=1e-6, rtol=1e-5`, with the same cache object retained. CPU checks use Torch reference
  kernels, not FLA/Triton; CUDA-kernel equivalence is not claimed.

The opt-in native Part C path is:

```bash
cd docs/review/experiments
python exp_loop.py --native
```

It uses the same supervised Python executor, permits five serial calls (including repairs),
and records structured protocol failures and end-to-end inference timings. It writes
`exp_native_results.json` separately from historical results. Tests include actual jailed
runtime-error recovery and a real locally cached Qwen tokenizer round trip; the latter skips
when absent and never downloads it. Importing the experiment no longer loads model weights.

**Not completed:** new 4B native accuracy/latency measurements, randomized held-out-family
evaluation with no-tool and Python-tool baselines, prefix-cached resubmission, continuous
batching, and P1 containment. Those remain the next gates before SFT/RL.

### 2026-11-12: bounded offline evaluation prerequisites

Implemented [the evaluation harness](../../src/neural_compiler/eval/harness.py) without
loading models, importing task data, or accepting a benchmark policy. Task identity/family,
prompt, and checker are separate; references are never passed to inference. The integer
checker requires a complete final answer on the last line, rather than crediting an earlier
matching integer. Other checker contracts can be supplied by callers.

The no-tool, Python-tool and caller-labelled current-best paths share prompts, checker
and resource budgets. Only tool availability differs for no-tool. "Current best" is a
comparison label, not a claim that a backend is best; the caller supplies the actual
already-loaded session factory and executor. No new C/DSL tier is selected here.

- Total generated tokens, turn/call/response tokens, serial calls, prompt/context size
  and elapsed time have explicit finite budgets. Limits do not reset after repair turns.
  Prompt overflow prevents prefill; result overflow prevents cache injection.
- Failed executions are retained with timing and status; runtime errors can be repaired.
  Missing isolation fails explicitly, rather than pretending it is a recoverable model error.
- End-to-end timing includes prompt prefill, decoding, failed attempts, execution and result
  injection. Callers must supply device synchronization. The model watchdog is cooperative
  at token/turn boundaries; the subprocess executor has its separate hard deadline.
- The cost ratio uses total elapsed time, including failures, divided by correct answers.
  Zero successes produce `seconds_per_correct: null` and `no_correct_answers`, not zero
  or a success-shaped fallback. Raw family/case/path results remain available.

**Finite routine ledger:** one initial evaluation/protocol check (33 cases passed), one
extended budget-edge check (21 evaluation cases passed), and one root gate (75 passed).
Ruff lint, scoped format check, whitespace check and Pylance harness diagnostics passed.
No checks failed; existing Torch JIT deprecation warnings remain visible. The shared tiny
CPU model/tokenizer fixtures were extracted without changing their reference kernels or
logit tolerances. Fixtures include three seeded arithmetic examples and actual jailed error
recovery; they are unit controls, not accepted task data or measured model accuracy.

No downloads, pretrained inference, GPU studies, dependencies or host privileges changed.
Next: exact-boundary hybrid checkpoint/resubmission correctness. Dataset/family/split
acceptance, matched statistical evaluation and serving-engine latency measurements remain
separately scoped; this harness alone does not satisfy those gates.

### 2026-11-12: exact-boundary CPU hybrid checkpoints

[LiveSession](../../src/neural_compiler/bridge/session.py) can now capture an exact
sampled-token boundary and fork independent sessions from it, without full re-prefill.
The snapshot includes full-attention KV, convolution history, recurrent state, logits,
token history and the pending sampled token. Restore clones the saved state; advancing
one branch does not mutate the source, sibling branches or the retained snapshot.

This is deliberately a **process-local CPU prerequisite**, not a vLLM/SGLang prefix-cache
integration or a 4B performance claim. It supports only non-offloaded `DynamicCache`
with standard dynamic/full-attention and linear-attention layer types. Unsupported cache
types, non-CPU/autograd tensors, inconsistent token boundaries and stale model weights/
buffers/configuration fail explicitly. Restore requires the same unchanged eval-mode model.
The default snapshot cap is 64 MiB of tensor storage, including logits, and is checked
before copying. The source, retained snapshot and each fork occupy separate memory;
this per-snapshot cap is not an aggregate server memory-management policy.

**Finite routine ledger and repair:** the first focused cache/protocol/evaluation check
ran 45 cases (44 passed, one failed). The ownership check found dictionary-valued
recurrent/conv state where the implementation and fixture initially expected lists.
The repair counts dictionary tensor storage, verifies all four state types are independently
cloned, and tests the precise storage cap. Revised focused check: 46 passed; final focused
checkpoint check: nine passed; root gate: 84 passed. Ruff lint, scoped format, whitespace
and Pylance session diagnostics passed. Existing Torch JIT warnings remain visible.

Tests compare serial native-call forks with live continuation and independent full-prefill
logits (`atol=1e-6, rtol=1e-5`), including stop/EOS/length boundaries, divergent sibling
responses and subsequent decoding without injection. Live and identically-fed restored
sessions also match exactly in the fixture. No tolerance was relaxed. No downloads,
pretrained inference, GPU runs, dependency changes or host security changes occurred.

Next: enforce matched case/family coverage in the offline reporting layer, then continue
P1 containment prerequisites. Real-engine checkpoint formats, GPU correctness, cache
eviction, matched latency studies and containment qualification remain outstanding.

### 2026-11-12: paired case/family reporting

The [offline harness](../../src/neural_compiler/eval/harness.py) now preflights unique
task IDs, all three comparison paths and identical resource budgets before any inference.
It runs the same task/checker object through each supplied path. Reporting rejects duplicate
results, missing baseline/current-best pairs and inconsistent family identities. Costs are
reported by path and by family, retaining failed-attempt time; invalid/nonfinite elapsed
times and mixed-path single summaries fail explicitly.

These are consistency checks, not cohort/split acceptance, statistical confidence bounds,
or proof of matched hardware/intrinsics. A complete table does not qualify task quality or
generalization; current-best remains a caller-provided label.

**Routine ledger:** 27 focused evaluation cases passed, then the root gate passed 90 tests.
Ruff lint, scoped format check, whitespace and Pylance harness diagnostics passed.
No failed attempts, downloads, datasets, pretrained inference or GPU studies occurred.

Read-only containment inspection found installed `libseccomp.so.2` and a cgroup-v2 mount
with CPU/memory/PID controllers, but the mount is **read-only**. Do not remount it or change
host privileges. Next: implement opt-in seccomp-filter plumbing with bounded trusted
fixtures; policy acceptance and writable delegated per-request cgroups remain separate.

### 2026-11-12: opt-in syscall-filter plumbing

Added [explicit seccomp-policy export](../../src/neural_compiler/bridge/seccomp.py) and
bubblewrap filter-descriptor plumbing in [the executor](../../src/neural_compiler/bridge/execution.py).
Callers may supply `SeccompPolicy(allowed_syscalls=(...))` to `run_python` or `run_jailed`.
Unlisted calls receive `EPERM`; unknown syscall names, missing libraries and export/setup
failures produce explicit isolation errors without an unfiltered fallback.

**No production allowlist is selected, and default execution behavior is unchanged.**
The policy in tests is a trusted interpreter/launcher fixture only. It permits launcher
execution and required I/O, and deliberately excludes process creation and sockets.
The kernel fixture performs one bounded fork attempt (reaping any unexpected child) and
one socket-creation attempt. Both were denied with `EPERM`; ordinary arithmetic still
ran under that same filter. Descriptors are private, passed only to bubblewrap, and closed
after execution/export scope. These checks do not prove complete containment.

**Routine ledger:** the focused filter/executor/runtime check passed 40 cases, then the
root gate passed 96 tests, with real bubblewrap/filter checks rather than skips on this host.
Ruff lint, scoped format and whitespace passed. Pylance found a deprecated contextmanager
return annotation; it was corrected to `Generator` without changing runtime behavior.
No failed execution checks, downloads, dependency installs, privileged host changes,
fork/memory bombs or untrusted services were used.

Remaining externally gated work: the cgroup-v2 mount is read-only, and neither vLLM nor
SGLang is installed. Do not remount/change privileges or install serving engines under
routine test authority. Product syscall/import-policy acceptance and independent containment
evidence, accepted held-out datasets/splits and exact pinned model-study budgets remain
outstanding. Offline infrastructure is not renewed authority for those actions.
