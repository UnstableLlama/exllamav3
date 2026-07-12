# QLoRA-on-EXL3 — Handoff & Next-Step Plan

> Working session handoff. Branch: **`claude/magical-mayer-fq6z4i`**.
> Goal of the original task: prove whether **QLoRA fine-tuning on EXL3-quantized
> weights** is possible, and get a visible end-to-end demo (fine-tune a small
> model to talk like a pirate).

> **Maintenance note (2026-06):** the superseded HF-Trainer training path
> (`exllamav3/training/hf_qlora.py`, the old HF-Trainer `examples/qlora_train.py`
> — NOT today's YAML launcher of the same name — `examples/qlora_infer.py`, and
> `tests/test_qlora_train_loop.py`) has been **removed**. The transformers-free
> native path (§0/§0b) is the only supported route. Sections §3–§6 below
> describe the removed code and the abandoned transformers-5.x investigation;
> they are kept for historical context only. All exllamav3-internal
> reach-through used by the native forward now lives in the single seam
> `exllamav3/training/backbone.py`.

> **Maintenance note (2026-07, Session 19):** all training scripts moved out of
> `examples/` into a top-level `training/` directory (`examples/` is now
> byte-identical to upstream; experiment tooling is `training/experiments/`).
> Path references throughout this document were rewritten to the new locations;
> per-session prose still describes the layout as it was at the time. See
> `training/README.md` for the current map.

---

## Backlog — things to do later (consolidated, in priority order)

> The single list of deferred work, gathered from the per-session "still open"
> notes below (which remain the detailed context for each item). Newest
> priority first, per the 2026-07 direction.

0. **MoE training (Qwen3.5 family + Gemma4 MoE) — BUILT (Sessions 18 + 20 +
   21) and FORWARD-GATED (Session 22): forward + backward box-verified on
   Qwen3.5-2B (GDN), Qwen3.6-35B-A3B (GDN+MoE) and a Gemma4-MoE finetune, plus
   a clean GDN training smoke and new VL text-tower support. What remains is
   MoE training smokes with routed-expert adapters + real SFT runs — see the
   Session 22 notes.** The native forward now covers the full Qwen3.5
   family — the hybrid GDN + gated-attention layers (Session 18: fla
   `chunk_gated_delta_rule` on CUDA bf16/fp16, sequential fp32 reference
   elsewhere) and the Qwen3.5-MoE / Qwen3-MoE BlockSparseMLP (Session 20:
   std top-k router, shared expert + sigmoid shared gate, opt-in
   routed-expert targets `expert_*_proj` with `--expert-r`, router frozen,
   no aux loss) — AND the Gemma4 MoE layout (Session 21: alt residual
   channel — routing + routed experts fed from the raw post-attention
   residual through their own pre-norms — routed/shared post-norms,
   per-expert scale, GeGLU, no shared gate). What remains is the box work:
   fp32 + bf16 validate gates on real Qwen3.5(-MoE) and Gemma4-MoE EXL3
   quants, then first training runs — see the Session 18 / 20 / 21 box
   lists. Still not covered: Qwen3-Next (fused qkvz layout), sample packing
   on GDN models (rejected loudly; train unpacked — plain Qwen3-MoE and
   Gemma4 MoE pack fine). The Session-24 hole — runtime LoRA NOT applied on
   the fused MoE expert path — is CLOSED in code (Session 26: `experts_lora`
   forces the per-expert torch branch; loader warning is now a slow-path
   notice); end-to-end box demo still pending, needs a trained expert
   adapter (the gemma4moe semancy ones were deleted).
1. **Quantization-aware LoRA — BUILT (Session 17), BOX-TESTED + SHELVED
   (Session 25, verdict: not worth it).** `--quant-aware {noise,ste}` was
   built (noise injection on the frozen-weight closure + a straight-through
   proxy of the requantize step; QA-LoRA's own group-wise operator ruled out
   for a trellis base — decision record in the Session 17 notes). **The box
   A/B ran in Session 25 (3bpw, Llama-3.2-3B, semancy) and the user decided
   to SCRAP it.** Headline: a plain **early-stopped** adapter matched
   quant-aware `noise` on held-out loss AND quantized *better* (KL 0.058 vs
   0.070) for less compute — the KL "win" of noise over an overtrained plain
   arm was overfitting-regularization, which early-stopping does better. The
   whole motivation (LoRAs weak on quants) was the Session-24 decode bug, now
   fixed. The `code` (flags, `quant_aware.py`, tests, run-log fields) is
   **MARKED FOR PROBABLE REMOVAL** — left in the tree for now as a documented
   negative result, and pulled from the fork README (Session 25); rip it out
   (trainer flags, `training/quant_aware.py`, `tests/test_quant_aware.py`,
   YAML launcher keys, run-log schema fields, `adapter_config` provenance
   keys) in a later cleanup unless the 2.5bpw+`ste` lane is ever pursued. Only untested
   rescue path was 2.5bpw (S17 predicted the payoff grows as bpw drops); the
   user declined it. `ste` mode also untested, but the bar is now
   early-stopping, which is high. Full write-up: Session 25 notes. The
   fused-decode runtime-LoRA prerequisite (Session 24) is done, so runtime
   adapters on EXL3 bases do fire.
2. **Near-inference-time training pipeline on KTO/DPO** (the reason Session 16
   built preference training): a workflow where preference signal collected at
   serving time feeds short adapter updates against the exact deployed quant.
   Needs: the Session-16 box gates first, then plumbing (data capture format,
   scheduled short runs, adapter hot-reload via `LoRA.from_directory`).
3. **Trainable-head chunked CE** with a head/LoRA-B gradient (Session 10
   next-work #1's remaining half; supersedes Session 9 #7).
4. **Audit item A1 — dequant 3×→1× per linear per step** (~13% wall at the
   measured 19% dequant share; worth doing opportunistically).
5. **Liger GeGLU + 4D per-head q/k/v norm wiring** (promoted by the measured
   Session-12 liger win: +8.8% tok/s, −1.1 GB/GPU from RMSNorm alone).
6. **qerr low-bpw retest** (2.5–3 bpw, where the quantization error is large)
   before shelving it; it lost to pissa/default at 4 bpw.
7. **Head-aware balanced autosplit** (Session 10 #2 — deprioritized since the
   fused softcap head removed the output-card logit spike).
8. **Mirror newer features into the DDP arm** (A/B/C VRAM levers, `--optim`,
   SVD inits, preference training — the last also needs a cross-rank
   all-reduce for KTO's KL estimate) and **wire `qlora_train_pref.py` into the
   YAML launcher**.
9. **Query-tiled big-head attention** + drop the pointless GQA
   `repeat_interleave` in the `sdpa` branch (Session 8 #1/#2; only bites at
   8k+ context on head_dim-512 layers).
10. **Fused-kernel LoRA — recover the decode perf (Session 24 follow-up).**
   The Session-24 fix makes runtime LoRA on an EXL3 base fall back from the
   fused decode kernels (mgemm / BC bsz-1 graph) to the per-linear path
   whenever an adapter is loaded — correct, but box-measured at a **~60%
   decode tok/s hit while adapted** (1B r32 −65%, 3B r128 −59%; zero cost with
   no adapter, `unload()` restores full speed). Follow-up: add the LoRA delta
   **on top of** the fused mgemm output instead of falling back, so decode
   keeps the fused k/v (and gate/up) path and only pays the two small LoRA
   GEMVs. (BC bsz-1 stays disabled under LoRA — gate/up inject before the
   activation.) Biggest relative win on small models where launch overhead
   dominates. Until then: `unload()` when not steering, or deploy via
   merge-and-requantize (no runtime adapter, no hit).

---

## 0. RESOLVED — QLoRA-on-EXL3 works end-to-end (transformers-free)

> Completed on branch `claude/determined-gauss-suq9gx`. The original question
> ("is QLoRA fine-tuning on EXL3-quantized weights possible?") is **answered:
> yes**, demonstrated end-to-end on the GPU box with the real model, with **no
> `transformers` dependency in the path at all**.

**What was run and confirmed (Llama-3.2-1B-Instruct, EXL3 4bpw, single GPU):**

1. **Forward validated against native.** `training/qlora_validate_native.py`
   PASSED: the differentiable forward's logits match exllamav3's own (correct)
   inference forward — top-1 next-token identical on every prompt, **100%
   per-position argmax agreement**, last-token logits `cos ≈ 0.999999`,
   `max|Δ| ≈ 0.02–0.03` (just fp32-vs-native-fp16 rounding). e.g.
   "The capital of France is" → ` Paris`. This was the whole ballgame: the
   backbone that produced garbage under transformers 5.x is correct here on the
   same quantized weights.

2. **Training works.** `training/qlora_train_native.py` (plain PyTorch loop, only
   `pip install datasets`) trained adapters on `TeeZee/dolly-15k-pirate-speech`.
   Healthy diagnostics throughout: first loss ~2–3 (NOT ~11 random), grad norm
   20–50 (gradients reaching adapters), `|B|` climbing monotonically 0→13, EMA
   loss falling 2.78→~2.35 then plateauing at the data's irreducible-loss floor.

3. **Adapter saves + reloads natively + steers generation.**
   `training/qlora_infer_native.py` loads the PEFT adapter via the native
   `LoRA.from_directory` loader (224 tensors = 32 layers × 7 targets) and the
   output measurably changes vs base. Cranking `--lora-scaling` proved the
   learned direction is exactly the dataset's pirate transform: at ~5× effective
   the generation collapses into `"be be be …"` — the arrr library's dominant
   `is/are/am → be` substitution, over-amplified. Coherent-but-clearly-pirate
   sweet spot is `--lora-scaling ~1.4` (effective ~2.8×).

**Caveat on the *visible* demo (not a code issue):** the chosen dataset is a
**light, inconsistent** pirate conversion (the `arrr` library: `the→th'`,
`is→be`, `you→ye`, `my→me`, occasional canned phrases; responses also lowercased
+ terse; many rows show no pirate markers at all — verified by previewing the
rows). So at the trained scale (`--lora-scaling 1.0`) the effect is subtle, and
the most consistently learnable signal is the lowercasing/terseness, not the
sparse substitutions. For a *naturally* dramatic pirate at scale 1.0, swap in a
heavier-pirate dataset (the loader only needs instruction/response-style fields);
nothing about the training path needs to change.

**Recommended workflow now: §0 (next section). The transformers-5.x
investigation in §4–5 is fully superseded and only of historical interest.**

---

## 0b. Transformers-free native path — implementation details (option 2)

> Added on branch `claude/determined-gauss-suq9gx`.

Rather than keep fighting the transformers-5.x RoPE bug (§4–5 below), the
**fallback option 2 (§6) is now built**: a self-contained, autograd-friendly
Llama forward on exllamav3's *own* loaded weights — **no `transformers` import in
the training path at all**, so it cannot be broken by an upstream version bump.
This is now the recommended path.

**New code (all CUDA-free to import; pure torch):**
- `exllamav3/training/native_llama.py`
  - `NativeLlamaQLoRA(model, r, alpha, target_modules, compute_dtype, …)` —
    builds a differentiable Llama decoder (RMSNorm + GQA/NeoX-RoPE attention +
    SwiGLU + residuals) directly over a **loaded native `exllamav3.Model`**. It
    reuses the exact RoPE table (`attn.rope.inv_freq`), norms, and `sm_scale`
    the correct native inference forward uses. Frozen base weights are
    reconstructed on the fly via `get_weight_tensor()`; only LoRA `a`/`b` (fp32)
    train, routed through the gradchecked `EXL3LoRAFunction`. Head loss via the
    streaming `fused_linear_cross_entropy` (no `[tokens, vocab]` logits).
    `.compute_loss()`, `.logits()`, `.save_adapter()` (PEFT format),
    `.apply_to_native()/.remove_from_native()` (so generation reflects the
    adapter mid-train). Unsupported features (q/k-norm, sliding window,
    softcapping, MoE, gating, partial/mRoPE, non-NeoX) are rejected loudly.
  - `DiffLinear` — differentiable frozen-base + optional-LoRA linear.
- `training/qlora_validate_native.py` — **the correctness gate.** Compares the
  differentiable forward's logits against the native (correct) forward,
  per-prompt: top-1 token agreement, per-position argmax agreement, last-token
  `max|Δ|` / cosine. Run this FIRST.
- `training/qlora_train_native.py` — plain PyTorch training loop (no HF Trainer /
  transformers / accelerate; just `pip install datasets`). Pirate SFT,
  completion-only masking via the native Llama-3 chat template, fused-CE,
  gradient checkpointing, live native samples.
- `tests/test_native_llama.py` — CPU tests (torch only): `DiffLinear` matches
  reference + gradcheck; one decoder block matches an independent plain-torch
  reference to <1e-4; backward reaches every adapter while the base stays
  frozen. (Other CPU tests in §3 still apply.)

**Workflow (on the GPU box, any transformers version or none):**
```
# 1. PROVE the forward is correct (no training):
python training/qlora_validate_native.py --model /mnt/two/Weights/meta-llama-Llama-3.2-1B-Instruct/4/
#    Expect: PASS, "The capital of France is" -> ' Paris', high argmax agreement.

# 2. TRAIN (transformers-free):
python training/qlora_train_native.py \
    --model /mnt/two/Weights/meta-llama-Llama-3.2-1B-Instruct/4/ \
    --out   /mnt/two/Weights/meta-llama-Llama-3.2-1B-Instruct/4/pirate2
#    Expect: first loss ~2-4 and dropping; live samples turn piratey.

# 3. VERIFY on the native inference path (already worked before):
python training/qlora_infer_native.py \
    --model /mnt/two/Weights/meta-llama-Llama-3.2-1B-Instruct/4/ \
    --adapter /mnt/two/Weights/meta-llama-Llama-3.2-1B-Instruct/4/pirate2
```

**Status: RUN AND CONFIRMED on the GPU box** — see §0 for the full results
(validate PASSED with 100% argmax agreement; training healthy; adapter
saves/reloads natively and steers generation). Issues found and fixed during the
real run, all on this branch: CPU-embedding vs GPU-decoder device split; KV cache
must be allocated before `model.load()`; exact prompt/response label masking. The
§4–5 transformers-5.x investigation below is fully superseded (historical only).

---

## 0c. Session 2 — PROVEN end-to-end on a visible demo; dataset density is the key variable

> Branch `claude/zen-franklin-g5hedw` (merged to master). Many runs on
> Llama-3.2-1B and -3B (4bpw), single-GPU and 2× RTX 3090 (DDP).

### Headline result

The EXL3-QLoRA path is **proven end-to-end with an unambiguous visible demo.** An
**ALL-CAPS smoke test** (`--uppercase-response`: train the model to RESPOND IN
CAPS) gave a clean, controllable before/after on Llama-3.2-1B 4bpw:
- BASE → normal mixed case; ADAPTED → SHOUTS IN CAPS, strength scaling with
  `--lora-scaling` (subtle at 1.0 after a short run, consistent across all prompts
  at 2–3). No ambiguity: differentiable forward over the trellis-quantized base,
  frozen base + trained LoRA, save/reload/steer — all working on quantized weights.

### THE key lesson: signal *density*, not rank/steps/model size

Every earlier style demo was muddy for ONE reason — sparse/inconsistent training
signal. The uppercase test isolated the variable:
- **Uppercase** — *every token of every row* changes → learns cleanly, shows
  controllably (can't reach low loss without it, can't hide it at decode). ✅
- **Pirate** (`TeeZee/dolly-15k-pirate-speech`) — `arrr`-library swaps
  (the→th', is→be, you→ye) are *sparse* and many rows barely pirate. Trained hard
  (r64, ~2 epochs, 1B & 3B) it DOES show th'/be/ye when cranked (effective ~2.5–3
  on 1B; coherent further up on 3B) but collapses into "be be be" past that. Real
  but light.
- **UwU** (`superdrew100/UwU_Alpaca_data`) — style in *rare* tokens
  (emoji/caps/OwO). Loss fell to ~0.7 (English backbone fit) but markers stayed
  low-probability and never surfaced at decode, even at scale 2 + temp; only soft
  persona traces ("shy being") leaked. Sparse-marker styles don't transfer to a
  small model's greedy/low-temp generation.
- **Shakespeare** (`Roudranil/shakespearean-...`) — dense register BUT a *play
  script*: tangential monologues + stage directions. At strength it degenerated
  (parroted `*stage directions*`, repetition); tamed it went bland. Data-structure
  ceiling.

**Recipe for a good visible demo: a DENSE, CONSISTENT style on CLEAN
instruction→answer Q&A.** Uppercase is the trivial (no-LLM) instance of exactly
that. A heavily-styled *generated* dataset (every row strongly transformed) would
behave like the caps demo — clean and controllable. Light off-the-shelf style
sets (pirate) or sparse-marker ones (UwU) won't give a clean scale-1.0 demo on a
small model.

### Tooling added this session (on the branch / merged to master)

`training/qlora_train_native.py` (+ DDP variant):
- **Dataset-agnostic loader** — `--instruction-key/--context-key/--response-key`,
  `--dataset-split`. Defaults are Alpaca (`instruction`/`input`/`output`, dataset
  `superdrew100/UwU_Alpaca_data`). Pirate (Dolly schema):
  `--dataset TeeZee/dolly-15k-pirate-speech --instruction-key instruction
  --context-key context --response-key response`.
- **`--uppercase-response`** — the dense smoke test (uppercases only the response).
- **`clean_style_text`** (default on; `--no-clean-text`) — strips
  `[stage directions]`/`*actions*` + normalizes whitespace; `--min-response-words`
  drops junk-short rows. Use `--no-clean-text` for UwU (keeps `*action*` flavor).
- **Checkpointing** — `--save-every N` + save-on-Ctrl-C (previously saved only at
  the end, so early-stopping discarded everything).
- **Resume** — `--resume <adapter_dir>` + `NativeLlamaQLoRA.load_adapter()`
  (inverse of `save_adapter`). NOTE optimizer state is NOT restored (cold AdamW
  re-warmup; harmless for LoRA); `--r`/`--targets` must match the checkpoint.

`training/qlora_infer_native.py`:
- **Sampling controls** — `--temperature/--min-p/--top-p/--top-k/--seed`. Library
  default is temp 0.8 + min_p 0.08, which truncates the low-prob tail and hides
  sparse-marker styles; `--temperature 0` = greedy. `--lora-scaling` unchanged.

`training/qlora_train_native_ddp.py` (NEW): multi-GPU via DDP (see §0d).

### Multi-GPU (DDP) — confirmed working on hardware (2× RTX 3090)

Both GPUs 100% util; disjoint data shards (~total/N per rank); loss tracks a
single-GPU run at the same *effective* batch. **GPU1 was on PCIe ×4 and it didn't
matter** — only the tiny LoRA grads are all-reduced, so the slow lane isn't a
bottleneck. That's exactly why DDP (not FSDP) fits QLoRA-on-EXL3.

```
torchrun --standalone --nproc_per_node=2 training/qlora_train_native_ddp.py \
    --model /mnt/two/Weights/<model>/4/ --out /mnt/two/Weights/<model>/4/run \
    --dataset ... --lora-r 128 --alpha 128 --batch 16 --steps 600 --save-every 100
```
- Run once in one terminal — `torchrun` spawns one process per GPU. Only rank 0
  prints/saves (so the log looks single — confirm both GPUs with `nvidia-smi`).
- Resume a single-GPU checkpoint on N GPUs: add `--resume <dir>` (loaded on every
  rank before the broadcast). Effective batch = `--batch × nproc × --grad-accum`.
- DDP script has NO live `🎭` samples / `|B|` column — confirm via the infer sweep.

### Tuning lessons

- **Effective strength = `(alpha/r) × --lora-scaling`.** Single-GPU default is
  r=32/alpha=64 (ratio 2.0); DDP default r=64/alpha=64 (ratio 1.0). Use ratio 1.0
  (`--alpha == --r`) for an intuitive knob.
- **Loss plateau ≠ done.** EMA flattens fast; style keeps firming past it.
  Pirate-hard *broke through* a second time (~2.0→~1.4 around 1 epoch) learning the
  deeper swaps. EMA is a local logging var — it "resets" on resume (meaningless);
  watch raw loss.
- **Harder training → lower inference scale.** A harder-trained adapter is stronger
  per unit scale, so the coherent sweet spot moves DOWN; sweep low first.
- **Bigger base holds coherence under amplification** (3B coherent at higher scale
  than 1B before "be be be" collapse).
- **Live samples run at effective `alpha/r`** — light/sparse styles show nothing
  there even when learned; judge by the inference scale sweep. (Dense styles like
  uppercase DO show live.)

### Gotchas hit (and fixed)

- **torchrun eats `--r`** (abbrev-matches `--rdzv-*`/`--role`). DDP script uses
  `--lora-r` (dest `r`); single-GPU `--r` is fine.
- **OOM from `--batch 48 --no-grad-ckpt`** on wordy data — full attention
  activations × layers exceed 24GB. Fix: drop `--no-grad-ckpt` (checkpointing on)
  and/or lower `--batch`. Only use `--no-grad-ckpt` with VRAM to spare.
- **`<|eot_id|>` spam** in some generations — infer script sets no EOT stop
  condition, so it runs into new assistant turns. Cosmetic; adapter unaffected.
- **`.../4/` in chat commands is a placeholder** for the full model path.

### Run status
- **Uppercase smoke test (1B):** ✅ PROVEN — clean CAPS before/after, scalable.
- **Pirate-hard (1B r64, resumed single→2-GPU):** light but real pirate at
  effective ~2.5–3; collapses past that.
- **Pirate-hard (3B r128, 2 epochs, DDP):** th'/ye at scale ~3, coherent (no hard
  collapse) but still light — dataset ceiling.
- **UwU (1B/3B):** soft persona only; sparse markers don't surface. Not recommended.
- **Shakespeare:** rejected (play-script structure).

### Recommended next step
A **dense funny style on clean Q&A** — *generate* it (take Alpaca/Dolly prompts,
rewrite every answer in a strong style with a local model) so every row is heavily
styled; it'll then behave like the caps demo. OR move to the flagship: low-bpw
(2.5–3) bigger-model fine-tune on a real task with a metric, benchmarked vs what
BNB NF4 can fit (the actually-valuable result — see §0d / implications).

### Session 3 — Yoda generated demo + EXL3-vs-BNB parity + the LoRA-on-quant finding

Long session. Three arcs: (A) build a dense Yoda dataset and prove the visible
demo; (B) stand up a controlled EXL3-vs-bitsandbytes QLoRA comparison; (C) a real
finding about why LoRAs look weak on EXL3-quantized bases at inference.

#### A. Yoda dataset + the density nuance

Picked **Yoda-speak** as the dense style (syntactic clause inversion over COMMON
tokens — unlike pirate/UwU). Off-the-shelf search was dry (only `dvgodoy/
yoda_sentences`, 720 translation pairs), so we **generate**.

- `training/experiments/make_style_dataset.py` — rewrites ONLY the response of a normal
  instruction set (default `yahma/alpaca-cleaned`) into a target style via a LOCAL
  exllamav3 model; Alpaca-schema JSONL. Styles: `yoda`/`archaic`/`pirate`/
  `corporate`; `--refine-from` does a stricter second pass over an existing set.
  Use a strong instruct model as `--gen-model` (we used `TheDrummer_Rocinante-XL-
  16B-v1` 4bpw). Gotchas fixed live: create out-dir up front; stop at EOT (RP
  finetunes role-play a whole convo past the answer); drop `min_new_tokens` (it
  triggered a sampler cuda/cpu mask bug); reject prompt-echo/refusal rows.
- `training/experiments/score_style_density.py` — Yoda-ness metric = clause-final inversion
  rate (sentences ending in aux/pronoun/contraction, plus a front-loaded
  "displaced subject" signal). **Known blind spot: noun-subject fronting ("Ended
  the war did") and main-verb endings — needs POS to catch — so the score is a
  conservative LOWER BOUND. Do NOT hard-filter on it** (it can't tell good
  noun-subject Yoda from junk; both score ~0).
- `qlora_train_native.py` loader now also reads a **local file path** for
  `--dataset` (json/jsonl/parquet/csv); DDP inherits it.

**THE density nuance (correction to S0c):** Yoda is dense at the SENTENCE level
but **sparse at the TOKEN level** — most words within an inverted sentence are
still normal order, so teacher-forced loss got low (~0.4) without the model
committing to inversions at greedy decode. So on the quantized base it needed
`--lora-scaling ~3` to surface (1B collapsed there; 3B held coherence and gave
clean Yoda). A density audit confirmed bimodality (~27% of rows barely inverted);
a Rocinante **refine pass** improved quality but the metric undercounted the gain
(it produces noun-subject Yoda the metric can't see). Dataset density was NOT the
bottleneck — see arc C for the real reason the 4bpw demo looked weak.

#### B. EXL3-vs-BNB QLoRA comparison harness (the flagship, parity check)

Goal: same model / data / LoRA / optimizer, only the frozen-weight format differs
(EXL3-4bpw vs bitsandbytes NF4), on Llama-3.2-3B, Yoda data. **Chose NOT to use
Axolotl** (it can't train EXL3 at all; mixing frameworks confounds; its dep tree
threatens the pinned torch/EXL3 `.so`). Instead a minimal matched loop:

- `training/qlora_train_bnb.py` (NEW) — transformers 4-bit NF4 + PEFT LoRA in a
  hand loop mirroring `qlora_train_native.py` byte-for-byte (same Llama-3 chat
  prompt, completion-only masking, `datasets` shuffle(seed=0)+select, val split,
  LoRA targets/r/alpha, AdamW/lr/clip, bf16). Optional DDP (manual LoRA-grad
  all-reduce, same as the EXL3 DDP arm). Runs in the same venv (just
  `pip install bitsandbytes peft accelerate`) or an isolated one.
- Added to all three trainers: `--val-frac` + **identical held-out eval loss**
  (mean per-example, batch 1), `--eval-every`, `--save-best` (keep the best-val
  checkpoint; Ctrl-C won't clobber it), `[PERF]` tok/s + peak VRAM. `--gen-out`
  on the BNB trainer and `qlora_infer_native.py` dump samples for the scorer.
- Fixes found running it: NCCL teardown hang → pass `device_id` to
  `init_process_group`; `--r` eaten by torchrun → use `--lora-r`; **default
  `--max-samples` mismatch (bnb 4000 vs ddp 0) silently trained the arms on
  different data** → aligned to 0 (use all); match EFFECTIVE batch across arms
  (`--batch` is per-GPU under DDP).

**Overfitting caught by the eval curve:** at `lr 2e-4`, r=64, ~4 epochs, train
loss hit 0.09 while **held-out loss rose to 3.11** — the endpoint adapter was
memorized garbage (this, not the dataset, is why scale-3 gens degenerated). Fix:
`--lr 1e-4` + all data + `--save-best` → clean minimum ~2.0.

**Results (matched, 5329 train / 280 val, lr 1e-4, r64/a64, eff-batch 32):**
- **Held-out loss: near-identical (~2.0 both arms) — 4-bit PARITY confirmed.**
  EXL3 was a hair lower at matched steps.
- **EXL3 is more memory-efficient:** it ships fused-CE (never materializes the
  `[tokens×128k]` logits), so it fit `--batch 16`; the stock BNB/PEFT loss OOM'd
  at 16 on a 24GB card and needed `--batch 8 --grad-accum 2`.
- **EXL3 converged in ~⅓ the steps** — but that's an effective-LR/init difference
  between our `EXL3LoRAFunction` and PEFT (grad norms ~2.5 vs ~0.6 at the same
  nominal lr), NOT a quant property. Compare loss FLOORS, not steps.
- **The visible demo WORKS:** QLoRA-on-EXL3 Yoda, applied to bf16, gives clean
  coherent inversion ("Dinner for tonight, what should you? Many options, there
  are."). Both arms produce strong Yoda → quality parity too.

#### C. FINDING — LoRAs are attenuated on EXL3-quantized bases at inference

Controlled test (user's `ezexl3` frontend, correct Llama-3 templates, 0%/100%
scaling, BOTH the EXL3- and BNB-trained adapters, applied to BOTH the bf16 and the
4bpw base): **only the bf16 base produced strong steering; the 4bpw base
attenuated every adapter.** Correlated with LOW rank/alpha.

`Linear.apply_lora` is **base-agnostic** (`delta = x@a@b` added identically for
EXL3 and bf16; the `alpha/r` scale is folded into `B` at load) — so this is NOT an
application bug. Mechanism: the EXL3 trellis adds a per-output quantization
perturbation `x·ε`; a low-rank/low-alpha LoRA's delta is small and gets **buried
in `ε` on the quantized base**, while on bf16 (no `ε`) the same delta dominates and
the style shows. Higher rank/alpha grows the delta past the quant floor — exactly
the observed rank/alpha correlation. This is why our earlier "weak Yoda on 4bpw"
looked like a dataset/training problem when it was really a **signal-to-quant-noise
ratio at inference**; the adapter was good all along (loss + bf16 gens prove it).

**Implications:**
- Evaluate adapters on bf16 for a fair comparison (sidesteps a confound that hits
  both arms) — done; parity holds.
- Deploying a swappable low-rank adapter ON the EXL3 base is attenuated. Options:
  **(a) higher rank/alpha** so the delta clears the quant floor, or **(b) merge the
  adapter into bf16 and re-quantize** (delta becomes part of `W`; no small signal
  to bury — the clean deploy path, loses hot-swap).
- **This gets WORSE at 2.5–3bpw (bigger `ε`)** — so for the low-bitrate prize,
  merge-and-requantize is likely the right deployment story. Flagged before that
  experiment.

#### Recommended next steps
1. **Merge-and-requantize test** (chosen, arc C option b): merge the EXL3 Yoda
   adapter into bf16, re-quantize to 4bpw, confirm the style survives on the
   quantized base. Validates the real deployment path.
2. Optional: rank/alpha sweep on the 4bpw base to map the quant-floor threshold
   (turns the qualitative finding into a curve — useful to the exllamav3 community).
3. Then the headline low-bitrate run: EXL3-2.5/3bpw (where NF4 can't follow),
   deployed via merge-requantize, on a real metric.

### Session 4 — real-task training: schedulers, `messages`/test-split eval, prompt formats, full embed/head, BOS fix

> Branch `claude/epic-planck-n892gw`. Turned the proven QLoRA-on-EXL3 path into a
> real-task trainer, driven by a live run on **UnstableLlama/semancy** (a
> philosophy fine-tune: 436 train / 116 test, OpenAI-style single-turn `messages`,
> no system prompts). All code changes; the runs happen on the GPU box (2×3090).
> Everything below is **run-confirmed** unless noted.

**At a glance — what's new this session (all in `training/qlora_train_native.py` +
the DDP variant; the BNB arm mirrors everything except `--prompt-format`,
`--inspect`, and `--train-embeddings/--train-head`):**

| Flag / change | What it does |
|---|---|
| `--messages-key` | Load OpenAI `messages` rows (user→prompt, assistant→supervised response). |
| `--scheduler {none,linear,cosine}` + `--warmup-ratio`/`--warmup-steps` | Transformers-free LR schedule with warmup (HF-equivalent `LambdaLR`). Default `none` = old constant LR. |
| `--weight-decay` (def 0.01) | Explicit AdamW weight decay (was torch's implicit 0.01). |
| `--epochs` | Derive `--steps` from train size × effective batch (folds in `world_size` under DDP). |
| `--eval-split` / `--eval-dataset` | Held-out eval loss on a **real** split (e.g. `test`) instead of carving `--val-frac` off train. |
| `--inspect N` | Decode the first N built examples (prompt vs supervised span, turn-end check) and exit. Tokenization gate; also a native-forward feasibility check. |
| `--prompt-format {auto,mistral,metharme}` | Chat format: model-native, explicit Mistral `[INST]`, or Pygmalion `<|user|>/<|model|>`. |
| `--train-embeddings` / `--train-head` | Fully train embed_tokens / lm_head (PEFT `modules_to_save`) and save them, not just LoRA. |
| **BOS fix** | `build_sft_examples` was emitting a **doubled `<|begin_of_text|>`** + a stray BOS on the response; now normalized to exactly one. (Found by `--inspect`.) |

Shared helpers (`build_sft_examples`, `collate`, `make_lr_scheduler`,
`resolve_steps_and_warmup`, `format_prompt_and_eot`, `extract_single_turn`) live
in `qlora_train_native.py`; the DDP script imports them. The BNB arm
(`qlora_train_bnb.py`) inlines byte-identical copies (separate venv, can't import
the exllamav3 path) for `--messages-key`, scheduler/warmup/`--weight-decay`,
`--epochs`, and `--eval-split` — so a matched EXL3-vs-NF4 run needs only the same
flags on both. (`--prompt-format` and `--train-embeddings/--train-head` are
native-arm only for now.)

**New trainer features (both `qlora_train_native.py` and the DDP variant; shared
helpers live in `qlora_train_native.py` and are imported by the DDP script):**
- **`--messages-key`** — OpenAI `messages` loader. For single-turn rows it takes
  the user turn as the prompt and the assistant turn as the supervised response
  (system turns ignored; the dataset has none). `extract_single_turn()` does the
  pull; the rest of the completion-only masking path is unchanged, so the answer
  (plus `<|eot_id|>`) is supervised and the prompt is `-100`. Takes precedence
  over the flat `--instruction/context/response-key`.
- **LR schedulers** — `--scheduler {none,linear,cosine}` + `--warmup-ratio`
  (fraction of steps) or `--warmup-steps` (absolute). `make_lr_scheduler()` is a
  transformers-free `LambdaLR` matching HF's `get_{linear,cosine}_schedule_with_warmup`
  exactly: LR ramps 0→base over warmup, then linear-to-0 or half-cosine-to-0.
  Default `none` keeps the old constant-LR behavior (matched-arm runs unaffected).
  Per-step `sched.step()`; current LR is logged each step.
- **`--weight-decay`** (default 0.01) — now explicit on the AdamW over the LoRA
  params (torch's AdamW default was already 0.01; this just makes it a knob).
- **`--epochs`** — if >0, computes `--steps` from the train-set size and the
  *effective* batch (`batch*grad_accum`, ×`world_size` under DDP), so the schedule
  length matches the requested passes. e.g. 436 rows, eff-batch 16, 2 epochs → 56
  steps (warmup 6 at ratio 0.1).
- **`--eval-split` / `--eval-dataset`** — held-out eval loss on a *real* split
  (e.g. semancy's 116-row `test`) instead of carving `--val-frac` off train.
  Built identically on every rank under DDP; works with `--eval-every`/`--save-best`.
- **`--inspect N`** (single-GPU script) — decodes the first N built examples,
  showing the masked prompt span vs the supervised response span and **warning if
  the response was truncated by `--seq-len`** (so the model would never see the
  turn-end token). Run once to verify tokenization on any new dataset/schema
  before a long run.

**Tokenization** for the `messages` path: `default_chat_prompt()` (Llama) injects
**no** system prompt when none is passed, emits the standard Llama-3 template
ending at the assistant header; the response is tokenized separately and
terminated with the architecture-correct turn-end token, prompt masked `-100`.

**Doubled-BOS bug found by `--inspect` (fixed).** Running `--inspect 3` on the GPU
box revealed every prompt began with `<|begin_of_text|><|begin_of_text|>` and the
**response span began with a stray `<|begin_of_text|>`**. Cause: the special-token
encode path (`tokenizer.py:243/254`) calls the underlying HF tokenizer with
`add_special_tokens=True`, and the Llama-3 tokenizer has `add_bos_token=true`, so
it auto-prepends BOS on *every* `encode()` — on top of the literal BOS in the chat
template, and again on the separately-encoded response. exllamav3's own `add_bos`
flag is independent of this. This is non-standard (real Llama-3 = exactly one BOS,
none mid-sequence) and meant the EXL3 arm wasn't even BOS-matched to the BNB arm
(which uses `add_special_tokens=False` and so gets a single BOS). **Fix:**
`build_sft_examples` now normalizes to one leading BOS and strips the response's
spurious one (no-op for tokenizers that don't auto-prepend, so it's general). The
fix lives in the trainer, NOT the tokenizer (the inference path relies on the
auto-BOS). Prior pirate/Yoda runs carried this double BOS and still trained/
validated (the forward math was unaffected), but new runs should use the fix.
Pure-logic checks (scheduler shape, epoch→step math, messages extraction, BOS
normalization) pass; the rest needs the GPU box (no torch/CUDA in the container).

**Recommended semancy run (per the research plan: r=16/α=32, lr 1e-4, cosine,
~10% warmup, wd 0.01, eff-batch 16, completions-only, all linear targets, 2 epochs):**
```
# 0. Verify tokenization first (single-GPU, exits after printing):
python training/qlora_train_native.py --model /path/to/exl3_model \
    --dataset UnstableLlama/semancy --messages-key messages \
    --no-clean-text --seq-len 2048 --inspect 3
#    Confirm: PROMPT is the user turn, RESPONSE is the assistant turn, and
#    "ends with turn-end token? True" (else raise --seq-len).

# 1. Train (2× GPU DDP; --batch 8 × 2 GPUs = eff-batch 16):
torchrun --standalone --nproc_per_node=2 training/qlora_train_native_ddp.py \
    --model /path/to/exl3_model --out /path/to/out/semancy \
    --dataset UnstableLlama/semancy --messages-key messages --no-clean-text \
    --eval-split test --eval-every 10 --save-best \
    --lora-r 16 --alpha 32 --lr 1e-4 --scheduler cosine --warmup-ratio 0.1 \
    --weight-decay 0.01 --batch 8 --grad-accum 1 --epochs 2 --seq-len 2048
```
- **`--no-clean-text` is important here**: the default cleaner strips `[...]`/`*...*`
  and collapses newlines — fine for play-script style sets, **wrong for a
  reasoning dataset** (would delete bracketed content and paragraph structure).
- **`--seq-len`**: philosophy/reasoning answers can be long; 512 (the default)
  likely truncates them. Use `--inspect` to check, then size `--seq-len` so most
  responses end in the turn-end token. Bigger seq-len costs VRAM (drop `--batch`
  or keep grad-checkpointing on if OOM).
- Recall **finding C**: a low-rank adapter (r=16) is *attenuated* on the EXL3
  base at inference. Evaluate on bf16 (or merge-and-requantize) for a fair read;
  the held-out `test` loss is the format-independent signal.

**BNB-NF4 arm matched too.** `training/qlora_train_bnb.py` got the same flags
(`--messages-key`, `--scheduler`/`--warmup-ratio`/`--warmup-steps`,
`--weight-decay`, `--epochs`, `--eval-split`/`--eval-dataset`) with the helpers
*inlined* (it runs in the separate transformers+bitsandbytes+peft venv and can't
import the exllamav3 path) but byte-identical to the EXL3 arm, so a matched
EXL3-vs-NF4 comparison on semancy just needs the same flags on both:
```
# EXL3-4bpw arm: the DDP command above.
# BNB-NF4 arm (point --model at the bf16 HF weights; same eff-batch via --batch):
~/exl3/bnb-venv/bin/torchrun --standalone --nproc_per_node=2 \
    training/qlora_train_bnb.py --model /path/to/Llama-bf16 --out /path/to/out/semancy_bnb \
    --dataset UnstableLlama/semancy --messages-key messages --no-clean-text \
    --eval-split test --eval-every 10 --save-best \
    --lora-r 16 --alpha 32 --lr 1e-4 --scheduler cosine --warmup-ratio 0.1 \
    --weight-decay 0.01 --batch 8 --grad-accum 1 --epochs 2 --seq-len 2048
```
Compare the held-out `test` loss floors (per S3-B: compare floors, not steps —
the arms differ in effective LR/init). BNB may need a smaller `--batch` +
`--grad-accum` to hit eff-batch 16 within 24GB (it lacks the EXL3 arm's fused-CE).

**semancy run result (Llama-3.2-1B 4bpw, 2×3090 DDP, r16/α32, lr1e-4 cosine,
warmup6, 56 steps):** clean — both GPUs, cosine schedule exactly as designed
(LR→1e-4 by step6, →0 at step56). Train loss 3.53→2.14; held-out `test` loss
3.30→**3.09** (`--save-best`); peak VRAM **5.26 GB/GPU** (huge headroom); 179s.
Eval flattened ~3.09 after step30 with a widening train/eval gap → near plateau;
3.09 is high vs the style runs (~2.0) but expected (dense reasoning + a
deliberately-hard generalization test split, not memorization). Likely
capacity-bound on 1B — a 3B/8B base is the bigger lever than more 1B epochs.

### Prompt formats (`--prompt-format`) + Mistral

`build_sft_examples` got a `--prompt-format {auto,mistral,metharme}` knob (single +
DDP; `format_prompt_and_eot()` is the seam):
- **auto** (default, unchanged): the model's own template via
  `default_chat_prompt` — Llama-3 headers, Mistral `<s>[INST] … [/INST]`, etc.,
  with the architecture-correct turn-end token.
- **mistral**: explicit `<s>[INST]{q}[/INST]{a}</s>` (no spaces; `[INST]`/`[/INST]`
  are control tokens). Identical to **auto** for the `mistral3` arch — which is
  what **Mistral-Medium-3.5-128B** (and Small/Medium 3.x) loads as: its
  `mistral3.py:243` `default_chat_prompt` already emits
  `<s>[SYSTEM_PROMPT]{sys}[/SYSTEM_PROMPT][INST]{q}[/INST]` (the current V13
  control-token format), so **Medium 3.5 needs no new format — auto already
  covers it**; `mistral` just makes it explicit / arch-independent. (Caveats for
  actually training it: it's a 128B — needs a multi-GPU EXL3 quant; and `--inspect`
  doubles as the native-forward feasibility check since it builds the net and
  `assert_block_supported` would reject an unsupported block.)
- **metharme**: Pygmalion format `<s><|user|>{q}<|model|>{a}</s>`. On a base
  model the `<|user|>`/`<|model|>` markers are **plain text** (not registered
  special tokens) — the model learns them as a literal pattern, the standard way
  these tunes train; EOS ends the turn. The literal `<s>` + the existing
  BOS-normalization → exactly one leading BOS, none mid-sequence (verified).
  Mistral did **not** do this before (its `default_chat_prompt` is `[INST]`).

### Training the embeddings + LM head (`--train-embeddings` / `--train-head`)

LoRA freezes `embed_tokens`/`lm_head`; these flags fully train them
(PEFT `modules_to_save` semantics) and save them. Single + DDP; in
`NativeLlamaQLoRA`:
- A trainable **fp32 copy** of the embedding (`[vocab,hidden]`) and/or head
  (`[hidden,vocab]`) is reconstructed once from the frozen base and placed on the
  GPU compute device (the base embedding is on CPU under `prefer_cpu`; a CPU
  optimizer would crawl). exllamav3 loads a *separate* embed and head even for a
  tied model, so they're trained **independently** — no shared-param special case
  (the saved config records `tie_word_embeddings` only as a merge-time hint).
- **Head loss path:** the fused-CE head is frozen-only (returns no weight grad),
  so `--train-head` switches `compute_loss` to a standard-autograd cross-entropy
  computed **only at the supervised positions** (labels≠ignore) — the head gets a
  gradient and memory scales with supervised tokens, not the full `[tokens,vocab]`.
- **Grad-checkpointing fix:** `forward` used to `detach()` the embedding (frozen
  assumption); it now only detaches when `hidden` doesn't already require grad, so
  a trainable embedding's gradient isn't severed.
- Optimizer: embed/head go in a **0-weight-decay** group (`param_groups()`);
  decaying a whole embedding table is harmful. LoRA keeps its weight decay.
- Saved to `modules_to_save.safetensors` (HF orientation `[vocab,hidden]`) beside
  the adapter, kept OUT of `adapter_model.safetensors` so the per-linear LoRA
  loader is undisturbed; `adapter_config.json` lists `modules_to_save`.
  `load_adapter` restores them on resume, and `LoRA.from_directory` now applies
  them at inference (see "Applying a trained embed / head / head-LoRA at
  inference" below). CPU test: `test_modules_to_save_param_groups`.

**Cost / caveats:** these are big matrices. On the tied 1B (vocab 128k×2048 ≈
262M params) that's ~4 GB (fp32 master+grad+Adam m,v) — fine. On a 16B (vocab
131k×~6144 ≈ 805M *each*, untied) it's ~13 GB *per* matrix — under **DDP it's
replicated per card AND the grad is all-reduced every step** (the embed/head grad,
not just the few-MB LoRA grad), so `--train-embeddings`/`--train-head` on a 16B
will OOM 24 GB and is slow over PCIe. Realistic on small models, or large models
only with `--parallel split` / more VRAM.

### Applying a trained embed / head / head-LoRA at inference (`LoRA.from_directory`)

The four "extra" surfaces (`--lora-head`, `--lora-embed`, `--train-head`,
`--train-embeddings`) are saved **beside** `adapter_model.safetensors`, not in it
— so the main file is byte-identical with or without them (a "did it save?"
red herring; check for the side files instead):
- `lora_modules.safetensors` — low-rank head/embed LoRA (`lm_head.lora_a/b`,
  `embed_tokens.lora_a/b`, internal orientation, **unscaled**).
- `modules_to_save.safetensors` — fully fine-tuned head/embed (HF orientation
  `[vocab,hidden]`).

`LoRA.from_directory` (used by `training/qlora_infer_native.py`) now **consumes
both files automatically** so a head/embed adapter actually fires at inference
(previously they were saved but silently dropped — only the per-linear LoRA in
`adapter_model.safetensors` was applied). How each is wired:
- **Head LoRA** → the LM-head is a native `Linear` with runtime LoRA slots, so
  `lm_head.lora_a/b` load straight into them; `apply_lora` does `x @ a @ b` and
  the loader bakes `alpha/r` (× `--lora-scaling`) into `b` to match the trainer.
- **Full head** (`--train-head`) → installed as `Linear.lora_full_weight`, an
  fp16 `[in,out]` override that **supersedes** the quantized base matmul for the
  head (the trained fp16 head is better than the quantized one, so it replaces it
  rather than adding a delta). Works on tied models too (exllamav3 keeps a
  separate head `Linear`).
- **Embed LoRA / full embed** → the input `Embedding` has no LoRA slot, so these
  are **folded into the embedding weight in place**. Full embed is a direct
  replacement; embed-LoRA adds `scale·(a@b)` but divided by the module's
  `multiplier`/`sqrt(d)` normalize first, because the trainer adds the shift
  *after* that scaling (a no-op divide on Llama/Mistral where both are 1).

`unload()` reverts all of the above (clears the override, restores the original
embedding weight). Implementation: `exllamav3/model/lora.py`
(`_load_module_adapters`) + the guarded `lora_full_weight` branch in
`exllamav3/modules/linear.py`. **Interop note:** these side files use the
trainer's own keys, not PEFT's (`lora_embedding_A/B`,
`modules_to_save.default.weight`), so HF/PEFT/Axolotl won't read the head/embed
parts — a PEFT-format export is the remaining follow-up for external-tool
loading; the per-linear `adapter_model.safetensors` is already standard PEFT.

**Mistral caveat:** the native forward (`backbone.assert_block_supported`,
backbone.py:71) **rejects sliding-window attention**, so Mistral-7B-v0.1
(sliding_window=4096) won't load; v0.2/v0.3/Nemo/Small (sliding_window=null) are
fine. Verify a new Mistral base with `--inspect` first (it now reports the
metharme spans + the EOS turn-end check).

Run a Mistral metharme SFT by adding `--prompt-format metharme` to the usual
command (point `--model` at a no-sliding-window Mistral EXL3). Inference must use
the same metharme template for the adapter to fire (the single-GPU live `sample`
already does; set it in your own frontend for real inference). The BNB arm still
uses `[INST]`/native only — mirror `--prompt-format` into `qlora_train_bnb.py` if
a metharme EXL3-vs-NF4 comparison is wanted.

### Session 4 — status, run-confirmed, and open items

**Run-confirmed on the box (2×3090):**
- semancy DDP run end-to-end on Llama-3.2-1B 4bpw: cosine schedule, `--epochs`,
  `--eval-split test`, `--save-best` all working (result above; eval `test` loss
  ~3.09, 5.26 GB/GPU, 179 s).
- `--inspect` on the 1B (Llama) and on **Rocinante-XL-16B** (mistral, metharme):
  both show one BOS / correct spans / `ends with turn-end token? True`. The 16B
  loaded fine through the native forward (no sliding-window rejection), so
  mistral-family + metharme works on a real 16B.
- `--prompt-format metharme` on the 16B produced exactly
  `<s><|user|>{q}<|model|>{a}</s>`.
- BOS fix verified (the doubled-BOS dump → single BOS after the fix).

**Not yet run (write-confirmed only — verify before relying on):**
- `--train-embeddings` / `--train-head` on real hardware (logic + a CPU test pass;
  the head-grad path and the save/load round-trip haven't run on GPU yet). Smoke
  it on the 1B first.
- The 16B **metharme training** run itself (only `--inspect` was run; use DDP
  `--batch 2 --grad-accum 4` for eff-batch 16, or `--batch 1 --grad-accum 8` if it
  OOMs on load).
- Mistral-Medium-3.5: it's the `mistral3` arch and `--prompt-format auto`/`mistral`
  already emit its V13 `[SYSTEM_PROMPT]`/`[INST]` format, but no EXL3 quant of a
  128B was trained (needs multi-GPU `--parallel split`).

**Open items / would-be-nice next:**
- Mirror `--prompt-format` and `--train-embeddings/--train-head` into the BNB arm
  (PEFT supports `modules_to_save` natively) for matched comparisons.
- Make live samples / the native infer path reflect a trained embed/head (today
  only the runtime LoRA slots are wired; trained matrices are for merge/requantize).
- Tests for the new paths need a GPU/model (CPU tests can't build the full net):
  only `test_modules_to_save_param_groups` is pure-CPU. Run `tests/test_native_llama.py`
  + `tests/test_fused_ce.py` + `tests/test_qlora_grad.py` after pulling.
- For semancy specifically: a bigger base (3B/8B) is the likely win over more 1B
  epochs (the ~3.09 floor looks capacity-bound); judge style on bf16 / merge per
  finding C, not on the attenuated 4bpw base.

### Session 5 — broader architectures: Gemma3/4 + Qwen3 dense in the native forward

> Goal: train current dense models (Gemma4, Qwen3.x) on the EXL3 native path.
> The native forward was scoped to one block shape (pre-norm GQA + NeoX-RoPE
> softmax attention + pre-norm SiLU GatedMLP) and `assert_block_supported`
> rejected everything else. This session **generalizes** that forward instead of
> forking a per-arch one.

**The triage (read the arch files, not memory — exllamav3 already has inference
support for all of these):**
- **Qwen3.5 / 3.6 are hybrid linear-attention** (`architecture/qwen3_5.py`): even
  the non-MoE `Qwen3_5ForCausalLM` builds ~3/4 of layers as **`GatedDeltaNet`**
  (delta rule + exp gating + causal Conv1D + L2 q/k-norm) and the rest as gated
  full-attention. Training them needs a **differentiable Gated DeltaNet** (its own
  recurrent forward+backward) — a separate research-grade project, **not done**.
  This is the hard blocker; "dense" ≠ standard transformer for Qwen3.5/3.6.
- **Gemma4 dense text** (`architecture/gemma4.py`) is **softmax** attention — no
  linear-attn blocker — but adds: q/k/v-norm, **sandwich post-norms**, **GeGLU**,
  alternating **sliding/full** layers with **per-layer head dims**, Gemma `(1+w)`
  RMSNorm, embedding scaling, optional logit softcapping. All differentiable.
- **Qwen3 (3.0) dense** = standard transformer + **q/k-norm** only (falls out for
  free from the generalization).

**RUN-CONFIRMED on the box (gemma-4-12B-it 4bpw, 1×GPU, fp32 eager):**
`qlora_validate_native.py` **PASSED** — 100% per-position argmax agreement vs
exllamav3's own forward on every prompt, last-token `cos ≈ 0.999998`,
`max|Δ| ≈ 0.08` (just fp32-vs-native-fp16 rounding), `--check-backward` PASS.
The decisive bug was the missing **per-layer `layer_scalar`** (below): without it
the forward was per-block-correct but compounded to garbage over 48 layers (0%
argmax, cos~0). The `sm_scale=1.0` question is settled — correct as-is (Gemma's
query scaling is folded into the weights; the near-perfect cosine confirms it).
Still to run: the bf16 flash/SDPA path (`--compute-dtype bfloat16`) and a real
training run.

**What was changed (compiles + CPU logic checks pass; forward now GPU-validated on
gemma-4-12B as above):**
- `training/backbone.py`: `assert_block_supported` relaxed to allow q/k/v-norm,
  GeGLU, sliding window, sandwich post-norms and softcap, while still rejecting
  GatedDeltaNet (linear attn), MoE, attention output gating, mRoPE, partial
  rotary and non-NeoX RoPE. New `norm_spec()` (reproduces `RMSNorm.forward_torch`:
  `y = x/rms(x) * constant_scale * (weight + constant_bias)`, so Gemma's `(1+w)`
  and unweighted v-norm are read from the module, not hardcoded), `block_post_norms()`,
  `attn_qkv_norms()`, `head_softcap()`; `block_metadata` gains `sliding_window`,
  `softcap`, `activation`, `use_k_as_v`.
- `training/native_llama.py`: `_rmsnorm` → spec-driven `_norm`; `_block_forward`
  now does per-head q/k/v-norm (pre-RoPE), attn softcap, sandwich post-norms
  (`x = x + post_norm(sublayer_out)` — confirmed against the fused `rms_norm` CUDA
  kernel, `norm.cu:205`), GeGLU, and `use_k_as_v` (V = raw K projection); `_attn_bias`
  gains a sliding-window band; `forward` builds an attention bias per
  (window, device); final norm uses `_norm`; final-logit softcapping handled in
  `logits()`/`compute_loss()` (the fused-CE path can't softcap, so it falls back
  to a supervised-position CE when a final cap is present). **Reduces
  bit-identically to the old Llama/Mistral/Qwen2 path when all features are off.**
- `tests/test_native_llama.py`: updated to the new entry/meta interface and added
  `test_gemma_block_matches_reference` (q/k/v-norm + sandwich + GeGLU + sliding +
  softcap + `(1+w)`) vs an independent reference.

**Loading:** `Model.from_config` defaults to `component="text"`, so a multimodal
`Gemma4ForConditionalGeneration` checkpoint loads its **text decoder** only; the
`split_decoder` embedding-first/head-last layout holds. Use `--sample-every 0` for
a first Gemma4 run (live generation would exercise the SWA/recurrent cache path,
irrelevant to training).

**MUST DO before trusting a Gemma4 run (the correctness gate):**
```
# CPU first (torch only): the differentiable block vs an independent reference.
python tests/test_native_llama.py
# Then on the box: logits parity vs exllamav3's own forward on a real Gemma4 dense:
python training/qlora_validate_native.py --model /path/to/Gemma4-dense-exl3
#   Expect high per-position argmax agreement + tiny last-token max|Δ|.
# Only then: python training/qlora_train_native.py --model ... --sample-every 0 ...
```
Open: q/k-norm is folded into exllamav3's RoPE kernel in the native path (we apply
norm-then-RoPE, mathematically equal) — the validate gate is what confirms it on
real weights. Gemma4's `sm_scale=1.0` (vs Gemma2/3 `query_pre_attn_scalar**-0.5`)
is read from the module, so no special-casing — but eyeball it in validation.

#### FlashAttention-2 fast path (long-context training)

The native block forward was **eager** — it materialized the `[b, n_q, t, t]`
score matrix in fp32 — which is the O(t²) memory wall at long context.
exllamav3's own FA2 is inference-only (`@torch.inference_mode` kernels), so the
training path now uses the upstream **`flash_attn` package's autograd-capable
`flash_attn_func`** instead (already installed in the qlora-venv, 2.8.3).

- `native_llama._block_forward` gained a `use_flash` branch: flash takes
  `[b, t, nh, hd]` directly (no transpose / no GQA expand), and the causal mask,
  Gemma sliding window (`window_size=(W-1, 0)`) and softcap go through flags — so
  the eager `[t, t]` bias is **not built** when flash is active (that omission is
  what realizes the saving). Eager stays as the reference / CPU / fp32 / gradcheck
  path.
- `--attn-impl {auto,eager,flash}` on both trainers + the validate script
  (`NativeLlamaQLoRA(attn_impl=...)`). **auto** = flash when the package imports
  AND the run is CUDA fp16/bf16, decided per-forward; fp32 / CPU always run eager.
- **VRAM saved ≈ ~2 × b · n_q · t² · 4 bytes** (the eliminated score matrix +
  softmax). With grad-checkpointing on (default) that is the **per-block** peak —
  independent of model depth / hidden size, only `b · n_q · t²`. Examples (b=1):
  n_q=32 → ~4 GB at t=4k, ~16 GB at t=8k; n_q=16 (Gemma) → half. Net effect:
  roughly 4–8× more context (or batch) on the same card in the t=4k–16k range.
  Flash does NOT touch the residual-stream checkpoints (`~layers · b · t · d · 4`),
  which become the next term at extreme context.
- **Per-block mode (Gemma mixes head sizes).** FA2 only supports `head_dim <= 256`,
  but Gemma4's *global* layers exceed that. So the mode is chosen per block:
  **flash** (head_dim ≤ 256, % 8 — the sliding/local layers), **SDPA**
  (`F.scaled_dot_product_attention`, head_dim > 256 full-causal no-softcap — keeps
  the big-head global layers O(t) too, so they don't re-impose the t² peak), else
  **eager**. Only eager blocks build the `[t, t]` bias.
- **Validation:** the default fp32 `qlora_validate_native.py` exercises *eager*
  (mem-efficient kernels need fp16/bf16). To validate flash+SDPA, run with
  `--compute-dtype bfloat16`; expect a slightly looser match than fp32 eager, still
  high argmax agreement. Relies on right-padding (which `collate` guarantees).

**Two upstream Gemma4 native-forward fixes (needed for the validate oracle / live
sampling on GPU, hit while running the gate on gemma-4-12B):**
- `architecture/gemma4.py` `_prepare_noncausal_mm_spans`: built boundary tensors
  with CPU literals and cat'd them with a CUDA tensor → device-mismatch crash on
  any GPU text forward. Now built on `ids.device`.
- `modules/attn.py`: the no-cache SDPA fallback (taken for `head_dim > 256` since
  the `bighead` kernel is paged/cache-only) returns a transposed, non-contiguous
  `[b, t, nh, hd]`; `o.view(...)` → `o.reshape(...)` in both `decode_flash_attn`
  paths. (xformers is NOT required — it's optional and was ABI-mismatched in the
  venv; the SDPA fallback is correct, just slower.)

Status: flash/SDPA path is GPU-only (CPU suite covers the eager reference). The
bf16 flash/SDPA path itself is **run-confirmed indirectly** — the Gemma4-12B
training run below descends cleanly in bf16 (which engages flash+SDPA) — but the
dedicated bf16 `qlora_validate_native.py --compute-dtype bfloat16` parity pass is
still worth running once (see Session 6 open items).

---

### Session 6 — Gemma4 run-confirmed end-to-end; tooling (logging, dual-eval, UX)

> Branch `claude/confident-goodall-9bnuwp`. Long session. Turned the Gemma4
> support into a confirmed working trainer on real hardware (gemma-4-12B-it 4bpw)
> and built out the run-quality tooling. Everything below is **run-confirmed on
> the box (1×GPU and 2×GPU DDP)** unless marked otherwise.

**Headline: QLoRA-on-EXL3 works on Gemma4-12B.**
- Forward parity gate PASSED (fp32): `qlora_validate_native.py` on gemma-4-12B-it
  4bpw → **100% per-position argmax agreement** vs exllamav3's own forward,
  last-token `cos ≈ 0.999998`, `max|Δ| ≈ 0.08`.
- Training run confirmed (semancy, 1×GPU r16/α32 lr1e-4 cosine, and 2×GPU DDP
  lr5e-5 eff-batch16): clean descent (train 5.1→2.4), held-out `test` **2.51**
  (vs the 1B's ~3.09 floor — bigger base is the lever, as predicted). The
  wikitext dual-eval *also* dropped during the philosophy SFT = **positive
  transfer, not forgetting** (watch for the eventual crossover under harder/longer
  training — that's the forgetting signal the dual-eval exists to catch).

**The decisive Gemma4 bug (and two upstream fixes):**
- **`layer_scalar`** — Gemma4's `TransformerBlock` carries
  `key_layer_scalar="layer_scalar"` and multiplies the whole residual stream by a
  learned per-layer scalar at block end (`transformer.py:222`). Omitting it made
  the forward per-block-correct but **garbage over 48 layers** (0% argmax,
  cos~0). Now read via `backbone.block_metadata["layer_scalar"]` and applied in
  `_block_forward`. This was *the* fix that took the validate from FAIL → PASS.
- **`architecture/gemma4.py`** — `_prepare_noncausal_mm_spans` built boundary
  tensors with CPU literals and `cat`'d them with a CUDA tensor → device-mismatch
  crash on any GPU text forward. Build on `ids.device`.
- **`modules/attn.py`** — the no-cache SDPA fallback (reached for `head_dim>256`;
  Gemma4 global layers, since the `bighead` kernel is paged/cache-only) returns a
  transposed non-contiguous tensor; `o.view(...)` → `o.reshape(...)` in both
  `decode_flash_attn` paths. (xformers is **not** required — it was ABI-mismatched
  in the venv; the SDPA fallback is correct, just slower.)
- `sm_scale=1.0` for Gemma4 (vs Gemma2/3 `query_pre_attn_scalar**-0.5`) is
  confirmed correct as-is (read from the module; the ~perfect cosine proves the
  query scaling is folded into the weights).

**FlashAttention-2 fast path is now per-block + visible:**
- `_block_forward` picks **flash** (head_dim≤256), **SDPA** (head_dim>256
  full-causal no-softcap — keeps Gemma's big-head global layers O(t)), or **eager**
  per block; `describe_attn()` prints the plan at startup (e.g.
  `attn: 40×flash, 8×sdpa [impl=auto, flash_attn available]`). `--attn-impl
  {auto,eager,flash}` on the trainers + validate. (Fixed a cosmetic bug where the
  summary mislabeled everything `eager` because it tested `block.device.type`
  on a device *string*; the forward itself keys off the live `hidden.is_cuda` and
  was always correct.)

**Run-quality tooling added this session (all three arms — native single, DDP,
BNB — unless noted):**
- **`--run-log` CSV (default `qlora_runs.csv`)** — one metadata row per run,
  written on normal finish AND Ctrl-C (`status=completed|interrupted`): model,
  arch, all hyperparameters, eff-batch, train/val/eval2 sizes, start/end train
  loss, **start_val/start_eval2 (baseline)**, best_val + best_val_step,
  final_val/final_eval2, total_s, s_per_step, sup/tot tok/s, peak VRAM. Shared
  `append_run_log`+`RUN_LOG_FIELDS` in `qlora_train_native.py` (DDP imports; BNB
  inlines an identical copy). **Self-heals** on schema change: if an existing
  file's header differs it moves the old file to `<path>.bak` and starts fresh.
- **Live rolling tok/s** on the per-step line (`ThroughputMeter`, train-step
  compute only); `[PERF]` now reports both supervised and total tok/s.
- **`--shuffle` / `--shuffle-seed`** — deterministically shuffle rows before the
  `--val-frac` carve. With `--eval-split` (a real test split) train is shuffled
  and the split is preserved (they're separate `load_dataset` calls).
- **Second eval set** — `--eval2-dataset` (+ `--eval2-split` / `--eval2-config` /
  `--eval2-text-key` / `--eval2-max-samples`). With `--eval2-text-key` it's a
  plain-text LM loss over packed `seq_len` blocks (e.g. wikitext); `--eval2-config`
  supplies the HF config (`wikitext-2-raw-v1`). Each block now starts with **one
  BOS** when the model uses one (gated on `bos_token_id`; Qwen → none), so the
  absolute LM number is meaningful, not just the trend. `build_lm_examples` shared
  (native) / inlined (BNB) with matched tokenization, so EXL3-vs-NF4 is comparable.
- **Baseline (step-0) eval** — when an eval set is selected, the held-out (and
  eval2) loss is computed once before step 1 (no-op adapter = base model) and
  printed `[eval] step 0 (baseline): ...`; logged as `start_val`/`start_eval2`.
  Training timer + VRAM peak (re)start after it.
- **No more "looks hung after Done."** — the post-loop final eval is reused from
  the last in-loop eval when it landed on the final step (else computed once with
  a `-- computing final held-out eval (GPU busy, not hung) ...` notice). Was a
  duplicate full pass on a big model.
- **torchrun redirect** — `qlora_train_native.py` launched under torchrun
  (RANK/WORLD_SIZE in env) exits with a one-line pointer to the DDP script instead
  of an argparse wall (the intuitive `--parallel ddp` footgun).

**Throughput note:** native EXL3 training is ~136 tok/s (1×) / ~215 tok/s (2×GPU
DDP, all-ranks est) on the 12B — correctness-first, not speed-tuned (trellis
reconstruction ×3 under checkpointing + SDPA on the big-head global layers). The
`[PERF]`/`s_per_step` CSV columns are there to track this across configs.

**Open items / next day:**
1. **Run the bf16 parity pass**: `qlora_validate_native.py --compute-dtype
   bfloat16` on gemma-4-12B to formally confirm the flash/SDPA logits vs native
   (expect looser than fp32 — ~0.99x cos — but high argmax). Confirms the
   `attn:` line shows flash actually engaging.
2. **Matched EXL3-vs-NF4 Gemma4 run** (the flagship): same flags on
   `qlora_train_bnb.py` (point `--model` at bf16 HF Gemma4); compare held-out
   floors + the run-log rows. Note BNB lacks `--prompt-format`/Gemma specifics —
   verify the chat formatting matches.
3. **Qwen3.5 / 3.6** remain unsupported — they need a differentiable **Gated
   DeltaNet** (linear/recurrent attention; ~3/4 of layers). This is the open
   research frontier; start with a single-layer forward-parity check against
   exllamav3's `GatedDeltaNet` before committing to the backward.
4. Speed: if wall-clock matters for long runs, profile trellis-reconstruction vs
   SDPA-big-head cost; a fused/ cached reconstruction or training-time flash for
   head_dim>256 (when a kernel supports it) are the levers.

### Session 7 — retained checkpoint history (`--checkpoint-every`) + the three save modes clarified

> Goal: keep a rollback-able history of the LoRA across a run, not just one
> latest/best/endpoint copy. Also pinned down the "is it still saving the lowest
> held-out val?" question.

**The three save modes are now distinct (single-GPU + DDP):**
| Flag | Where it writes | Behavior |
|---|---|---|
| `--save-every N` | `--out` (overwritten) | One **latest** copy, refreshed every N steps. |
| `--save-best` | `--out` (overwritten) | One **best-val** copy; only rewritten when the **PRIMARY** held-out eval improves (`val_examples` from `--eval-split`/`--val-frac`; eval2/wikitext does NOT drive it). |
| **`--checkpoint-every N`** (NEW) | `--out/checkpoint-<step>` (retained) | A **history** — each is kept, never overwritten. Roll back / pick from any. |

- **`--checkpoint-every N`** saves the adapter to `--out/checkpoint-<step>`
  (zero-padded 8-wide so `ls` sorts numerically) every N steps, independent of the
  other two modes. **`--keep-checkpoints K`** caps retention (delete oldest;
  `0` = keep all) — matters under `--train-embeddings/--train-head` where each
  checkpoint carries the big embed/head matrices, not just the few-MB LoRA.
- Shared helpers `checkpoint_dir()`/`list_checkpoints()`/`prune_checkpoints()` live
  in `qlora_train_native.py`; the DDP script imports them and writes from rank 0
  only with a `dist.barrier()` (same single-writer pattern as `save()`). Not yet
  mirrored into the BNB arm (separate venv; add if a matched run needs it).

**Full resume (`--resume` now restores optimizer + LR schedule + step):** every
save target (the best at `--out`, a `--save-every` copy, and each
`--checkpoint-every` dir) now also writes a small **`trainer_state.pt`** beside
the adapter (AdamW state_dict + `LambdaLR` state + `step` + `best_val`/`ema`). On
`--resume <dir>` the trainer loads it (when present) and **continues**: the
optimizer moments, the warmup/cosine position, and the step counter all pick up
where they left off, instead of the old behavior of cold-restarting the schedule
from step 0 (which would replay warmup mid-run — wrong for the short 56-step
semancy cosine). `--reset-optimizer` keeps the old weights-only behavior (use when
changing LR/schedule or resuming across a different GPU count / device topology).
A dir with only adapter weights (a pre-Session-7 checkpoint or a foreign PEFT
adapter) falls back to weights-only automatically. Helpers
`save_trainer_state()`/`load_trainer_state()`/`restore_optimizer_state()` are
shared (DDP imports them); under `--parallel split` `restore_optimizer_state`
moves each AdamW tensor onto its param's device (params span GPUs); under DDP
every rank loads the same rank-0 state (ranks are identical after each
all-reduce). `torch.load(weights_only=False)` since it's our own trusted file.
**Write-confirmed only** (no torch in the container) — smoke a stop/resume on the
box: run a few steps with `--checkpoint-every`, Ctrl-C, then `--resume
<out>` and confirm the printed `continuing at step N` + LR match where it stopped.

**Two ergonomics fixes (during the live gemma-4-31B run):**
- **`--eval2-max-blocks N`** — caps the number of packed eval2 LM blocks directly
  (wikitext packed into 285 blocks at seq-len 1024, swamping the 116-example
  primary `test` set). `--eval2-max-samples` only caps *source rows*, which is
  unpredictable after packing; `--eval2-max-blocks 116` sizes eval2 to ~match the
  primary set. Added to `build_lm_examples` (shared, so DDP gets it via import) +
  both trainers' CLI. (BNB arm inlines `build_lm_examples` — mirror there if a
  matched run needs it.)
- **Text cleaning is now opt-in (`--clean-text`), was opt-out (`--no-clean-text`).**
  The default is now **no cleaning** — right for the reasoning/code/markdown data
  these runs mostly use (brackets and paragraph structure are content). Pass
  `--clean-text` to strip `[stage directions]`/`*actions*` + normalize whitespace
  for play-script style sets. `--no-clean-text` is kept as a **deprecated no-op**
  (warns once) so existing commands don't break — drop it from new commands. Both
  trainers; the BNB arm still has the old `--no-clean-text`-on-by-default (flip it
  there too for a matched run).

**Chunked-vocab LM head (`--head-vocab-chunk N`) — relieves the output-card OOM
on big-vocab models.** The gemma-4-31B split run OOM'd on cuda:1 at the **first
training step**, inside the head-weight reconstruction (`get_weight_tensor` →
`preapply_had_r`, a **5.25 GiB** fp32 spike for the 262k-vocab head): the fused CE
reconstructed the whole `[hidden, vocab]` head at once on the output device, on
top of the grad graph. (Eval survived because it ran under `no_grad`.)
- **Fix:** reconstruct + matmul the head in **vocab-column tiles**. The EXL3 kernel
  already slices (`ext.reconstruct_slice`, 128-aligned); the three head transforms
  are all slice-safe at that granularity (`preapply_had_l`/`su` mix only the input
  dim; `preapply_had_r` is **block-diagonal over the output dim at `had_n`=128**;
  `sv` is per-column) — so a 128-aligned column slice reconstructs **bit-identically**
  to the matching slice of the full weight. New `LinearEXL3.get_weight_tensor_slice`,
  exposed via `backbone.head_weight_slice_closure` (falls back to plain column
  indexing for a dense head).
- **`FusedLinearCrossEntropyVocabChunked`** (fused_ce.py) computes the **same loss
  and grad** via an **online softmax** (per-token running max/sum across vocab
  chunks) + a two-pass backward that reuses the saved per-token LSE. Loop is
  **vocab-outer, token-inner**, so each weight chunk is reconstructed exactly once
  per forward and once per backward — **total dequant work = the single-shot path,
  no extra cost**. Peak head memory drops from `~[hidden, vocab]` to
  `~[hidden, chunk]` (+ a `[token_chunk, chunk]` logits tile): at `--head-vocab-chunk
  32768` on the 31B that's the 5.25 GiB spike → ~0.7 GiB. Wired into `compute_loss`
  (frozen-head path only; `train_head`/final-softcap still take the materialized
  path) behind `--head-vocab-chunk` (single + DDP; `NativeLlamaQLoRA(head_vocab_chunk=)`).
  **Default 0 (off)** — opt in after validating.
- **Validation:** the loss + analytic grad were checked against naive CE
  (finite-difference, all vocab/token-chunk combos, ignore-index) — **algorithm
  confirmed**. The torch autograd Function is gradchecked in `tests/test_fused_ce.py`
  (`test_vocab_chunked_*`, incl. *bit-identical to the single-shot fused head*) —
  **run on the box** (no torch in the container). The EXL3 slice reconstruction is
  GPU-only and is now gated automatically: **`qlora_validate_native.py` runs a
  head-slice check** (`get_weight_tensor()[:, a:b]` vs `get_weight_tensor_slice(a, b)`
  at the first/middle/last aligned chunk; expects bit-identical, folds into the
  PASS/FAIL and the non-zero exit, SKIPs for an unsliceable head, `--skip-head-slice-check`
  to opt out). So the standard pre-run gate already covers it; then run
  `python tests/test_fused_ce.py` for the autograd gradcheck and a 1-step train
  smoke with `--head-vocab-chunk 32768` (watch cuda:1 peak drop and the loss match
  an off run). Once trusted it should let you **drop the `--use-per-device` juggling
  and raise `--batch`/`--seq-len`**.

**Re "was it still only saving the lowest held-out val?" — diagnosis (no
regression):** saving the lowest val is **opt-in via `--save-best`**, not the
default; without it a run saves the **endpoint** ("Done."). With `--save-best`
the logic is intact (`qlora_train_native_ddp.py` best-tracking branch), but the
`[best step N, val …]` line only prints when the val *improves*, so once the
held-out curve plateaus/rises (the Gemma4 run flattened ~step 30) it stops
printing those lines even though the earlier best checkpoint is correctly kept.
So a DDP run "not indicating it anymore" = either `--save-best` wasn't passed, or
it was and the eval had already plateaued. `--checkpoint-every` sidesteps the
reliance on a single best/endpoint adapter.

**Status: write-confirmed** (helpers unit-tested for ordering + prune; both
scripts parse). Not yet exercised on the GPU box — smoke it with a small
`--checkpoint-every` + `--keep-checkpoints` on the next run.

**Big-run plan: gemma-4-31B-it on semancy, layer-split across 2×24GB**
(`qlora_train_native.py --parallel split`, single process — NOT ddp, which would
replicate the ~17 GB base per card). The recommended invocation reuses the
established r16/α32 lr1e-4 cosine profile + the Gemma4 specifics
(`--sample-every 0` to avoid the SWA/recurrent cache path, `--no-clean-text`,
`--messages-key messages`, `--eval-split test`, auto prompt/attn) + the wikitext
dual-eval + `--checkpoint-every`. Run the forward-correctness gate **under the
same split** first (`qlora_validate_native.py --parallel split --use-per-device
8 24 --check-backward`) — first 31B Gemma4 on the device-aware split forward, so
prove parity before the run. **Greedy-autosplit footgun:** the 17 GB base fits
one card, so without a per-device cap the whole model lands on cuda:0 and cuda:1
idles — `--use-per-device 8 24` caps cuda:0 near half the base to force the split;
watch the per-card VRAM line and tune (the 262k-vocab head is end-heavy on
cuda:1). **Not yet run** — the gate result + the held-out `test` floor (vs 1B
~3.09 / 12B 2.51) are the first things to record next session.

**MTP note:** gemma-4-31B's checkpoint may carry MTP tensors, but exllamav3's
`gemma4.py` registers only `{"text", "vision"}` components (no `"mtp"`), so MTP is
**not loaded** — our training path (`component="text"`) never touches it, and it's
not wired for inference on this arch either. No special handling needed; nothing
breaks. The real consideration is downstream: fine-tuning the trunk shifts its
hidden states, so a *frozen* MTP draft head's speculative-acceptance rate would
drift — retraining MTP alongside would need (a) a Gemma4 `"mtp"` component in
exllamav3 and (b) a differentiable MTP forward + multi-token loss in our path
(neither exists). MTP speeds up *inference* (self-speculative decoding), not
training.

---

### Session 8 — 8k context on 2×3090: long-context OOM, run-confirmed but BARELY (more to do)

> Goal: train gemma-4-12B-it 3bpw QLoRA at **`--seq-len 8192 --pack`**, r64/α64,
> `--parallel split` across 2×24GB (RTX 3090), batch 1, 262M trainable params.
> End state: **running, but on the ragged edge** of cuda:1 — see open items. Three
> structural fixes landed this session; one more (query-tiled big-head attention)
> is the next lever. This note supersedes the earlier incremental framing in the
> commit history (notably the "ride the mem-efficient backend" idea, which was
> wrong — see below).

**The arch (confirmed from `config.json`).** `head_dim: 256`,
**`global_head_dim: 512`**, `num_attention_heads: 16`, `num_key_value_heads: 8`,
`hidden_size: 3840`, `vocab_size: 262144`. So 40 sliding layers are head_dim 256
(→ `flash`) and **8 global (full-attention) layers are head_dim 512** (→ `sdpa`).
`describe_attn()` → `40×flash, 8×sdpa`.

**The real wall: head_dim 512 has NO O(t) attention kernel on Ampere.** FA2 caps at
256 (`flash_attn_2.py`: `dim > 256 → None`); torch's mem-efficient SDPA backend
**also caps at 256**; exllamav3's `bighead_scalar` is inference-only (needs a KV
cache + `q_len < 8`). So the 8 global layers **always** run the SDPA **math**
backend, which materializes the `[nq, L, L]` score matrix **in fp32** (the math
backend upcasts regardless of input dtype). At L≈8k that is ~4 GB *per global
layer*. Grad-checkpointing keeps one layer live, so the peak is one such matrix —
fine **if the card has room**, fatal when it doesn't. **This is exactly how
HF/Axolotl run gemma-4 too** (they eat the same O(t²) math on the global layers);
they fit a 31B at 8k only because everything *else* is lean. Our OOM was never the
4 GB itself — it was that cuda:1 was already maxed.

**Confirmed culprit allocation:** the OOM was `Tried to allocate 3.97 GiB` in the
backward = `16 × 8161² × 4 bytes` exactly — a near-full **single-document** packed
block (one ~8.2k-token doc) hitting a head_dim-512 global layer. The score matrix
scales with the **longest document in a block**, not the block size.

**Correction to the earlier framing (important for next time):** the
`sdpa`-branch changes that "keep the mem-efficient backend eligible" (per-document
`is_causal`, no mask, **hand-expanded GQA**) were built on a false premise —
**the mem-efficient backend never engages at head_dim 512**, so those layers are
always math. What actually helped: (a) the **per-document split** still matters
(it bounds the math score matrix to the longest *document* instead of the full
8192 block); but (b) the **GQA `repeat_interleave` expansion is now pointless
overhead** for head_dim 512 (math handles GQA via `enable_gqa`) — see open items.

**Three fixes that got it running (in order of impact):**
1. **bf16 activations (the big one).** The matmuls already ran in `compute_dtype`
   (the QLoRA linear casts input + reconstructs the frozen weight in bf16), but
   `_block_forward` then **upcast every activation back to fp32** via `.float()`
   (q/k/v, ctx, attn_out, mlp_out) and kept the **whole residual stream in fp32** —
   ~2× the memory of an HF/Axolotl bf16 forward. *That* was the structural reason a
   12B needed two cards where Axolotl fits a 31B. Fix: drop the `.float()` upcasts
   so activations follow `compute_dtype`; keep fp32 only where it matters — `_norm`
   and `_apply_rope` compute internals in fp32 but **return in the input dtype** (HF
   RMSNorm convention); the eager *reference* path still does scores/softmax in fp32;
   the **final** norm returns fp32 so the head/CE dtype contract is unchanged;
   `layer_scalar` is cast back to the residual dtype (an fp32 scalar would re-promote
   the whole stream). ~Halves activation + grad-checkpoint + attention-backward
   memory. **Bit-identical in fp32** (every new dtype op is a no-op when
   `compute_dtype` is fp32), so the fp32 validate gate and the fp32 CPU block tests
   are unaffected. NOTE: bf16 does **not** shrink the math score matrix (it stays
   fp32) — it frees everything *else* so that spike has room.
2. **`--optim {adamw,adamw8bit,paged_adamw8bit}`** (`build_optimizer`). `torch.AdamW`
   keeps `m`/`v` in fp32 = 8 bytes/param = ~2.1 GB for the 262M-param r=64 adapter,
   allocated lazily on the **first `optimizer.step()`** — which is why an early run
   passed step-0 eval, trained a few steps, then OOM'd at the first *in-training*
   eval (the moments had materialized). bitsandbytes 8-bit moments → ~2 bytes/param
   (~4× less, ~1.6 GB freed at r=64; `paged_` also offloads to host on a spike).
   Negligible quality cost (QLoRA paper uses paged 8-bit Adam). Default stays
   `adamw`. Needs `bitsandbytes` in the venv. **Native trainer only so far.**
3. **Per-document SDPA under packing** (`sdpa` branch): gather non-pad tokens, loop
   `is_causal` SDPA per document span (`pack["cu_seqlens"]`), scatter back — bounds
   the math score matrix to the longest document. `pack_ctx` feeds both `flash` and
   `sdpa`; the old explicit-`[t,t]`-mask path is gone. FlexAttention was tried first
   and does NOT fit a 24GB consumer SM at head_dim 512 (`No valid triton configs …
   Required: 200704, limit: 101376`) — removed.

Also fixed this session: a **corrupted #100/#101 squash-merge** had left
`native_llama.py` with dangling `_flex_*` references (NameError at construction);
master was repaired (`3f28d48`).

**Current run config (run-confirmed, barely):** `--parallel split --use-per-device
9 24 --seq-len 8192 --pack --r 64 --alpha 64 --head-vocab-chunk 32768 --optim
paged_adamw8bit --scheduler cosine`. Split = `{cuda:0: 36 blocks, cuda:1: 12
blocks + final norm + head}`; **cuda:1 is the constraint** (it carries the 262k
head *and* 2 of the 8 global layers, so a long-doc block spikes ~4 GB right where
free memory is tightest). Loss descends cleanly (4.1 → 2.4 by step 5).

**Open items / next session (in priority order):**
1. **Query-tiled big-head attention — THE next lever.** Bound the global-layer
   score matrix to `[16, q_tile, L]` (e.g. q_tile=2048 → ~1 GB vs ~4 GB) with a
   flash-style online-softmax accumulation so **both forward and backward** stay
   bounded (a naive query loop re-bloats the backward unless it's a custom
   `autograd.Function` or nested-checkpointed per tile). This makes head_dim 512 @
   8k fit with real margin regardless of document length, and is what unlocks
   higher rank (128, like the confirmed 2×3090 runs) / longer context.
2. **Drop the pointless GQA expansion** in the `sdpa` branch. Since head_dim 512 is
   always the math backend, `repeat_interleave(KV → nq)` just wastes memory — revert
   to `enable_gqa=True` (math handles GQA, keeps K/V at `nkv` heads). Small win, but
   free, and fold it into the query-tiling rewrite.
3. **Rebalance the split off cuda:1.** It holds the head + 2 global layers. Either
   force the global layers onto cuda:0, or lower `--head-vocab-chunk` to 8192
   (~375 MiB more margin), or shift blocks via `--use-per-device`.
4. **Mirror `--optim` into the DDP + BNB arms** for matched EXL3-vs-NF4 runs.
5. **bf16 parity gate** still worth running once: `qlora_validate_native.py
   --compute-dtype bfloat16` (the `flash`/`sdpa` paths run only in fp16/bf16).
6. **Throughput**: layer-split is serial (cuda:0 100% / cuda:1 0% see-saw); true
   overlap needs pipeline-parallel micro-batching, not built. ~420 tok/s is near the
   floor for this split. Not memory-related, but the next efficiency frontier after
   query-tiling.

---

### Session 9 — bf16 flash/packing parity gate CLOSED; review pass + doc/comment fixes

> Branch `claude/exllama-qlora-review-xginxq`. A review of the whole QLoRA-on-EXL3
> body of work, plus the bf16 packing verification that had been the standing
> open item since Session 6, plus two box-free code/doc accuracy fixes.

**bf16 forward parity is now confirmed for the flash + packing path (was the #1
open verification gap).** Run-confirmed on the box:
- **`qlora_validate_native.py --check-packing --compute-dtype bfloat16`**:
  `attn: 16×flash` with packing **PASS** — 100% per-position argmax agreement,
  last-token `cos ≈ 0.99996`. This is the first time the bf16 *flash* path (not
  just fp32 eager) is differenced against exllamav3's own forward, and the first
  with sample packing engaged.
- **`tests/test_native_llama.py`**: packing **document-isolation** + **pad-NaN**
  checks PASS.
- **bf16 `--pack` training run** (4000 docs → 1413 packed blocks, **82.5% filled**)
  descends cleanly on `16×flash`, grad norms 7–30, `|B|` climbing — confirming the
  **flash-varlen backward** and the **`o[keep] = of` scatter under
  grad-checkpointing** (a real risk area: a custom scatter inside a checkpointed
  block, re-run on recompute).

**Remaining parity sub-gate (precise scope):** the verified run is `16×flash`, i.e.
**all head_dim ≤ 256 — no `sdpa` blocks exercised**. The **big-head `sdpa` path in
bf16** (Gemma4's 8 global layers, head_dim 512, the per-document SDPA loop) is still
only validated *indirectly* via the 12B/8k training descent. To close it the same
way, run `qlora_validate_native.py --compute-dtype bfloat16` on a **Gemma4** base so
`describe_attn` reports `…×sdpa` and the gate covers those blocks. Lower risk than
flash was (plain `is_causal` SDPA, no custom scatter) — but it is the last
uncovered attention branch, and it would **also** serve as the verification for the
pending GQA-expansion removal (next item).

**Code/doc accuracy fixes this session (box-free, no numeric change):**
- **`native_llama._block_forward` (`sdpa` branch) — comment corrected.** The old
  comment still claimed the per-document SDPA "keeps the mem-efficient backend
  eligible" via hand-expanded GQA + no mask. Session 8 established that head_dim 512
  *always* hits the SDPA **math** backend (mem-efficient/flash cap at 256), so that
  rationale was wrong. Comment now states the reality; the `repeat_interleave` GQA
  expansion is annotated as **pure overhead pending removal** (the math backend
  reads `enable_gqa` directly). **The expansion itself was intentionally left in
  place** — removing it changes the attention path and there were no test runs to
  confirm it; do it in the query-tiled big-head rewrite (Session 8 open #1/#2) and
  cover it with the bf16 Gemma4 `sdpa` gate above.
- **Gemma2 `--head-vocab-chunk` no-op warning.** `compute_loss` routes any model
  with final-logit softcapping (Gemma2) to the materialized supervised-position head
  path *before* the vocab-chunk branch, because the chunked-vocab CE can't apply the
  tanh cap — so `--head-vocab-chunk` is silently a no-op there. That is exactly the
  case you'd want it (Gemma2 = 256k vocab + softcap). `NativeLlamaQLoRA.__init__` now
  prints a one-line heads-up so the bypass isn't silent; **no loss-path change**.
  (A real fix would be a softcap-aware chunked CE — not built; flag if Gemma2 with
  long supervised spans becomes a target.)

**Review findings still open (carried forward, unchanged):**
- **bf16 `sdpa` big-head parity gate** on Gemma4 (above) — the one real remaining
  correctness check.
- **Drop the GQA `repeat_interleave`** in the big-head `sdpa` path (free margin on
  the constrained card; do it with the query-tiling rewrite, verify via the gate).
- **Mirror `--optim {adamw,adamw8bit,paged_adamw8bit}`** into the DDP + BNB arms
  (currently native-single-GPU only) so a matched EXL3-vs-NF4 flagship run has equal
  optimizer-state memory. (Session 8 open #4.)
- **Micro-nit:** `EXL3LoRAFunction.backward` reconstructs the frozen weight and
  computes `grad_x` *before* checking `needs_input_grad[0]`; the reconstruction is
  wasted when `grad_x` isn't needed. In practice the first wrapped linear's input
  always requires grad, so cost ≈ 0 today — noted only for completeness.

**Next (box runs, when you're running again):**
1. The bf16 Gemma4 `sdpa` parity gate (closes the last correctness hole).
2. A real packed run with a **held-out eval** to quantify the tok/s win from `--pack`
   and confirm the loss floor is unchanged vs unpacked.
3. The low-bitrate flagship (EXL3 2.5/3bpw where NF4 can't follow, on a real
   metric) — still the highest-value *unrealized* result (§0d).

#### Session 9 (cont.) — VRAM-efficiency research + feature A: CPU-offloaded embed/head optimizer

Researched VRAM-efficiency techniques across Axolotl / Liger / torchao / DeepSpeed /
unsloth and mapped them onto this repo (see chat log for the full sourced writeup).
Net gaps vs Axolotl: fused RMSNorm/SwiGLU/RoPE kernels (Liger), CPU activation
offloading (unsloth/torchtune), and a CPU-offload optimizer. The hot path's fp32
hygiene is already correct (norm reductions / softmax / CE fp32; activations bf16
since Session 8), so the precision wins are confined to the trained embed/head.

**Feature A — `--offload-embed-head-optim` (native single-process trainer; RUN-
CONFIRMED on the box).** Puts the fully-trained embedding / LM-head optimizer
on CPU via **torchao `CPUOffloadOptimizer`** with **bf16 stochastic-rounding** master
weights, so the ~12 bytes/param of Adam state for the (huge, untied ~0.8B-each)
embed/head matrices never sits on the GPU — only the bf16 param + transient grad do.
- **Two-optimizer split** (`qlora_train_native.py`): LoRA stays on the existing
  AdamW/8-bit + `LambdaLR` + grad-clip path; the embed/head group goes on
  `CPUOffloadOptimizer(ms_params, partial(torchao.optim.AdamW, bf16_stochastic_round=
  True))` (state-only offload — NOT `offload_gradients`, so grad-accum still works).
- **Constraints handled** (from torchao's docs): it's a wrapper with no LR-scheduler
  support and **forbids grad clipping on its params** → embed/head are excluded from
  `clip_grad_norm_` (only LoRA is clipped), and the schedule's LR is **mirrored** onto
  the offload optimizer each step so embed/head track the LoRA LR. `save/load_trainer_
  state` round-trips its state under a separate `offload_optimizer` key (absent in
  pre-offload checkpoints → loads fine). Weights are loaded (line 946 `load_adapter`)
  before the optimizer is built, satisfying torchao's "load weights first" rule.
- **bf16 master** requires the params to be bf16: `NativeLlamaQLoRA(modules_to_save_
  dtype=bfloat16)` (fp32 otherwise). The `--train-head` CE now upcasts logits to fp32
  (no-op for an fp32 head; essential for a bf16 one — a bf16 softmax over a big vocab
  is unstable).
- **Scope:** single-process only (torchao is single-GPU; should also cover
  `--parallel split` since that's one process — verify). NOT wired into the DDP arm.
  Needs `pip install torchao` in the venv.
- **Residual uncertainty (must smoke-test):** whether `CPUOffloadOptimizer` forwards
  `lr=`/composes with the `partial`-bound `bf16_stochastic_round` exactly as assumed,
  and whether it composes with `--parallel split` (params on cuda:0/cuda:1). Smoke:
  ```
  python training/qlora_train_native.py --model <exl3> --dataset <small> \
      --train-head --train-embeddings --offload-embed-head-optim \
      --steps 5 --batch 1 --checkpoint-every 3   # then --resume to confirm round-trip
  #  Expect: loss descends, |B| climbs, embed/head Adam state on CPU (nvidia-smi: the
  #  embed/head optimizer no longer shows on-GPU), resume continues at the right step/LR.
  ```

**Feature B — `--lora-embed` / `--lora-head` (RUN-CONFIRMED on the box).**
The low-rank alternative to fully training the embedding / LM head: a rank-r *shift*
(`r*(vocab+hidden)` params vs `vocab*hidden`), trained through **ordinary autograd**
(no custom Function — correctness rests on the forward formulas, not a hand-written
backward). Mutually exclusive with `--train-embeddings`/`--train-head` per module.
- **Embedding** (`native_llama.forward`): `hidden += scale * (F.embedding(ids, A) @ B)`
  with `A=[vocab,r]` (token-indexed, so only rows for tokens in the batch get a
  gradient — sparse/cheap), `B=[r,hidden]` zero-init (no-op at start). Added after the
  base embed scaling; the from-zero B absorbs any constant factor.
- **Head** (`native_llama.compute_loss`): routes to the materialized supervised-
  position path (like `--train-head`) and adds `scale * (hs @ A) @ B` to the frozen
  head's logits, in fp32, with `A=[hidden,r]`, `B=[r,vocab]` zero-init. Memory scales
  with supervised tokens (the chunked-vocab fused head is frozen-only, so it's bypassed
  when `lora_head` is on — fine, the delta needs full logits at the supervised rows).
- Params ride in `lora_parameters()` (GPU-resident, optimized by the main optimizer,
  included in the grad clip; small, never offloaded). Saved to a **separate**
  `lora_modules.safetensors` (merge-path, like `modules_to_save.safetensors`) so the
  runtime per-linear LoRA loader is undisturbed; `load_adapter` restores it and now
  tolerates a missing `adapter_model.safetensors` (embed/head-only checkpoints).
  `adapter_config.json` records `lora_embed`/`lora_head`.
- **Live `🎭` samples / native infer do NOT reflect embed/head LoRA** (only the
  runtime per-linear LoRA slots are wired) — same as `--train-head`/`--train-embeddings`;
  judge via the held-out eval (`compute_loss` includes both deltas) or after a merge.
- Smoke: `--lora-embed --lora-head --steps 5 --batch 1 --checkpoint-every 3`, then
  `--resume` to confirm the `lora_modules.safetensors` round-trip; loss should descend.

**Feature C — `--offload-activations` + `--use-liger` (RUN-CONFIRMED on the box).**
The two general (model-agnostic) VRAM levers.
- **Activation offload** (`--offload-activations`): wraps the decoder block loop in
  torch's built-in `torch.autograd.graph.save_on_cpu(pin_memory=True)`, so the
  grad-checkpointed block-boundary activations saved for backward are parked in CPU
  RAM. Needs gradient checkpointing + CUDA. **Numerically identical by construction**
  (save_on_cpu only relocates saved tensors), so it needs no parity gate — only a
  VRAM/throughput check. Synchronous copies (no CUDA-stream double-buffering yet, the
  unsloth async refinement), so a modest wall-clock cost for real GPU-memory headroom.
- **Liger kernels** (`--use-liger`): routes RMSNorm (the 2D/3D attn/mlp/post/final
  norms — the 4D per-head q/k/v norm stays torch) and SwiGLU (silu only — GeGLU stays
  torch) through Liger's Triton autograd Functions. RMSNorm uses `casting_mode="gemma"`
  (full-fp32) + `offset=constant_bias` to **match this module's fp32-internal `_norm`
  numerics** for every arch (so it reduces to the validated path); guarded to CUDA +
  fp16/bf16 + `constant_scale==1.0`, with the torch path as fallback for everything
  else. **Changes numerics slightly → MUST run the parity gate first:**
  `qlora_validate_native.py --compute-dtype bfloat16 --use-liger` (the flag is wired
  into the validate script + its backward check). Needs `pip install liger-kernel`.
- Both are opt-in, native-trainer + validate only; eager/fp32/CPU paths untouched.
- Smoke: add `--offload-activations` and/or `--use-liger` to a short run and watch peak
  VRAM drop; for Liger, gate parity first as above.

**A/B/C are now RUN-CONFIRMED on the box (Llama-3.2-1B 4bpw + gemma-4-12B, single
GPU).** All three train, descend, and resume correctly; the bf16 Liger parity gate
passes. Confirmed results + the bugs found and fixed while running them:

- **A (`--offload-embed-head-optim`)**: 547M trainable params (full embed+head on the
  tied 1B) trained at **3.39 GB peak VRAM** — *lower* than the plain-LoRA run's 4.07 GB
  — proving the embed/head Adam state is genuinely off-GPU. Resume round-trips
  (`modules_to_save` + `offload_optimizer` state). Throughput drops (~22→106 tok/s as
  the CPU AdamW warms) — the expected once-per-step CPU cost for the memory win.
  - **Fix while running:** torchao 0.17 has no `torchao.optim.AdamW`; the fp32 clone
    with `bf16_stochastic_round` is **`_AdamW`**. Looked up defensively now.
- **B (`--lora-embed` / `--lora-head`)**: 30.8M trainable params (vs 547M full),
  trains + descends, `lora_modules.safetensors` round-trips on resume. Mutual-exclusion
  guards work.
- **C (`--use-liger`)**: bf16 forward parity gate PASS on Llama (100% argmax, cos
  0.99996) and backward PASS on Gemma4.
  - **Fix while running:** the frozen norm weight is an exllamav3 *inference tensor*;
    Liger saves it for backward → `RuntimeError: Inference tensors cannot be saved`.
    The `w.to(dtype)` cast was a no-op when dtypes matched, so it leaked through —
    now `w.clone()`d. (Caught by `--use-liger --check-backward`; would have broken any
    Liger training run, not just the gate.)
  - **Liger parity finding:** Liger is a *wash* vs the plain-torch norm/MLP path — same
    bf16 noise band (cos ~0.9998), borderline top-1 flips go both ways (Liger better on
    one prompt, worse on another). Not more/less accurate; its win is memory+speed —
    since quantified at real size (§0c Session 12 addendum: +8.8% tok/s, −1.1 GB/GPU,
    identical convergence on the 12B malamus config).
- **C (`--offload-activations`)**: confirmed numerically equivalent; at 1B/seq-2048/
  batch-2 it saved only ~0.07 GB (4.78→4.71) at ~3% slower — small because that config
  is model/optimizer-dominated. The saving scales with seq-len × batch × depth; measure
  it at long context where checkpointed activations dominate.

**bf16 Gemma4 forward finding (the long-open sub-gate, now run):** the bf16 big-head
**SDPA** path (Gemma's 8 global layers, head_dim 512, fp32-math fallback) is close to
native (cos ~0.9998, `max|Δ|` ~0.5–0.9) but **argmax-noisy on borderline tokens** — a
single top-1 can flip vs native, independent of Liger (it flips both ways with/without).
The fp32 gate (100%, cos 0.999998) remains the correctness proof. `qlora_validate_native.py`
now **tolerates a low-precision top-1 flip when argmax-agreement ≥ 0.8 and cos ≥ 0.999**
(fp32 stays strict), so this no longer reads as a spurious FAIL.

#### Session 9 — DONE this session (recap) and OPEN for next session

**DONE (branch `claude/exllama-qlora-review-xginxq`, all merged/pushed):**
- Full review of the QLoRA-on-EXL3 work; recorded the bf16 flash/packing parity
  (`--check-packing`) result that had been open since Session 6.
- VRAM-efficiency research vs Axolotl/Liger/torchao/DeepSpeed/unsloth (sourced; in the
  session log). Net: this repo already has FLCE + packing + grad-ckpt + 8-bit optim +
  bf16 activations; the gaps it filled are below.
- **Three VRAM features built + RUN-CONFIRMED** (native single-process trainer; see the
  detailed blocks above for the design and the bugs fixed):
  - **A** `--offload-embed-head-optim` — embed/head optimizer → CPU (torchao, bf16
    stochastic rounding). 547M params @ 3.39 GB on the 1B; resume round-trips.
  - **B** `--lora-embed` / `--lora-head` — low-rank embed/head training (30.8M vs 547M).
  - **C** `--offload-activations` (torch save_on_cpu) + `--use-liger` (Liger RMSNorm/
    SwiGLU). Liger parity = wash vs torch; offload numerically identical.
- Validate gate now tolerates a low-precision borderline top-1 flip (fp32 strict).

**OPEN — measurements & real-use (NOT correctness; correctness is confirmed):**
1. **Quantify the VRAM wins at scale** — the smoke runs were too small to show C's
   benefit. Do with-vs-without `peak VRAM` diffs at a realistic config:
   - `--offload-activations`: bump `--seq-len 4096/8192` (or `--batch`) — that's where
     it pays (activations dominate; at 1B/2048/b2 it was only ~0.07 GB).
   - `--use-liger`: a sizable run with vs without; compare peak VRAM + tok/s (this gives
     the Liger memory/speed number we don't yet have).
2. **A real training run with `--train-head`/`--lora-head` + an eval** — confirm the
   embed/head training actually *helps* the task (held-out loss), not just that it runs.
   Live samples / native infer do NOT reflect embed/head training — judge via held-out
   eval or after a merge/re-quantize.
3. **`--parallel split` + `--offload-embed-head-optim`** — the one unverified combo
   (torchao offload optimizer with params spanning cuda:0/cuda:1, single process). Run
   the gate first: `qlora_validate_native.py --parallel split --use-per-device 8 24
   --check-backward`, then a short split training run.
4. **Re-run the Gemma `--use-liger` gate** to confirm the softened gate now reports
   `PASS` (`MISMATCH (tolerated: low-precision noise…)`), not FAIL.

**OPEN — could-build-next (nice-to-have, not started):**
5. **Mirror A/B/C into the DDP arm** (`qlora_train_native_ddp.py`). Today they're native
   single-process only. Note torchao's CPUOffloadOptimizer is single-process, so A under
   DDP would need a different offload (per-rank bnb paged, or a hand-rolled CPU optimizer)
   — or just document A as single-process/`--parallel split` only.
6. **Async (CUDA-stream) activation offload** — the current `--offload-activations` is
   torch's *synchronous* `save_on_cpu` (~3% slower here). unsloth's double-buffered async
   version is ~1%. Would replace/augment the save_on_cpu wrap in `native_llama.forward`.
7. **Chunked trainable-head CE** — `--train-head` / `--lora-head` currently materialize
   `[supervised_tokens, vocab]` logits (the vocab-chunked fused CE is frozen-head only).
   Extend `FusedLinearCrossEntropyVocabChunked` to emit a head/LoRA-B gradient so the
   trainable-head path stays memory-bounded on big-vocab models (Gemma 262k).
8. **GQA `repeat_interleave` removal** in the big-head `sdpa` branch + query-tiled
   big-head attention (carried from Session 8 open #1/#2; the bf16 Gemma `sdpa` gate now
   exists to verify it).
9. **Liger for GeGLU** (currently silu-only; GeGLU/Gemma MLP stays torch) and Liger
   RMSNorm on the 4D per-head q/k/v norm (currently torch) — both via the existing
   `--use-liger` guard, if the quantified Liger win (#1) justifies the extra wiring.

**Env note for next session:** torch 2.8.0+cu128, torchao 0.17.0, liger-kernel and
flash_attn installed in the qlora-venv. xformers is ABI-mismatched (ignored; the SDPA
fallback handles big heads). Test models: `$LLAMA1B` (Llama-3.2-1B 4bpw, tied) and
`$GEMMA4` (gemma-4-12B-it, 40×flash + 8×sdpa). Test scratch dir: `$OUT` /
`/mnt/two/Weights/qlora_test`.

---

### Session 10 — softcap-head fixes, the liger grad bug, and the next efficiency item

**DONE (branch `claude/repo-review-u6oe40`, pushed):** four fixes surfaced by a real
Gemma-4-12B (4bpw, 262k vocab, final-logit softcap) `--parallel split` run.

- **Inference-tensor backward crash.** The materialized supervised-position head loss
  (`train_head`/`lora_head`/`final_softcap`) does `hs @ w` with the frozen head weight.
  The EXL3 base loads under `@torch.inference_mode`, so `w` is an inference tensor and
  `hs` requires grad → autograd tries to save `w` for backward → `RuntimeError:
  Inference tensors cannot be saved for backward`. Clone `w` when `torch.is_inference`.
  (Same family as #106's Liger-norm fix, different site.)
- **Softcap-head OOM = #102's fp32 upcast.** #102 changed `logits = hs @ w` →
  `(hs @ w).float()`. On 262k vocab at `--seq-len 8192 --pack` that fp32
  `[~6.5k supervised tokens, 262144]` copy is ~6.7 GB — **double** the fp16 size and the
  single biggest allocation on the head card — and OOM'd cuda:1 by ~160 MB. The matmul
  already accumulates in fp32 internally and CE is stable on fp16 logits, so the full
  upcast bought nothing but the blow-up. Reverted to the pre-#102 head-dtype logits.
- **Exploding grad under `--use-liger` (~1e16 with a healthy ~4.8 loss).** The fused
  RMSNorm call passed only `(X, W, eps, offset, casting_mode)`, so Liger's `in_place`
  arg took its default `True` (signature confirmed:
  `(ctx, X, W, eps, offset=0.0, casting_mode='llama', in_place=True, row_mode=None)`).
  Its in-place backward writes `dX` into the grad-output buffer; with `use_reentrant=
  False` checkpointing + the residual that also consumes the norm's input, that reuse
  corrupts gradients — forward loss stays normal, grad norm explodes, and grad-clipping
  hides it by training on a garbage direction. Pass `in_place=False`. Grad → ~100.
  (Lesson: the `--use-liger` gate was a *smoke* test — backward runs + reaches every
  device — so it never checked grad **values** and couldn't catch this. A liger↔torch
  grad-**parity** check is the real gate.)
- **Diagnosed "won't split across 2 cards" (NOT a bug).** `_load_autosplit` is a *greedy
  fill*: it packs cuda:0 up to its `use_per_device` budget first, then spills the rest.
  With `use_per_device [8, 24]` a ~6 GB 4bpw 12B fits under the 8 GB card-0 budget →
  47/1 blocks, head on cuda:1. The launcher forwarded everything correctly (verified via
  `--dry-run`); `--device cuda:0` is ignored in split mode. Key insight for the item
  below: **even blocks ≠ even memory** — the output card additionally holds the LM head,
  final norm, and (in training) the `[tokens, vocab]` logit spike + CE temporaries, which
  for Gemma is several GB that exists on *no other card*.

**NEXT WORK ITEM — head-aware balanced layer split + chunked head CE (do together).**
These are one effort: the head CE is the spike that pins the output card, so chunking it
is what makes a balanced split achievable. Layer-split is *sequential* (no compute
parallelism) — this is purely a memory/fit lever for scaling seq-len / vocab / model
size, which is the "idle cuda:1 will bite later" concern.

1. **Chunked head CE for `--train-head` / `--lora-head` / `final_softcap`.** Today these
   materialize `[supervised_tokens, vocab]` at once (`FusedLinearCrossEntropyVocabChunked`
   is frozen-head, non-softcap only). Stream the head loss over supervised-token chunks,
   recomputing in backward, while (a) emitting the head-weight / LoRA-B gradient (the
   frozen fused CE gives a hidden-grad only), and (b) applying the tanh softcap **inside**
   the chunk with its Jacobian `1 - tanh(z/cap)^2` in backward. Keep the **head dtype
   (fp16)** per Session 10's revert — do not reintroduce a full-tensor fp32 copy; upcast
   only per-chunk internally if a chunk's softmax needs it. Validate with a CPU gradcheck
   vs `F.cross_entropy(cap*tanh((hs@w)/cap), lbl)` on loss **and** grads (hidden +
   head/LoRA-B), mirroring `tests/test_fused_ce.py`. (Supersedes Session 9 open #7, which
   only covered the non-softcap trainable head.)
2. **Head-aware balanced autosplit.** Replace the greedy fill (for training) with a split
   that balances *peak training memory* per card: estimate per-block cost `b` and the
   output-card-only head cost `h` (head weight + logit spike at the configured
   seq-len/supervised-token estimate + CE temporaries — smaller once #1 lands), then shift
   ~`h/b` decoder blocks *off* the output card onto the others. Compute it dynamically
   from the visible cards (auto when `parallel=split` and no explicit `use/reserve` given,
   or behind a `--balance-split` flag) and realize it as an auto-computed `use_per_device`
   so exllamav3 core's autosplit isn't forked — keep it behind the `backbone` seam. Gate
   with the existing `--check-backward` cross-device smoke plus a peak-VRAM-per-card print.
3. **Liger grad-parity gate (land this first — it's the safety net for re-enabling
   `--use-liger`).** The current gate only smoke-tests that backward runs and reaches
   every device, so it structurally cannot catch a wrong-*value* gradient — which is
   exactly how the `in_place=True` bug shipped. Add a real parity check to
   `qlora_validate_native.py --use-liger`: build two `NativeLlamaQLoRA` with identical
   seed/init on the same batch, one `use_liger=False` and one `use_liger=True`, run one
   `loss.backward()` each, and assert the per-adapter `lora_b.grad` (and `lora_a.grad`
   where nonzero) match within a relative tolerance — plus a loss-parity check. That
   turns the in_place-class of bug into a hard FAIL instead of a healthy-looking loss.
   Small, isolated, and independent of #1/#2; do it before trusting liger's VRAM number.

---

### Session 11 — optimization audit; instrumentation + first efficiency batch

> Branch `claude/qlora-familiarization-gjd9so`. A research pass over the whole
> pipeline for wasted compute/VRAM plus a survey of modern-framework techniques
> (Axolotl / Unsloth / Liger / CCE / Chronicals) — the full audit with sources
> lives in **`doc/qlora_optimization_audit.md`**. Headline findings: trellis
> dequant runs 3× per linear per step (the structural tok/s ceiling);
> checkpointing is unconditional even with VRAM headroom; the fused CE holds a
> full fp32 copy of the head weight (~4 GB on Gemma) and re-casts it per token
> chunk; packing is next-fit (~82.5% fill vs ~98% for FFD); the grad-accum loss
> is mean-of-means (the mild form of the Oct-2024 GA bug); RoPE cos/sin are
> rebuilt ~192× per step on a 48-layer model.

**PLAN for this session (batch 1 — box-free verifiable):**
0. Instrumentation: per-step wall-clock breakdown (data/forward/backward/optim
   via CUDA events), `--profile-dequant`, and run-log v2 — every run INCLUDING
   CRASHES auto-appends a CSV row (status=failed + error summary; full
   traceback to a sidecar `<run_log>.errors.log`), turning the CSV into an
   automatic lab notebook.
1. FFD sample packing (replace next-fit; print fill %).
2. Fused-CE dtype fix (drop the fp32 head-weight copy; upcast per-chunk logits
   only).
3. Grad-accum token-weighted loss normalization (native + DDP + BNB arms).

Results are recorded at the end of this section after implementation.

**DONE (all four items, committed on this branch; container-verified with CPU
torch -- box smoke runs still pending, see below):**

- **Instrumentation.** `StepTimer` splits every step's wall clock into
  data/fwd/bwd/opt: rolling mean on the per-step line (`1.84s: f 52% b 39% o
  8%`), run split on the `[PERF]` line, cumulative `t_*_s` columns in the CSV.
  All three arms; the DDP arm charges the grad all-reduce to `opt` (a fat opt%
  vs single-GPU points at the interconnect). `--profile-dequant N` times every
  trellis reconstruction (hook in `backbone`'s weight closures, incl. head +
  head-slice) for the first N steps and prints its share of step wall time --
  run this ONCE on the box before any dequant-count optimization work; it also
  lands in the CSV (`dequant_s_per_step`).
- **Failure-aware run log.** Any crash -- bad dataset name, OOM at step k, a
  guard's SystemExit -- now appends a `status=failed` row with the phase
  reached (`load_model`/`build_dataset`/`train step 17`/...) and an error
  summary, plus the full traceback to `<run_log>.errors.log`. Completed and
  Ctrl-C runs disarm it (no double rows). Rank 0 only under DDP. Hard process
  kills (OOM-killer, segfault) can't be caught -- those still leave no row.
- **Two latent run-log bugs found and fixed while wiring:** (1) both native
  arms carried a DUPLICATE dead `log_run` definition whose live copy had
  silently dropped `start_val`/`start_eval2` -- baseline evals were being
  logged as blank; (2) the BNB arm's inlined `RUN_LOG_FIELDS` had drifted
  (missing `pack`), so alternating arms on one CSV moved it to `.bak` every
  run. Both fixed; arm schemas verified identical by import. NOTE the schema
  grew (`pack_algo`, `ga_loss`, `t_*_s`, `dequant_s_per_step`, `phase`,
  `error`), so the first post-pull run moves the existing `qlora_runs.csv` to
  `.bak` -- expected, not data loss.
- **BFD packing** (`--pack-algo`, default `bfd`; `nextfit` = old behavior,
  verified byte-identical to the pre-rewrite code). Best-fit-decreasing via
  bisect over remaining capacities; deterministic, so DDP ranks pack
  identically. Measured on synthetic distributions: fill 73-86% -> **99%+**
  (mixed-length: 1338 -> 988 blocks = ~26% fewer steps/epoch for the same
  data); long-doc data caps lower (~84%) -- an inherent bin-packing bound.
  Invariants (no doc lost/duplicated/scrambled, per-doc position reset,
  seg/pad layout) covered in-container.
- **Fused-CE dtype fix.** Both fused heads now matmul in the head weight's own
  dtype and upcast only the `[chunk, vocab]` logits tile -- the full fp32
  `[d, V]` copy (~1 GB Llama-128k / ~4 GB Gemma-262k, re-created per token
  chunk in the single-shot forward!) is gone. fp32/fp64 weights keep bit-exact
  old math (all gradchecks pass unchanged); new bf16-weight parity test (loss
  rel < 2e-3, grad cos > 0.999 vs the fp32 reference).
- **Token-weighted grad accumulation** (`--ga-loss`, default `token`; `mean` =
  old behavior). Micro-batches are weighted by their supervised-token share of
  the whole step (shifted-label counts, matching the CE denominator), making
  the step gradient equal one big batch -- the Oct-2024 HF/Unsloth GA fix.
  Under DDP the share is global (one tiny all-reduce of counts per step),
  composed with the existing SUM/world_size grad reduction. All three arms;
  no-op at grad_accum 1. Loss curves at grad_accum > 1 will shift slightly --
  that's the fix, not a regression.
- The YAML launcher + sample config expose `pack_algo`/`ga_loss`/
  `profile_dequant`; tests print per-test wall-clock via `tests/util.run_timed`.

**Box smoke list for next session (nothing here is box-verified yet):**
1. Any short run: confirm the per-step timing line + `[PERF]` split look sane
   and `--profile-dequant 5` prints a dequant share (record it -- it decides
   how hard to chase audit item A1).
2. `kill` a run / feed a bad dataset name: confirm the `status=failed` CSV row
   + `.errors.log` traceback.
3. A `--pack` run on real data: confirm the printed fill % jumps vs
   `--pack-algo nextfit` and tok/s scales accordingly; loss floor unchanged.
4. A `--grad-accum > 1` run with `--ga-loss token` vs `mean`: expect similar
   curves on packed data (uniform blocks), a visible difference on unpacked
   variable-length data.
5. Big-vocab (Gemma) run WITHOUT `--head-vocab-chunk`: peak VRAM on the head
   card should drop by roughly the head's fp32 size vs pre-Session-11.

---

### Session 12 — softcap in the fused CE heads (fixes the Gemma big-batch head OOM)

> Branch `claude/qlora-cuda-oom-pdpb87`. Trigger: a Semancer-12B (Gemma-family,
> 262k vocab, final-logit softcap) `--parallel split` run with `--batch 3
> --seq-len 8192 --pack` OOM'd at train step 1 in `compute_loss`, at the
> softcap tanh line. Container-verified (CPU tests) AND **box-confirmed** —
> see "Box results" below.

**Diagnosis — why this OOM'd now when smaller runs didn't (no regression):**

1. **The softcap forced the materialized head path, and it scales with batch.**
   Any `final_softcap` model skipped BOTH fused heads (`--ce-chunk` and
   `--head-vocab-chunk` silently ignored — the startup note even said so) and
   materialized `[supervised_tokens, 262144]` logits. At `--batch 3 --seq-len
   8192 --pack` that's ~20k supervised tokens → **9.8 GB in bf16** — and the
   out-of-place cap chain `cap * tanh(logits / cap)` holds up to **three** such
   buffers at its peak (~29 GB). Session 10's run survived only because it was
   ~6.5k supervised tokens (batch 1) with the head on an otherwise-empty card.
2. **The greedy autosplit put ALL 48 blocks + final norm + head on cuda:0.**
   `use_per_device [8, 24]` fills cuda:0 to its budget first (Session 10
   diagnosis); this quant fit entirely under 8 GB, so unlike the Session-10 run
   (47/1, head on cuda:1) the whole model AND the head-loss spike shared
   cuda:0 while cuda:1 sat idle. Known behavior, still ugly — the head-aware
   balanced split (Session 10 next-work #2) remains open.

**Fix (this session): the tanh cap is elementwise, so it chunks — Session 10
next-work #1, the frozen-head 80% of it.**

- `fused_ce.py`: both `FusedLinearCrossEntropy` and
  `FusedLinearCrossEntropyVocabChunked` take a `softcap` arg (0 = off, exact
  old behavior). Forward applies `cap * tanh(z / cap)` inside each logits tile
  (elementwise → online-softmax stats over capped tiles are exact); backward
  chains the Jacobian `1 - (z_capped/cap)^2` into the logit gradient before
  the transposed matmul. Wrappers gain `softcap=0.0`.
- `native_llama.compute_loss`: a **frozen** softcapped head now routes to the
  fused heads (softcap passed through) — the materialized supervised-position
  path is only for `--train-head` / `--lora-head`. So on Gemma-family bases
  `--ce-chunk` and `--head-vocab-chunk` work again and the `[tokens, vocab]`
  spike is gone; the startup "ignored" note now fires on trainable-head runs
  instead of softcap ones.
- The remaining materialized path (trainable head + softcap) applies the cap
  in place (`div_().tanh_() * cap`): peak drops from 3 to 2 logit-sized
  buffers. Verified safe/equal (matmul/add save inputs not outputs; tanh_
  backward uses its own output, left unmodified by the final out-of-place mul).
- Tests: `test_fused_ce.py` gains softcap parity vs
  `F.cross_entropy(cap*tanh((h@w)/cap))` (both heads, loss + grad, with
  ignore_index and chunk sweeps) and fp64 gradchecks for both heads. All
  fused-CE / native-llama / qlora-grad CPU suites pass.

**Box results (Semancer-12B 4bpw, 2×3090, batch 3 × seq 8192 packed, the
previously-OOMing malazan config): CONFIRMED WORKING.**

- The run that OOM'd at step 1 now trains. Split came up 47/1 with final norm
  + head on cuda:1 (the "ignored" softcap note is gone, so the head loss
  streams in `--ce-chunk 64` × `--head-vocab-chunk 32768` tiles). All health
  signals per the standard checklist: first loss **3.38** falling smoothly
  (2.99 by step 6), `|B|` monotonic 0→0.126, steady **457–463 tok/s**,
  ~53.2 s/step, step split **f 31% / b 69% / o ~1%** (backward-heavy is
  expected: checkpoint recompute + dequant both live there).
- **Early grad-norm spikes** (step 1: 11545; steps 3–4: 427/1646; settled to
  25–54 from step 5 on). Read as the usual B=0-init LoRA transient, clipped by
  `--max-grad-norm 1.0`, and the loss curve stayed clean — NOT the Session-10
  liger in_place signature (that one persisted at ~1e16 with healthy loss;
  this run doesn't use `--use-liger`). Only worth revisiting if spikes recur
  mid-run.
- **Dequant profile recorded (the Session-11 A1 datapoint):** 5,000 trellis
  reconstructions in 50.95 s over 5 steps = **10.19 s/step ≈ 19% of step wall
  time** on this 48-layer 12B (profiling adds sync overhead, so true share is
  a bit lower). Implication for audit item A1 (dequant runs ~3× per linear per
  step): collapsing 3× → 1× would save at most ~2/3 of that ≈ **~13% wall** —
  real but not the dominant term; backward (69%) is mostly attention/MLP
  recompute. A1 is worth doing opportunistically, not as the next big rock.
- **Full run completed and converged** — the user reports this dataset "wasn't
  converging before"; this run: loss 3.38 → EMA **2.68** (final step 2.36)
  over 34 steps (2 epochs), grad settled 3–4, `|B|` → 0.377, 398 sup tok/s /
  456 tot tok/s, peak VRAM **18.32 GB (cuda:0) / 11.88 GB (cuda:1)**, 1832 s.
  Adapter saved + generation is coherent, in-style long-form RP. (Don't
  attribute the convergence win to any single change without an ablation —
  candidates since the last attempt: BFD packing at 98.4% fill, the fused
  softcap head, batch 3 at 8k now fitting at all.)
- **Observed at inference: the base's thinking-channel tokens leak** — the
  trained model's output opened with stray `<|channel|>thought`-style markers
  before the response. The SFT supervises clean metharme responses, so the
  base's channel habit survives 2 light epochs. Options if it persists:
  train with `--prompt-format gemma4-nothink` (#121, added for exactly this
  base family), more epochs/stronger adapter, or ban the channel tokens at
  sampling time in the frontend.

**Also this session — liger grad-parity gate built (Session 10 #3; write-
confirmed, box run pending).** `qlora_validate_native.py --use-liger` now runs
`check_liger_parity` automatically: two identically-seeded r=8 adapter nets
over the same frozen base (targets q/gate/up/down so both the Liger RMSNorm
and SwiGLU backwards are on the path, grad-checkpointing ON to reproduce the
#119 corruption conditions), one `loss.backward()` each on the same batch,
then hard-compare the losses (rel < 2e-2) and every adapter grad (per-adapter
cosine > 0.99, rel err < 0.15 — bf16 reassociation passes; the #119 failure
mode was ~14 orders of magnitude out). Skips with a message under fp32 (the
liger path is inactive there). Container-verified: compile + the metric
thresholds against synthetic noise/blowup/sign-flip cases. Box gate:
```
python training/qlora_validate_native.py --model $GEMMA4 \
    --compute-dtype bfloat16 --use-liger --parallel split
```
Only after this prints `liger parity: PASS` is `--use-liger` trustworthy for
real runs (and its VRAM number worth recording).

**First box run of the gate: FAIL** on Semancer-12B (bf16, split): loss
parity fine (rel 6.4e-3), 192 grads compared, worst at **layer 1** `q_proj.b`
(cos 0.9818, rel 0.20) — systematic low-precision drift accumulating toward
the deepest backward layers, not #119-style corruption (that was ~14 orders
of magnitude out).

**Wrong first hypothesis (kept for the record):** the `_norm` liger branch
cast the norm weight to the compute dtype (`w.to(dtype=x.dtype)`), which
would round an **fp16**-normed base to **bf16** on the liger side only (the
torch path uses `w.float()` on the originals). The cast is indeed pointless —
`casting_mode="gemma"` upcasts W to fp32 *inside* the kernel, no X/W
dtype-match assert — and it stays removed (device-move only, dtype kept).
BUT the re-run produced **bit-identical numbers** (loss 5.685615/5.649086,
worst 0.981780/0.201), proving the cast was a no-op here: this Gemma-family
base already stores its norm weights in the compute dtype. Not the cause on
this model.

**Second run's distribution (diagnostic report):** 3/192 outside (cos>0.99,
rel<0.15); median cos 0.9976 / rel 7.1e-2; worst five all `q_proj.b` /
`down_proj.b` at layers 0–4 (plus one at 23). A *shifted distribution* with
deep-backward-layer outliers, not one broken op. Key scoping fact: on this
base liger is **RMSNorm only** — Gemma's GeGLU keeps the (silu-only) liger
SwiGLU kernel out — so the whole spread comes from the RMSNorm substitution.

**Gate rebuilt as two tiers (the decisive experiment — run it next):**
- **Tier 1 — fp32 math gate** (always runs): the same torch-vs-liger compare
  at fp32 compute, where the only legitimate difference is kernel
  reassociation. Bounds: per-adapter cos > 0.9999, rel < 5e-3, loss rel <
  1e-4. FAIL here = the liger backward **formula** is wrong (or a buffer is
  corrupted) — no half-precision excuse available. The `_norm`/SwiGLU liger
  guards now allow fp32 (gemma-mode upcasts are no-ops there) to make this
  tier possible.
- **Tier 2 — noise-band gate** (at the training dtype, when half): bounds
  calibrated to the measured benign spread above (cos > 0.95, rel < 0.35;
  median printed for eyeballing).

Interpretation table for the next box run (same command as above):
**tier1 PASS + tier2 PASS** → liger cleared; record its VRAM/tok-s.
**tier1 FAIL** → real liger/wrapper bug; bisect the RMSNorm call
(in_place/casting_mode/offset) before any liger use.
**tier1 PASS + tier2 FAIL** → the tier-2 calibration is wrong for this
config; recalibrate from the printed distribution, don't force it.

**BOX VERDICT: tier1 PASS + tier2 PASS → LIGER CLEARED.** Semancer-12B, bf16,
split. Tier 1: loss rel **1.67e-6**, 0/192 outside, median cos 1.000000, all
rel ~4–6e-5 — liger's RMSNorm backward math is **exactly right**; the bf16
spread (median 0.9976 / worst 0.9818, identical across runs) is pure kernel
reassociation noise of correct math. The original FAIL was uncalibrated
thresholds, nothing more. The #119-corruption class and the wrong-formula
class each now have a tier that catches them. `--use-liger` is trustworthy;
what remains is measuring whether it's *worth it*: run the malamus config
with `use_liger: true` and record Δpeak-VRAM and Δtok/s vs the 18.32/11.88 GB
/ 456 tok/s baseline (liger's win is fused-norm activation memory; with
activations already offloaded it may be modest — that's the datapoint to
capture before deciding if it becomes a default).

**LIGER COST/BENEFIT: MEASURED — WORTH TURNING ON.** The A/B run above is
in: identical malamus config (same seed/shuffle/data/packing; `--use-liger`
the only delta) vs the Session-12 baseline on Semancer-12B 4bpw, 2×3090,
batch 3 × seq 8192, `--offload-activations` on both sides:
- **Throughput: 496 vs 456 tot tok/s (+8.8%)**, 432 vs 398 sup tok/s;
  ~49.3 vs ~53.2 s/step; **wall 1686 vs 1832 s for 34 steps (−8.0%)**.
- **Peak VRAM: 17.21/10.78 vs 18.32/11.88 GB — −1.1 GB on *each* GPU**, on
  top of activation offload.
- **Convergence run-level identical:** first loss 3.3789 vs 3.38, final EMA
  **2.6807 vs 2.68**, final-step 2.3663 vs 2.36, `|B|` 0.373 vs 0.377; step
  split f 31 / b 69 unchanged; dequant profile 9.50 vs 10.19 s/step (~19%
  share both). Early grad spikes (999/465/3071 at steps 3–5, settled to
  ~18–20 by step 6, one 216 blip at step 31) are the baseline's B=0-init
  transient class (it had 11545 at step 1), clipped as usual — not the #119
  signature (persistent ~1e16).

So the "may be modest" caveat resolved in liger's favor: **set
`use_liger: true` in the malamus config going forward** (the guard already
falls back to torch off-CUDA / fp32, and the two-tier gate is there for any
new base). Note the whole win comes from the **RMSNorm swap alone** — this
GeGLU base keeps liger's (silu-only) SwiGLU kernel out — which upgrades
Session 9 #9 (liger GeGLU + 4D per-head q/k/v norm) from "if the win
justifies it" to *justified; wire when convenient* for another increment of
the same kind.

**Still open (unchanged from Session 10):** trainable-head chunked CE with a
head/LoRA-B gradient (next-work #1's other half, superseding Session 9 #7),
head-aware balanced autosplit (#2, deprioritized now that the head CE is
chunked).

---

### Session 13 — PEFT-variant strategy (decision record) + PiSSA / qerr SVD inits built

> Container-verified (CPU tests); **nothing here is box-verified yet** — the
> gates and A/B runs are the next box session. Context: the user's goal is
> training good RP models for release on HF in **full merged + quantized**
> formats; tokens/time are limited, so this session picked the highest
> value-per-effort item from the modern-PEFT menu and built it.

**Decision record — modern PEFT variants (DoRA / PiSSA / EVA / LoRA-GA),
ordered for THIS pipeline.** A survey report (HF-PEFT-centric) was reviewed;
the ranking below reweights it for our constraints, which the papers can't
see: (1) nothing here is a config flag for us — each method is an
implementation project in the native trainer; (2) the frozen EXL3 trellis
base **cannot be modified**, so any "residual/compensated base" scheme must
become adapter-side bookkeeping; (3) the end goal is merged-then-requantized
models, so adapter-swap ergonomics are irrelevant; (4) our regime is short
runs on tiny SFT sets — the Session-12 runs' `|B|` was **still climbing
(0→0.37) at the final step**, i.e. the default zero-init spends a large
fraction of the whole run getting off the ground. Initialization is
disproportionately valuable here; per-step reparameterizations are not.

1. **PiSSA (+ the qerr sibling) — BUILT this session, see below.** Cheapest
   real implementation (SVD of weights we already dequantize everywhere),
   strongest quantization story, directly attacks the short-run init
   problem.
2. **EVA — next, if init proves out.** Broadest paper evidence; activation-SVD
   init computed from the *quantized* forward (adapts to the model we actually
   ship). Build the fixed-rank version first (skip rank redistribution — it
   touches adapter config/save/merge for a secondary effect). Cost: an
   activation-capture + incremental-SVD pre-pass.
3. **LoRA-GA — deferred.** Tuned for exactly our fast-convergence problem, but
   needs `∇_W` of the frozen weights, which `EXL3LoRAFunction` deliberately
   never computes; would need a per-layer `dY^T X` estimation pass + scale
   bookkeeping, for a benefit PiSSA/EVA partially capture with less machinery.
4. **DoRA — last, possibly never.** The only method that changes every
   training step: per-column norms of `(W0 + BA)` need a cross-term against
   the dequantized base *per step*, in a backward that is already
   dequant-bound (~19% of wall). Its edge is at low rank (we run r=64
   comfortably) and its small-adapter win is void when shipping merged.
- **rsLoRA:** at a FIXED rank it is literally an alpha rescale
  (`s = α/√r` vs `α/r`; r=64/α=64 → s=8 vs s=1). Not a project — a
  hyperparameter. `--use-rslora` (already supported by the module) is now
  exposed in the trainer; treat it as the tuned-baseline knob in sweeps, per
  HF's "don't benchmark against untuned vanilla LoRA" warning.
- **Eval prerequisite (hard, for ALL of the above):** every A/B here is
  unjudgeable on train loss. The dataset is RP (MMLU is not the metric) —
  the right harness is the one the trainer already has: the dataset's own
  held-out split (`--eval2-split test` / `--val-frac`) plus fixed sample
  prompts, in same-seed A/B pairs exactly like the Session-12/13 liger
  comparison.

**BUILT: `--init-lora {default,pissa,qerr}` — SVD adapter inits for the
native trainer** (`exllamav3/training/lora_init.py`; wired through
`native_llama.py`, the trainer, the validate gate, the YAML launcher).

- **pissa** (Meng et al., NeurIPS'24): adapter starts as the top-r principal
  component of the dequantized base. The paper retrains against a residual
  base `W_res = W − principal`; our trellis is immutable, so the residual is
  realized as a **frozen rank-r offset folded into the frozen-weight
  closure**: `W_eff = W_q − s·A0B0` served by `DiffLinear._weight_closure()`,
  adapter initialized to `A0/B0` → the effective delta `s·(AB − A0B0)`
  starts at exactly 0 (function-preserving). The offset rides the same
  closure the backward recomputes, so gradients see the residual base too;
  cost is one rank-r matmul per reconstruction (noise next to the trellis
  dequant, which `--profile-dequant` still times). Use α=r with pissa
  (s=1, the canonical setting).
- **qerr** (the LoftQ idea, single-shot): adapter starts as the top-r SVD of
  the **quantization error** `E = W_orig − dequant(W_q)`, i.e. step 0 is the
  closest rank-r repair of the ORIGINAL bf16 model. No offset, no
  bookkeeping — the nonzero start is the point. Needs `--init-ref-model`
  (the original HF dir; padding regions are explicitly zeroed). The lower
  the bpw, the bigger E: this is the natural companion of the low-bitrate
  EXL3 story (2.5–3bpw), and may speak to the Session-3 finding that LoRAs
  come out attenuated on quantized bases.
- Both use PiSSA's fast randomized SVD (`--init-svd-niter 16`, 0 = exact) and
  divide factors by √s so the *scaled* delta equals the SVD component for any
  α/r/rslora. Embed/head LoRA keeps default init (pissa is ill-defined on the
  token-indexed embedding; the head isn't trellis-quantized).
- **Save/export correctness (the HF-release path):** a pissa adapter's true
  delta is `s·(AB − A0B0)`, so `save_adapter` writes the **converted rank-2r
  standard LoRA** (`[A | A0]` / `[s·B ; −s·B0]`, exported α′ = r′ = 2r →
  loader scale 1.0) — correct for ANY consumer (PEFT, `LoRA.from_directory`,
  merge scripts) — plus a `pissa_init.safetensors` **sidecar** with the exact
  fp32 A/B/A0/B0. `load_adapter` prefers the sidecar (randomized SVD is not
  reproducible, so offsets cannot be recomputed on resume; a pissa resume
  without the sidecar is a hard error). `adapter_config.json` records
  `init_lora` + `init_lora_r` (the rank that actually trained). qerr saves
  through the standard path unchanged. `apply_to_native` (live 🎭 samples)
  pushes the same rank-2r concatenation so generation matches training.
  Size note: a pissa checkpoint carries the fp32 sidecar + the 2r export —
  ~2 GB at r=64 on the 12B vs ~340 MB today; mind `--keep-checkpoints`.
- **Step-0 gate** (`qlora_validate_native.py --init-lora pissa|qerr
  [--init-ref-model …]`), in the two-tier tradition: pissa must be
  **function-preserving** vs the base model — fp32 near-exact (loss rel <
  1e-4, hard FAIL otherwise: offset sign/scale/orientation bugs land here),
  bf16/fp16 in a loose noise band (2e-2; the cancellation of the large
  principal component is inherently noisier — calibrate from the first box
  run if needed). qerr is not function-preserving by design (step 0 ≈ the
  bf16 model), so it gets a wide sanity bound + printed deltas; its exact
  factor math is CPU-tested.
- **Tests** (`tests/test_lora_init.py`, all pass in-container): exact/truncated
  principal recovery; pissa step-0 function preservation + residual-base math
  after B moves; qerr reconstructing a synthetic low-rank quantization error
  through a real temp-dir reference safetensors (incl. α/r scale folding and
  the padding guard); pissa converted-export delta parity + sidecar resume
  round-trip (bit-exact fp32, offsets restored); rslora scale. Existing
  native-llama + qlora-grad CPU suites pass unchanged.
- Also: `--use-rslora` exposed in the native trainer; YAML launcher + sample
  config gained `use_rslora` / `init_lora` / `init_svd_niter` /
  `init_ref_model` (single/split only — the DDP arm is NOT wired, mirroring
  A/B/C). **Run-log schema grew** (`use_rslora`, `init_lora` — native + BNB
  field lists kept byte-identical): the first post-pull run moves the
  existing `qlora_runs.csv` to `.bak` — expected, not data loss.

**Box list for next session (in order):**
1. **Gates first:** `qlora_validate_native.py --model $SEMANCER --compute-dtype
   bfloat16 --init-lora pissa` (runs the fp32 function-preservation gate +
   bf16 band), then `--init-lora qerr --init-ref-model <original HF dir>`.
   Nothing trains on these inits until both print PASS.
2. **The A/B/A2 experiment** (the reason this exists): three same-seed malamus
   runs — `default` vs `pissa` (with α=r) vs `qerr` — **with the eval split
   enabled** (`--eval2-split test` or `--val-frac`, + `--eval-every`), which
   is also checklist prereq #1. Watch: held-out loss, the `|B|` ramp (init
   runs should start with |B| already at working magnitude), early-step loss
   drop, and init wall time (expect seconds with niter 16). Record captured
   variance medians the init prints.
3. If either init wins on held-out loss: it becomes the malamus default, and
   EVA gets built next session for the same harness. If neither moves the
   needle at r=64: raise the prior that init matters less at generous rank,
   and re-test qerr at low bpw where E is large before shelving.

**Still open (carried):** trainable-head chunked CE, head-aware balanced
autosplit (deprioritized), liger GeGLU + 4D per-head norm wiring (promoted by
the Session-12/13 liger win), audit item A1 (dequant 3×→1×, the biggest
remaining perf lever at ~19% of wall).

### Session 14 — box verdict: PiSSA WINS; EVA built; pissa VRAM halved; |dB| telemetry

> Box results from the Session-13 list (user-run), then this session's builds
> (container-verified CPU tests; the eva gate + A/B are the next box items).

**Box results — the three-way same-seed A/B/A2 (Llama-3.2-3B-Instruct 4bpw,
malamus, r=128, α=128, 1 epoch = 17 steps, bf16, 2-GPU split, liger):**

- **pissa wins, clearly.** Final EMA loss **3.0168** vs default **3.0475** vs
  qerr **3.1045**; pissa tracks below default from ~step 3 on with the same
  step-1 loss. The user reports the win **replicated on a larger-model run**.
  Per the Session-13 decision rule: **pissa (α=r) is now the malamus
  default**, and EVA was built this session (below).
- **pissa's function preservation held live on the real model:** step-1 loss
  3.1698 vs the default arm's 3.1697 (bf16 noise band, exactly as the gate
  predicts). Captured principal variance at r=128: median 23.5% (init 12.1s).
- **qerr underperformed BOTH at 4bpw** — and the diagnostics say why: its
  step-1 loss (3.1630) starts slightly *below* base (it is the rank-128
  repair of the bf16 model, as designed; captured error variance median
  20.3%), but its grad norms collapse ~5× (0.45–0.83 vs 2–6 for the others)
  and stay flat: after the quant-error repair, the remaining gradient is
  small yet the task loss barely moves — at 4bpw the error-repair directions
  neither help nor make room for the task. The Session-13 plan already
  covers this branch: **re-test qerr at low bpw (2.5–3), where E is large,
  before shelving it**; at 4bpw it is not competitive.
- **VRAM:** pissa peaked at 5.63/6.20 GB vs 5.26/5.77 for default/qerr —
  **+~0.4 GB per GPU, exactly the fp32 A0/B0 offsets** (they doubled the fp32
  adapter footprint). Fixed this session (below).
- **Caveat for the record:** these runs had eval OFF (`--eval-every 0`,
  `--val-frac 0`; `--eval2-split test` was set but never sampled). At exactly
  1 epoch the train-loss comparison is still fair-ish (every batch is unseen
  when scored, same seed/order across arms), but the decision-grade pissa-vs-
  eva A/B below should run with the eval split actually on, per the standing
  checklist.
- Also noticed in these logs: `|B|` printed as a constant (263.702 / 70.514)
  for the init arms — the trained delta is invisible under the init
  component's magnitude. Fixed below.

**Built this session:**

1. **pissa VRAM halved + spike removed** (`DiffLinear.set_init_offset` /
   `_weight_closure`): the on-device offsets now live in the **compute
   dtype** (the closure cast them to it on every reconstruction anyway →
   bit-identical training), the **exact fp32 masters move to CPU**, and the
   residual is applied with one fused out-of-place `addmm` (no `[in,out]`
   product temporary; in-place would be unsafe for fp16 inner layers, whose
   `get_weight_tensor` returns the stored weight itself). The masters are
   what the sidecar, the converted rank-2r export and `apply_to_native` now
   read — necessary for correctness, not just exactness: A≈A0 early on, so a
   bf16-rounded A0 against the fp32 A leaves a spurious delta comparable to
   the trained one. Expected on the 3B r=128 run: pissa overhead drops from
   ~+0.4 to ~+0.2 GB/GPU. Sidecar/resume stays bit-exact fp32.
2. **`|dB|` telemetry** (trainer step line, renamed from `|B|`): logs
   ‖B − B0‖ with B0 = zero for default/eva (values identical to the old
   column), the fp32 sidecar masters for pissa (survives resume), or a CPU
   fp32 snapshot taken at startup for qerr (on a qerr resume this measures
   movement since the resume). The "is the adapter still growing at the end"
   read now works for init runs too.
3. **EVA, fixed-rank (`--init-lora eva`)** per the Session-13 plan, now that
   an init won on the box:
   - **Mechanism:** a short no-grad pre-pass streams the training set's
     activations through the *quantized* forward; each target's input feeds
     a streaming top-(r+8) SVD sketch (block incremental PCA, a few MB per
     site — no Gram matrices, no stored activations); A ← top-r
     right-singular vectors, **B stays 0**, so step 0 is *exactly* the base
     model in every dtype — no offset, no sidecar, standard save/merge path.
     q/k/v (and gate/up) provably share their input tensor, so they share
     one sketch and one A (asserted at runtime via data_ptr). Pad tokens are
     dropped via the attention mask. Rank redistribution from the paper is
     intentionally skipped (fixed-rank first, per the decision record).
   - **Trainer:** `--init-eva-tokens` (default 65536) budgets the pre-pass,
     drawn in order from the (packed) training blocks after data prep; on
     `--resume` the eva init is skipped (the checkpoint's A/B already carry
     it — nothing to reconstruct, unlike pissa). YAML launcher key
     `init_eva_tokens` added (single/split only, like the rest). Run-log
     schema UNCHANGED (init_lora already covers it — no CSV roll this time).
   - **Gate:** `qlora_validate_native.py --init-lora eva` runs the real
     pre-pass machinery on the gate prompt and demands **exact** function
     preservation at BOTH tiers (rel < 1e-6; B=0 means any deviation at all
     is a corrupted init path).
   - **Tests** (`tests/test_lora_init.py`, all pass in-container): sketch
     recovers a planted activation subspace streamed in folds (exact +
     randomized, orthonormality, captured-variance vs exact SVD,
     rank-starvation raises); apply path shares one sketch across q/k
     (identical A), keeps o distinct, drops pad rows (a huge pad-only junk
     direction must NOT appear in A), keeps B at zero with bit-exact forward
     preservation, and refuses to run without pre-pass data. Plus the new
     pissa compute-dtype-storage test; existing suites pass unchanged.

**Box list for next session (in order):**

1. **Gates:** `qlora_validate_native.py --model <model> --compute-dtype
   bfloat16 --init-lora eva` (new), and re-run `--init-lora pissa` (cheap;
   the offset storage changed — the fp32 tier is untouched by construction,
   but confirm the bf16 band). Nothing trains on eva until it prints PASS.
2. **The pissa-vs-eva same-seed A/B on malamus** — `--init-lora pissa` (α=r)
   vs `--init-lora eva` vs default as the anchor arm, **with the eval split
   actually on this time**: **`--eval-split test` + `--eval-every N`** (or
   `--val-frac`). NOTE the earlier session notes said `--eval2-split test` —
   that was wrong-by-omission: `--eval2-*` is the *second* monitor and inert
   without `--eval2-dataset`, which is exactly why the Session-14 runs came
   out eval-less. The PRIMARY eval (the one `--save-best` tracks) is the
   `--eval-*` family. Watch held-out loss, the now-meaningful `|dB|` ramp, and
   eva's pre-pass wall/captured-variance print (expect seconds and a
   *lower* captured fraction than pissa's — activations are less
   low-rank-concentrated than weights; that is normal and not a bug).
3. **Confirm the pissa VRAM drop** on the same 3B r=128 config (expect
   ~5.4/6.0 GB peak instead of 5.63/6.20).
4. Carried: qerr low-bpw retest (2.5–3 bpw quant of the same model) before
   shelving it; the standing eval-prereq note applies to any decision-grade
   run.

**Repo tidy (toward a PR-able boundary):** experiment-specific tooling moved
to `training/experiments/` (`make_style_dataset.py`, `score_style_density.py`,
`train_rocinante_yoda.sh`, + a README defining the product-vs-experiment
boundary). Live path references updated; historical session records above
keep the old paths. Inventory vs the upstream fork point (v0.0.43,
`c5d9c65`): ~13.1k inserted lines total, of which only ~250 touch core
inference files (the backbone-seam discipline paid off) — the four standalone
core bugfixes (gemma4 device, xformers ImportError, attn view→reshape,
transformers nn.Parameter) are upstream-PR-able today independent of any
training decision; the training subsystem's home (in-tree PR vs separate
repo) is an open decision pending upstream appetite — see the Session-14
discussion.

### Session 15 — eval1/eval2 option parity, YAML polish, fork README

- **Primary-eval parity with eval2** (both backends + launcher + sample
  YAML): `--eval-config`, `--eval-text-key` (plain-text LM mode for the
  PRIMARY eval — `--save-best` then tracks that LM loss), `--eval-max-samples`,
  `--eval-max-blocks`. Run-log schema unchanged (none of these are logged
  fields — no CSV roll).
- **Root cause of the Session-14 eval-less runs identified and corrected in
  the box list:** earlier notes said `--eval2-split test`, but `--eval2-*` is
  the *second* monitor and inert without `--eval2-dataset`. The primary eval
  is the `--eval-*` family: use **`--eval-split test` + `--eval-every N`**.
- **Sample YAML** (`qlora_train_config.yaml`): eval section rewritten with a
  worked "usual setup" comment; verified programmatically that the file
  covers EVERY launcher-accepted key (flatten → validate → build_backend_argv
  round-trip, zero missing/unknown).
- **README.md** now opens with the fork spiel: why-EXL3-for-QLoRA, YAML
  quickstart + minimal config, feature overview, the PiSSA/EVA/qerr/rsLoRA
  init story (with the pissa-won-its-first-A/B status), project state, and
  links to this handoff; upstream's original README kept intact below it.

### Session 16 — preference training: DPO + KTO on the native path

> Branch `claude/qlora-kto-dpo-6t56y6`. Container-verified (CPU suites all
> pass, incl. the new `tests/test_preference.py`); **nothing here is
> box-verified yet** — the smoke list below is the next box session. Context:
> the user was asked to add KTO and DPO, toward a later near-inference-time
> training pipeline built on them (now backlog #2).

**Credit / licensing:** loss semantics follow **HuggingFace TRL**'s stable
trainers — `DPOTrainer` and `KTOTrainer` (KTO was promoted from
`trl.experimental` to the stable API in
[huggingface/trl#6175](https://github.com/huggingface/trl/pull/6175), training
logic unchanged in that move). TRL is **Apache-2.0**, which permits this with
attribution; this is an **independent reimplementation** against the native
EXL3 path (TRL's trainers assume HF Transformers models), not copied code —
credited in `exllamav3/training/preference.py`, here, and the README. Papers:
DPO (Rafailov et al., arXiv:2305.18290), KTO (Ethayarajh et al.,
arXiv:2402.01306), IPO (arXiv:2310.12036), SLiC hinge, APO.

**The design in one paragraph.** Preference losses need per-sequence
completion log-probabilities under the policy AND a frozen reference model.
Both come from the existing net: (1) the fused CE heads gained a
`reduction="none"` per-token mode (still streamed — no `[tokens, vocab]`
logits, both single-shot and vocab-chunked, softcap composes; backward takes a
per-token grad_output), and `NativeLlamaQLoRA.compute_logps()` row-sums it
into `(logps[b], counts[b])`; (2) the **reference model is the frozen base via
`net.adapters_disabled()`** — the PEFT disable-adapter trick, so **no second
model copy is ever loaded**: each `DiffLinear` gets an `adapter_enabled` gate
that drops the LoRA term AND the pissa offset together (they cancel at init,
so what remains is exactly the base `W_q`); the trainable/LoRA embed+head are
skipped too. For default/pissa/eva inits the reference therefore equals the
step-0 policy *exactly* (DPO baseline loss = ln 2 ≈ 0.6931 — a built-in
sanity anchor the trainer prints at step 0); **qerr is the exception** (its
step 0 is the error-repaired model, the reference is the raw base — the
trainer notes it).

**What was built:**
- `exllamav3/training/preference.py` — `dpo_loss` (sigmoid default +
  `label_smoothing` = cDPO, `hinge`, `ipo` with length normalization; rewards
  = β·logratio, detached), `kto_loss` (desirable/undesirable weights λ_D/λ_U,
  batch KL reference point `mean(policy_kl − ref_kl).clamp(min=0)` from
  mismatched pairs, `apo_zero_unpaired` variant, empty subsets OK),
  `mismatched_kl_shift` (TRL's +1 rotation).
- `fused_ce.py` — `reduction` arg on both fused heads + wrappers. NOTE the
  autograd `Function.apply` arity grew (reduction is a required positional),
  so any external direct `.apply` callers need the extra `"mean"` arg; the
  wrapper functions default it.
- `native_llama.py` — `DiffLinear.adapter_enabled`,
  `NativeLlamaQLoRA.adapters_disabled()` (reentrant, exception-safe),
  `compute_logps()` (frozen-head only; per-ROW sums, so **no packing** — a
  packed block would sum across documents).
- `training/qlora_train_pref.py` — the preference trainer, `--method
  {dpo,kto}`. DPO data = TRL explicit-prompt format
  (`--prompt-key/--chosen-key/--rejected-key`; conversational message-list
  values accepted); KTO = `--prompt-key/--completion-key/--label-key` +
  label-balance report with a λ weight hint (KTO paper's [1, 4/3] band). One
  DPO micro-batch runs chosen+rejected as ONE 2·batch-row policy forward + one
  no-grad reference forward; KTO adds two no-grad KL forwards (mismatched
  pairs, needs `--batch >= 2`, enforced). Example-weighted grad accumulation
  (per-sequence losses — the SFT token-weighting doesn't apply). Reuses the
  SFT trainer's machinery by import: chat templates + BOS normalization (the
  encode path was refactored into a shared `encode_prompt_response` — the SFT
  builder now calls it, byte-identical), scheduler/warmup/epochs, optimizers
  (incl. 8-bit), save/save-best/checkpoint-every/resume + trainer_state,
  run-log CSV (same schema — `arm=exl3-dpo|exl3-kto`, method hyperparams in
  `notes`; **no CSV roll**), StepTimer/ThroughputMeter, `--inspect`,
  `--init-lora` incl. an eva pre-pass fed from preference batches,
  liger/offload/attn-impl/head-vocab-chunk/split. Step line shows
  `acc`/`margin` (DPO) or `kl`/`rD`/`rU` (KTO); eval reports preference loss +
  reward metrics, `--save-best` keyed on eval loss.
- **Not in scope (v1):** DDP arm (KTO's KL needs a cross-rank all-reduce),
  YAML launcher wiring, sample packing, trainable embed/head, live 🎭 samples.
  Typical preference LRs are ~10–100× below SFT (default `--lr 5e-6`).
- `tests/test_preference.py` — reduction-none parity/gradcheck/softcap on both
  heads, per-row logps vs hand reference, every DPO/KTO variant vs hand
  formulas (incl. KL clamp, weights, empty subsets, gradient direction),
  adapter-disable == pure base (incl. with a pissa offset installed), context
  manager reentrancy/exception safety. All CPU suites pass
  (fused_ce/native_llama/qlora_grad/lora_init/preference).

**Box list for next session (in order):**
1. **Forward gate unchanged** (`qlora_validate_native.py` on the target base —
   nothing about the validated forward changed), then a **DPO smoke**: tiny
   paired set, `--inspect 3` first, then ~20 steps. Expect step-0 baseline
   eval/loss ≈ **0.6931** and rising `acc`/`margin`. A cheap paired set:
   `--dataset trl-lib/ultrafeedback_binarized` (prompt/chosen/rejected,
   conversational values — the loader handles both).
2. **KTO smoke**: e.g. `trl-lib/kto-mix-14k` (prompt/completion/label),
   `--batch 2+`; watch `kl` stay finite and `rD`/`rU` separate.
3. **Reference-forward correctness probe** (one-off): on a pissa-initialized
   net, confirm `adapters_disabled()` logps == a default-init net's step-0
   logps on the same batch (they should match to compute-dtype noise; this
   pins the offset-drop logic on real weights).
4. Then the real question for the pipeline goal: a small RP-preference set +
   held-out eval, DPO vs KTO on the same data, judged per the standing
   eval-prereq rules (same-seed pairs, eval split ON).

### Session 17 — quantization-aware LoRA (`--quant-aware {noise,ste}`) built

> Branch `claude/quantization-aware-lora-etptoj`. Backlog #1. Container-
> verified (new CPU suite + all existing suites pass); **nothing here is
> box-verified yet** — the gates and the decision A/B are the next box
> session. Context: the deploy path is merge-and-requantize (Session 3 arc
> C), and ordinary QLoRA training is blind to it — it optimizes against one
> fixed, exactly-known `W_q`, so (a) the adapter can spend capacity
> compensating the *specific* error realization `ε = W_q − W_orig` it was
> trained on (wasted the moment a requantize re-rolls it to `ε'`), and (b)
> nothing stops delta components below the quant-noise floor, which a
> requantize destroys (the attenuation finding, worse at 2.5–3 bpw).

**Decision record — why not QA-LoRA's own operator.** QA-LoRA (Xu et al.
2023, arXiv:2309.14717) gets its exact merge by constraining A so the adapter
delta is constant within each input quantization group; the merged delta is
then absorbed into the *zero points* of group-wise affine quant, so the
deployed model is exactly the trained one. The EXL3 trellis has no zero
points or group scales to absorb anything — the whole weight is re-fit
through Hadamard rotations + Viterbi search — so the exact-merge construction
has **no trellis analogue**. What survives is the objective (train the thing
you will deploy), realized by the two operators below. Related work checked:
NIPQ (arXiv:2206.00820, noise proxy > STE for QAT stability), RILQ
(arXiv:2412.01129, adapter-merged 2-bit compensation via activation loss —
a PTQ-side method), CLoQ/LoftQ/CLoQ-style calibrated inits (we have
pissa/qerr/eva). Nothing supersedes the noise-proxy approach for an
immutable trellis base.

**What was built (`exllamav3/training/quant_aware.py`, composed into
`DiffLinear._weight_closure_qa`; adapted r>0 linears only — non-adapted
layers stay exact, they contribute variance the adapter can't answer):**

- **`--quant-aware noise`** — pseudo-quantization-noise injection (the
  NIPQ/QuantNoise idea): each optimizer micro-batch, the frozen weight
  served to the forward AND its backward recompute is `W_q + δ` with fresh
  `δ ~ N(0, diag(σ²))`, σ per output channel at the layer's quant-error
  scale. Fully differentiable (additive constant per step — no STE bias);
  the adapter can't fit the trained-against `ε` and must put its energy
  above the noise floor in expectation. This is the closest differentiable
  proxy of "the merged model will be requantized with an error you cannot
  know yet".
- **`--quant-aware ste`** — delta-quantization straight-through (QA-LoRA's
  intent transplanted): the forward sees `W_q + Q(Δ_eff)` where `Q` snaps
  the *effective* adapter delta (`s·AB`, or `s·(AB − A0B0)` under pissa —
  exactly what a merge carries) to a per-channel uniform grid with step
  `q = √12·σ`; A/B gradients pass straight through while grad_x flows
  through the snapped weight the forward used. Sub-floor delta components
  contribute NOTHING to the forward — precisely the deploy behavior — so
  loss can only improve via components that survive. Deterministic, exactly
  function-preserving at Δ=0 (default/pissa/eva inits).
- **σ sources:** `--quant-aware-ref-model <original HF dir>` measures
  `rms(W_ref − W_q)` per output channel (exact; padded columns get σ=0 and
  are never perturbed; falls back to `--init-ref-model` when set). Without
  a reference: the rate-distortion heuristic `σ_col = std(W_q[:,col])·2^-K`
  with K read from the trellis (`backbone.linear_quant_bits`; ~6% relative
  at 4 bpw, ~18% at 2.5). `--quant-aware-scale` multiplies either source —
  calibrate the heuristic against one ref-measured printout, then drop the
  ref. fp16 (no-K) layers are skipped with a count in the startup line.
- **Determinism contract (the gradient-correctness crux):** the weight
  closure is re-invoked by the checkpoint recompute and by
  `EXL3LoRAFunction.backward`, and all (≤3) reconstructions within one
  micro-batch MUST see the same weight or gradients silently corrupt. Noise
  is drawn from a generator seeded by (net-level tick, stable layer id);
  the tick advances once per **grad-enabled** `net.forward` (eval, DPO/KTO
  reference/KL passes are no-grad and see clean weights — eval/validate and
  saves are ALWAYS exact). Consequence documented in the module: at most one
  grad-enabled forward in flight before its backward — true for the SFT
  trainer and the preference trainer's single policy forward. STE needs no
  seeding (deterministic in A/B, constant within a micro-batch).
- **Wiring:** trainer flags (native single/split only, mirroring the
  A/B/C + init-lora precedent — NOT the DDP arm, NOT `qlora_train_pref.py`
  v1), YAML launcher + sample-config keys (`quant_aware`,
  `quant_aware_scale`, `quant_aware_ref_model`; coverage round-trip
  reverified), `adapter_config.json` provenance keys, and **run-log schema
  grew** (`quant_aware`, `quant_aware_scale`; native + BNB field lists kept
  byte-identical) → the first post-pull run moves `qlora_runs.csv` to
  `.bak` — expected, not data loss. Nothing is persisted in checkpoints:
  the mode is run configuration, reapplied by the trainer after any resume.
- **Tests** (`tests/test_quant_aware.py`, all pass in-container): σ
  measurement (heuristic K-scaling + skip; ref-measured incl. padding),
  noise determinism within a tick / freshness across ticks / empirical std
  match / eval+disable exactness, grad consistency against the exact noisy
  weight, STE bit-exact preservation at Δ=0, sub-floor deltas ignored,
  snapping math, σ=0 column guard, straight-through grads, and both modes
  composing with a pissa residual offset. Existing suites unaffected (the
  off path is byte-identical: `_weight_closure_qa` returns the plain
  closure when the mode is off or the module is in eval).

**Cost expectation:** noise adds one `randn_like` + `addcmul` per weight
reconstruction (≤3/linear/step, riding the closure the dequant profiler
already times); ste adds one rank-r matmul + elementwise round. Both are
noise next to the trellis dequant (~19% of step wall at Session 12's
measurement) — confirm with `--profile-dequant 5` on the first box run.

**Box list for next session (in order):**
1. **Off-path sanity (cheap):** any short run WITHOUT `--quant-aware`
   behaves identically to pre-Session-17 (the validate gate needs no rerun —
   the off path is unchanged — but a 5-step loss-curve eyeball is free).
2. **Startup sanity with `--quant-aware noise`:** the ` -- quant-aware`
   line prints plausible relative scales (~6% median at 4 bpw heuristic);
   with `--quant-aware-ref-model` the measured numbers should be same-order.
   Loss should descend with a slightly noisier curve; grad norms same order
   as baseline (a persistent ~1e16 blowup = determinism contract violated —
   file a bug, that's the checkpoint-recompute mismatch signature).
3. **The decision A/B/A2** (same-seed malamus triple, eval split ON per the
   standing prereq): `--quant-aware none` vs `noise` (scale 1.0) vs `ste`.
   Judge on (a) held-out loss of the adapter as-trained, and (b) — the
   actual point — held-out loss / gens **after merge-and-requantize** of
   each arm at the same bpw. The QAT arms may show slightly WORSE (a) —
   that's the robustness tax — the win condition is (b): the smallest
   train→deploy degradation. Optionally add `--quant-aware-scale 0.5` if
   scale-1.0 noise visibly hurts convergence.
4. **Low-bpw follow-up (where the payoff lives):** repeat 3 on a 2.5–3 bpw
   base (σ ~3× larger, so both the problem and the expected win grow), and
   re-test qerr there too (carried Session-14 item; qerr's error-repair
   directions + noise robustness are natural companions at low bpw).

### Session 18 — Qwen3.5/3.6: prompt formats + differentiable Gated DeltaNet

> Branch `claude/exl3-qlora-prompt-formats-k3gskk`. Container-verified (new
> `tests/test_gdn.py` + all existing CPU suites pass); **nothing here is
> box-verified yet** — the gates below are the next box session. Two arcs:
> (A) the llama3/qwen3.5 prompt formats, (B) the big one — training the
> Qwen3.5/3.6 hybrid linear-attention models on the native path (the standing
> "open research frontier" from Sessions 5/6).

**A. Prompt formats (`--prompt-format`, all three native arms + YAML):**
- **`llama3`** — explicit Llama-3 header format (identical to `auto` on the
  llama arch; trains the pattern onto any base, metharme-style, on non-Llama
  tokenizers). `<|eot_id|>` ends the turn; the model's own BOS is used.
- **`qwen3.5`** — plain ChatML (identical to `auto` on qwen3/3.5 archs). Use
  when responses carry their own `<think>` spans (reasoning SFT). No BOS
  (Qwen defines none); `<|im_end|>` ends the turn.
- **`qwen3.5-nothink`** — ChatML with the reasoning block pre-closed empty:
  the assistant turn opens with `<think>\n\n</think>\n\n` inside the *masked*
  prompt, so the model trains to answer directly. Byte-matches what
  `PromptFormat_qwen35` (examples/chat_templates.py) prefills at inference
  with thinking off — train and serve see the same context (the
  `gemma4-nothink` of the Qwen family).
- Builders verified against `llama.py`/`qwen3_5.py` `default_chat_prompt` and
  `PromptFormat_qwen35` (byte-identical). Wired into `qlora_train_native.py`,
  the DDP arm, `qlora_train_pref.py`, and the sample YAML comment. The BNB
  arm still hardcodes the Llama-3 template (unchanged).

**B. Differentiable Gated DeltaNet — the Qwen3.5/3.6 unlock.**

*The triage that held since Session 5:* Qwen3.5/3.6 build ~3/4 of layers as
`GatedDeltaNet` (causal depthwise conv + SiLU over packed q/k/v, gated delta
rule with L2 q/k-norm and per-v-head exponential decay, gated RMSNorm output)
and the remaining 1/4 as softmax attention with an **interleaved output gate**
(q_proj emits `[q | gate]` per head; attn output × `sigmoid(gate)` before
o_proj). Both were rejected by `assert_block_supported`. Both are now built:

- **`exllamav3/training/gdn.py`** (new; pure torch, CPU-loadable like
  `fused_ce`): `gdn_delta_rule_reference` (sequential fp32 scan, transcribed
  from the inference module's own validated reference
  `torch_recurrent_gated_delta_rule`, made autograd-safe; GQA q/k expansion
  `j -> j // G` matching the split in_proj_qkv layout), `gdn_causal_conv1d_silu`
  (fresh zero conv state == left-pad k−1 zeros; exactly the inference conv on
  a whole sequence), `gdn_gated_rmsnorm` (`rmsnorm(x)·(w+bias)·silu(z)`,
  fp32 internals), `gdn_beta_g` (`beta = sigmoid(b)·beta_scale`,
  `g = −exp(a_log)·softplus(a + dt_bias)` — verified against gdn.cu).
- **Delta-rule fast path = fla's `chunk_gated_delta_rule`** — the SAME
  autograd-capable Triton kernel exllamav3's own inference prefill dispatches
  to, called with identical kwargs (`use_qk_l2norm_in_kernel=True`, no
  initial state), so train numerics match serve numerics by construction.
  Engaged on CUDA fp16/bf16 when fla imports and `--attn-impl != eager`;
  everything else runs the sequential reference (correct but O(t) sequential
  — fine for the fp32 validate gate, not for long training runs). Startup
  prints which path is live (`describe_attn` → `[gdn: fla chunked kernel]`
  vs `[gdn: torch reference -- SLOW]`), and `__init__` warns if fla is
  missing on a GDN model.
- **`backbone.py`**: `is_gated_delta_net`, `gdn_projections`,
  `gdn_norm_spec`; `block_metadata` now returns `kind: "attn"|"gdn"` (+
  `interleaved_gate` on attn, + the GDN dims/decay/conv tensors);
  `assert_block_supported` accepts GDN blocks with the **split** projection
  layout (in_proj_qkv/z/b/a — Qwen3.5/3.6) and interleaved-gate attention,
  still rejects: fused qkvz/ba (Qwen3-Next layout), MoE (`BlockSparseMLP` →
  Qwen3.5-MoE unsupported), headwise g_proj gating, mRoPE.
- **`native_llama.py`**: `_gdn_forward` (norm → split projections → conv+silu
  → delta rule → gated norm → o_proj residual → shared `_mlp_out` MLP half;
  no RoPE, no attention bias — the recurrence is causal by construction;
  right-padding safe), `_gdn_delta_rule` dispatch, interleaved-gate handling
  in `_block_forward` (chunk `[q | gate]` exactly like inference
  `project_qkv`, gate applied to the flattened ctx in all three attn modes),
  grad-checkpointed like every other block. **Target-name aliases**
  (`_GDN_TARGET_ALIASES`): the familiar llama-style target list adapts the
  analogous GDN projections — q/k/v_proj → `in_proj_qkv`, v_proj →
  `in_proj_z` too, o_proj → `out_proj`; the tiny per-head b/a projections
  only when named explicitly (`in_proj_b`/`in_proj_a`). So the default
  `--targets` trains qkv/z/out on GDN layers + everything on the full-attn
  and MLP paths, and pissa/eva/qerr/quant-aware all compose (they iterate
  `net._wrappers` generically).
- **Sample packing is NOT supported on GDN models** (the recurrence + conv
  would carry state across packed document boundaries): `net.forward` raises
  on `seg_ids`, both trainers abort `--pack` with a clear message, and the
  validate script skips `--check-packing`. fla's cu_seqlens varlen mode is
  the future fix if packing ever matters here (GDN blocks have no O(t²) term,
  so packing is a throughput win only).
- **Tests** (`tests/test_gdn.py`, all pass in-container): delta-rule
  reference vs a verbatim transcription of the inference reference (incl.
  GQA grouping), fp64 gradcheck of the rule, conv+silu vs the inference conv
  from zero state, full GDN block forward vs an independent plain-torch
  composition, backward reaches qkv/z/out adapters with base + b/a frozen,
  and the interleaved-gate attn block vs reference. Existing suites
  (native_llama/fused_ce/qlora_grad/lora_init/preference/quant_aware) pass
  unchanged.

**Box list for next session (in order):**
1. **Forward gates on a real Qwen3.5 dense EXL3 quant** (e.g. a
   Qwen3.5-instruct 4bpw): `qlora_validate_native.py --model $QWEN35`
   (fp32 eager — exercises the sequential reference against exllamav3's own
   forward; expect high argmax agreement), then `--compute-dtype bfloat16`
   (exercises fla chunked + flash attn on the gated full-attn layers;
   `describe_attn` should print `N×gdn … [gdn: fla chunked kernel]`), then
   `--check-backward` (grads through both block kinds). Nothing trains until
   these print PASS. Env: fla (`flash-linear-attention`) must import in the
   qlora-venv — the inference prefill path already uses it, but confirm the
   version pin survives (the Session-2 env note about its torch drag).
2. **Training smoke**: `--inspect 3` first (with `--prompt-format
   qwen3.5-nothink` on an instruct base), then a short unpacked run
   (`--sample-every 0` for the first run; live sampling exercises the
   recurrent-cache generator path, which is orthogonal to training). Expect
   first loss ~2–4, healthy grad norms, `|dB|` climbing. Watch tok/s — the
   GDN layers' fla backward is new territory; record `--profile-dequant 5`.
3. **A real SFT + eval-split run** on the target dataset, judged per the
   standing eval-prereq rules.
4. Later / optional: fla cu_seqlens packing for GDN models, fused-qkvz
   support (Qwen3-Next), MoE (Qwen3.5-MoE) — each a separate project.

### Session 20 — Qwen3.5-MoE: differentiable BlockSparseMLP (MoE) in the native forward

> Branch `claude/qwen35-moe-training-oqc1p0`. Container-verified (new
> `tests/test_moe.py` + all existing CPU suites pass); **nothing here is
> box-verified yet** — the box list below is the next box session. This
> removes the last blocker for Qwen3.5-MoE training (Session 18 built the
> other half: GDN + gated attention). Also unlocks **Qwen3-MoE**
> (`Qwen3MoeForCausalLM` — same BlockSparseMLP, std router, no shared
> expert, standard attention, so it packs too). Qwen3-Next stays rejected
> (fused qkvz GDN layout, a separate project).

**What the inference module does (the spec).** `modules/block_sparse_mlp.py`:
router `gate` (fp16 Linear `[hidden, E]`) → `ext.routing_std` = top-k over the
logits, then softmax over the selected k (`routing.cu:routing_std_topk_kernel`)
— mathematically identical to HF's softmax-over-all + top-k + renormalize with
`norm_topk_prob=True` (which both Qwen MoE configs assert), since restricting
a softmax to a subset and renormalizing equals the softmax over that subset's
logits. Optional post-softmax `per_expert_scale`. Routed experts = per-expert
gate/up/down EXL3 linears, SiLU, output accumulated in fp32. Qwen3.5-MoE adds
a **shared expert** (dense GatedMLP, always active) added as
`sigmoid(shared_expert_gate(x)) * shared_mlp(x)` (`ext.add_sigmoid_gate`).

**Design decisions (researched against unsloth / axolotl / PEFT practice):**
- **Target semantics:** plain `gate_proj`/`up_proj`/`down_proj` adapt dense
  MLPs and the **shared expert** only. Routed experts are **opt-in** via the
  explicit `expert_gate_proj`/`expert_up_proj`/`expert_down_proj` names
  (`_MOE_EXPERT_TARGET_ALIASES`, the `_GDN_TARGET_ALIASES` sibling) — matches
  axolotl's shipped MoE configs (attention-only default, experts via
  `lora_target_parameters` commented out). Rationale: a many-expert model
  gets one adapter pair per expert per layer (E×3×L), with sparse per-expert
  gradients; that's a deliberate choice, not a default. (Unsloth *does*
  default experts on, but behind custom grouped-GEMM kernels we don't have.)
- **`--expert-r`** (all three native arms + YAML `expert_r`): a separate
  (smaller) rank for routed-expert adapters — PEFT's own MoE recipe divides
  rank by expert count (`rank_pattern`, citing "LoRA Without Regret").
  Exported to `adapter_config.json` as a PEFT `rank_pattern`
  (+ `alpha_pattern` in the pissa-converted case); `LoRA.from_directory` now
  derives each module's rank **from its tensor shape** (+ honors
  `alpha_pattern`), so mixed-rank adapters — ours or PEFT's — scale right.
- **Router + shared gate: always frozen** (r=0 DiffLinears, not targetable).
  Universal practice (unsloth docs say it outright; axolotl comments it out;
  ms-swift has a router-freeze feature request citing routing collapse). The
  routing WEIGHTS stay differentiable w.r.t. the hidden state (gradient flows
  through the weighted sum → softmax → router matmul, exactly like HF); only
  the top-k index selection is piecewise-constant.
- **No auxiliary load-balancing loss.** HF computes it only when
  `output_router_logits=true` (default off); axolotl enables it for Mixtral
  but NOT for any Qwen-MoE config; with a frozen router it can't rebalance
  routing anyway — it would only distort the expert-weight gradients.
- **Routing softmax in fp32** (promoted to fp64 on the gradcheck path),
  matching HF's `softmax(..., dtype=torch.float)`; output accumulation fp32,
  matching the inference module's float output buffer.

**What was changed:**
- `training/backbone.py`: `is_block_sparse_mlp`, `_assert_moe_supported`
  (accepts std-router BlockSparseMLP incl. shared expert + shared gate +
  `per_expert_scale`; still rejects ds3/dots routers, grouped routing,
  `routed_scaling_factor`, `e_score_correction_bias`, expert/TP splits,
  Gemma4-style extra norms / `alt_residual_channel`), `_mlp_metadata`
  (`mlp_kind: "dense"|"moe"` + E / top-k / scale / shared activation, merged
  into `block_metadata` for both block kinds), and seam accessors
  `moe_expert_projections`, `moe_shared_projections`, `moe_router_linear`,
  `moe_shared_gate_linear`.
- `training/native_llama.py`: `_moe_out` (router → top-k softmax → sort
  tokens by expert (stable, so the grad-checkpoint recompute reproduces the
  exact fp reduction order) → per-expert gather / gated-MLP / weighted
  `index_add_` scatter → shared expert × sigmoid gate); `_mlp_out` split into
  a dispatch + `_gated_mlp` (dense path bit-identical, also runs the shared
  expert with liger support); construction wraps every expert projection in a
  DiffLinear (LoRA / pissa / eva / quant-aware compose — they iterate
  `net._wrappers` generically and skip r=0), `expert_r` knob, one-line notes
  at build (frozen experts / expert adapter count), `describe_attn` gains
  `[moe: N layers x E experts, top-k]`, and `save_adapter` emits
  `rank_pattern`/`alpha_pattern` for mixed ranks. Default targets that match
  nothing (e.g. `gate_proj` on a shared-expert-less Qwen3-MoE) are now
  dropped with a note instead of raising — explicit `--targets` still raise.
- `model/lora.py`: per-module B pre-scale (`_module_scaling`) from the
  tensor's own rank + `alpha_pattern`, replacing the single global
  `alpha/config_r` (which silently mis-scales mixed-rank adapters).
- Trainers: `--expert-r` on `qlora_train_native.py` / DDP / pref + YAML key
  `expert_r`; `--targets` help documents the MoE semantics; run-log CSV gains
  an `expert_r` column. `qlora_validate_native.py`'s backward/liger-parity
  smoke nets fall back to `q_proj`-only targets on a pure-MoE model.
- `tests/test_moe.py` (all pass in-container): `_moe_out` vs an independent
  HF-style reference (softmax-all + renorm — the equality IS the
  norm_topk_prob equivalence proof), Qwen3-MoE shape (no shared expert) +
  `per_expert_scale`, fp64 gradcheck through routing + experts + shared gate,
  backward reaches expert/shared adapters at mixed ranks with base + router +
  shared gate frozen, token-less experts get no gradient, dense dispatch
  unchanged. Existing suites (gdn / native_llama / fused_ce / qlora_grad /
  lora_init / preference / quant_aware) pass unchanged.

**Known caveats (by design, documented in code):**
- **Runtime-slot LoRA on routed experts does NOT fire at native inference:**
  `Linear.apply_lora` runs only via `Linear.forward`, and the quantized
  BlockSparseMLP inference forward dispatches experts through fused kernels
  (bc / `exl3_mgemm` / `exl3_moe`) that bypass it. `apply_to_native` prints a
  one-time warning; live `🎭` samples and `qlora_infer_native.py` will not
  reflect expert adapters. Deploy expert adapters by **merge-and-requantize**
  (already the recommended path per finding C). Attention/GDN/shared-expert
  adapters behave as before.
- **Cost:** every routed expert with ≥1 token in the batch dequantizes its
  3 trellis weights per layer per forward (and again in the checkpointed
  backward). At training batch sizes most experts are hit, so expect MoE
  steps to be dequant-heavy — record `--profile-dequant 5` on the first run
  (audit item A1, dequant caching, will matter more here than anywhere).
- One small host sync per MoE layer per forward (the expert-count bincount →
  `tolist`), same as inference pays.
- **Train bf16, not fp16** (unsloth force-upcasts qwen3.5/qwen3_moe: "fp16
  NaNs grad norms"); bf16 is already our default compute dtype.
- The fp32 validate gate computes router logits in fp32 vs the kernel's fp16
  hgemm + fp16 radix-sort top-k — a near-tie between two experts can select
  differently and show as a small per-token logit diff. Expect a slightly
  lower (still ~99%+) argmax agreement than dense models; a large drop means
  a real bug, not routing ties.

**Box list for next session (in order):**
1. **Forward gates on a real Qwen3.5-MoE EXL3 quant**:
   `qlora_validate_native.py --model $QWEN35_MOE` (fp32 eager; expect high
   argmax agreement, see the routing-tie caveat), then `--compute-dtype
   bfloat16` (fla chunked + flash on the attn layers; `describe_attn` should
   print the `[moe: ...]` summary), then `--check-backward`. A Qwen3-MoE
   quant (e.g. Qwen3-30B-A3B) also gates the no-shared-expert + packing
   path if available.
2. **Training smoke** (`--prompt-format qwen3.5-nothink`, `--inspect 3`
   first): default targets (attention + shared expert; expect the "routed
   experts stay FROZEN" note), short unpacked run, watch loss / grad norm /
   `|dB|` / tok/s and `--profile-dequant 5` (expect a much higher dequant
   share than dense).
3. **Expert-adapter smoke**: same run + `--targets ... expert_gate_proj
   expert_up_proj expert_down_proj --expert-r 1..4`; verify the trainable-
   param count print, per-step time hit, and that a save → `--resume`
   round-trips (shape-checked). Check `adapter_config.json` has
   `rank_pattern` when `--expert-r` ≠ `--r`.
4. **A real SFT + eval-split run**, judged per the standing eval-prereq
   rules; A/B attention+shared vs +experts on held-out loss.

### Session 21 — Gemma4 MoE: alt residual channel + extra norms in the differentiable MoE

> Branch `claude/gemma-4-moe-training-t0kfee`. Container-verified (all CPU
> suites incl. the new Gemma4 tests in `tests/test_moe.py` pass);
> **nothing here is box-verified yet** — the box list below chains after the
> Session-20 Qwen-MoE gates. This session started as "implement Gemma4 MoE
> from scratch", then #136 (Session 20, built in a parallel session) merged
> mid-way with the generic BlockSparseMLP machinery — so the work became a
> review of #136 plus the Gemma4-specific delta on top of it.

**What Gemma4 MoE adds over the Qwen MoE layout (the spec, from
`architecture/gemma4.py` + `modules/block_sparse_mlp.py` +
`modules/transformer.py`):**
- **`alt_residual_channel`** — the routing input and the routed experts read
  the **RAW post-attention residual** (`params["residual"]`, stashed by
  `TransformerBlock.forward` before `pre_feedforward_layernorm`), NOT the
  block's normed MLP input. Only the **shared expert** (the dense GatedMLP
  that would be the whole MLP on a dense Gemma4) reads the normed input.
- **Four extra RMSNorms**: `router.scale` (a weighted RMSNorm on the routing
  input with `constant_scale = hidden_size**-0.5`, weight key without the
  `.weight` suffix), `pre_feedforward_layernorm_2` (routed experts' input),
  `post_feedforward_layernorm_2` (routed output sum), and
  `post_feedforward_layernorm_1` (shared expert output) — all applied INSIDE
  the MoE, before the block's outer `post_feedforward_layernorm` sandwich +
  `layer_scalar` (already supported since Session 6).
- **No shared gate** (the Qwen3.5-MoE sigmoid gate is absent); GeGLU
  activation; `router.per_expert_scale` (bf16, post-softmax — already
  supported); router key `router.proj` (leaf `proj`, so no target-name
  collision).
- **Attention half needs nothing new**: per-layer head dims (global layers
  head_dim 512 → the big-head SDPA-math branch, Session 8), per-layer kv
  heads (`num_global_kv_heads`), `attention_k_eq_v` → `use_k_as_v` — checked
  this session that inference applies `v_norm` to the k-as-v copy taken from
  the RAW K projection (attn.py `project_qkv`), which is exactly what
  `_block_forward` already does. MTP tensors in the checkpoint are not
  loaded (`component="text"`; Session 7 note).

**What was changed:**
- `training/backbone.py`: `_assert_moe_supported` accepts
  `alt_residual_channel` and the four extra norms (still rejects ds3/dots
  routers, TP splits, `routed_scaling_factor`, `e_score_correction_bias`);
  `_mlp_metadata` gains `alt_residual_channel`; new seam accessor
  `moe_extra_norms(block)` → the four norm modules.
- `training/native_llama.py`: `_moe_out` gains the `residual` channel —
  routing input `z = router_pre(residual)`, expert input
  `ye = routed_pre(residual)` (both fall back to the normed input when the
  specs/flag are absent, so the Qwen path is untouched), routed sum through
  `routed_post`, shared output through `shared_post` before the add.
  `_block_forward`/`_gdn_forward` pass the post-attention residual into
  `_mlp_out` (exactly what inference stashes as `params["residual"]`).
  Construction reads the four norm specs via the seam. Fixed the #136
  `rank_pattern` export regex: `.*\.mlp\.experts\..*` → `.*\.experts\.\d+\..*`
  (Gemma4 expert keys have no `.mlp.` segment — `...layers.N.experts.K.*`;
  the `\d+` keeps Qwen's `shared_expert` out).
- `_norm` now keeps fp64 inputs in fp64 (was `x.float()`, silently rounding
  the fp64 gradcheck path to fp32 — the Gemma4 MoE gradcheck goes through
  norms, which is how this surfaced; half/bf16/fp32 behavior is unchanged,
  and no real run uses fp64).
- `lora_init._apply_eva`: routed-expert adapters that streamed too few
  routed tokens in the pre-pass (rank starvation / no sketch at all) now
  keep their default init with a counted note instead of hard-failing —
  non-expert targets still fail hard (there it means the pre-pass budget is
  wrong). Relevant only for `--init-lora eva` + `expert_*` targets.
- `qlora_train_native_ddp.py` `allreduce_grads`: **zero-fill `None` grads
  before the all-reduce** — with routed-expert adapters an expert can get
  tokens on one rank but not another, and the old per-rank
  `if grad is not None` skipped collectives asymmetrically (hang / silent
  corruption). Latent since #136 added `--expert-r` to the DDP arm; zero is
  the correct "no tokens routed here" gradient.
- `tests/test_moe.py`: Gemma4-layout builder + independent reference
  (HF-style softmax-all/renormalize routing formulation, transcribed norms),
  forward match with DISTINCT tensors on the two input channels (a
  wrong-channel bug cannot pass), fp64 gradcheck w.r.t. BOTH channels,
  backward-reaches-adapters through both channels, and a full
  `_block_forward` wiring test (attention → sandwich → MoE fed the raw
  residual → outer post norm → layer_scalar vs an independent full-block
  reference). Docs: README status line, training/README MoE section, YAML
  targets comment.

**Review of #136 (recorded):** design confirmed against the inference module
and kernels (`routing_std_topk_kernel`: top-k over logits then softmax over
the selected k, `per_expert_scale` after — the training forward reproduces
it, and its equality with HF's `norm_topk_prob=True` formulation is what
`test_moe_matches_hf_reference` proves). Found one real bug (the
`rank_pattern` regex above, Gemma4-only) and one latent DDP hazard (the
`None`-grad all-reduce skip above); both fixed this session. Target
semantics (routed experts opt-in via `expert_*_proj`, router + shared gate
always frozen, no aux loss) match unsloth/axolotl/PEFT practice per the
Session-20 research and carry over to Gemma4 unchanged — on Gemma4 the
default `--targets` train attention + the shared expert, which is the
always-active dense path.

**Box list for next session (in order; needs a Gemma4-MoE EXL3 quant):**
1. **Forward gates**: `qlora_validate_native.py --model $GEMMA4_MOE` (fp32
   eager; expect high argmax agreement — the Session-20 routing-tie caveat
   applies, plus Gemma4's bf16 big-head SDPA borderline-token noise from
   Session 9 in the bf16 pass), then `--compute-dtype bfloat16`, then
   `--check-backward`. `describe_attn` should print `…×sdpa` for the global
   layers AND the `[moe: N layers x E experts, top-k]` summary.
2. **Training smoke** (default targets → attention + shared expert;
   `--sample-every 0`, `--prompt-format gemma4-nothink` on an instruct
   base): short run, watch loss / grad norms / `|dB|`, record
   `--profile-dequant 5` (expect the MoE dequant-share caveat from
   Session 20 to bite harder here — every routed expert hit per step
   dequantizes 3 trellis weights per layer).
3. **Expert-adapter smoke**: add `--targets ... expert_gate_proj
   expert_up_proj expert_down_proj --expert-r <small>`; verify the
   trainable-param print, a save → `--resume` round-trip, and that
   `adapter_config.json` carries the corrected `rank_pattern`
   (`.*\.experts\.\d+\..*`).
4. **A real SFT + eval-split run** per the standing eval-prereq rules;
   A/B attention+shared vs +experts on held-out loss.

### Session 22 — BOX-VERIFIED: S18 GDN + S20/S21 MoE forwards on the box; VL text-tower support; GDN training smoke

> Branch `training/gdn-vl-mrope-partial-rotary` (pushed to origin). First GPU
> box session for the Sessions 18/20/21 work. All three new differentiable
> forwards (Gated DeltaNet, Qwen BlockSparseMLP, Gemma4 alt-residual MoE) are
> now **box-verified correct, forward AND backward**, on real EXL3 quants —
> plus a clean first GDN training run. Three code fixes landed (below); CPU
> suite still 68 passed. Models used (all the user's own EXL3 quants):
> `Qwen_Qwen3.5-2B/4` (S18, turned out to be the **VL** variant),
> `Qwen_Qwen3.6-35B-A3B/6` (S20, 40L×256e top-8), and the
> `dr-house...gemma4...26B-A4B-4.45bpw` finetune (S21, 30L×128e top-8).

**Results (all `training/qlora_validate_native.py`):**
- **S18 Qwen3.5-2B (dense GDN):** fp32 eager, bf16 (fla chunked kernel), and
  `--check-backward` ALL PASS. 100% per-position argmax, cos 0.9999.
  `describe_attn` = `6×flash, 18×gdn [gdn: fla chunked kernel]`. The hard
  research forward (Session 18) is correct on real weights for the first time.
- **S20 Qwen3.6-35B-A3B (GDN + MoE):** forward CORRECT, backward PASS (grads on
  both GPUs). `--parallel split --use-per-device 18 23`.
- **S21 Gemma4-MoE (alt residual + 4 extra norms):** forward math CORRECT (7/8
  fp32 prompts cos 0.9999 incl. one that spiked Δ=11.9 in bf16), backward PASS.
  Alt-residual channel + extra norms validated. `--parallel split
  --use-per-device 8 23` + `PYTORCH_CUDA_ALLOC_CONF=expandable_segments:True`
  (see split-balance note below).

**MoE validate-gate caveat (both MoE models, NOT a bug).** The strict PASS/FAIL
verdict is unreliable for MoE: the gate's fp32 router vs the kernel's fp16 hgemm
+ fp16 radix-sort top-k pick differently on a near-tie, and the reference oracle
is itself non-deterministic run-to-run on those ties (directly observed: native
flipped `young`↔`small` between identical runs). So a correct MoE forward shows
occasional per-token divergence (up to Δ≈8-12 on one unlucky prompt while others
are cos 0.9999) and the strict gate reports FAIL. Read MoE correctness from (a)
fp32 with MANY prompts — most cos 0.9999, a bug corrupts ALL prompts / ties
corrupt a few — and (b) backward PASS. **This is validation-only: training uses
our forward consistently and never compares against the kernel, so it does not
affect training.** Gate improvement (deferred, backlog): for MoE, report
aggregate argmax over N prompts vs a threshold and/or exclude tokens where the
oracle is non-deterministic.

**Split-balance note (Gemma4-MoE, 26B/4.45bpw ≈ 14.5GB).** The model fits in one
card's budget, so `--use-per-device 18 23` crammed all 30 layers on cuda:0 and
OOM'd the fp32 head reconstruction (2.75GB) with no headroom. Fix: STARVE cuda:0
(`--use-per-device 8 23`) so layers spill to cuda:1 and the output device keeps
room for the head; add `expandable_segments:True`. Bigger models (Qwen3.6-35B at
6bpw) split naturally.

**GDN training smoke — PASS (Qwen3.5-2B, semancy, r32/α64, 30 steps, single GPU,
`--prompt-format qwen3.5-nothink`).** First loss 3.02 (NOT ~11 random), EMA
3.02→2.72, grad norms stable 17-37 (NO 1e16 determinism-blowup), `|dB|` climbs
monotonically 0→1.58, cosine schedule exact. fla chunked kernel steady ~600
tok/s; **backward is ~70% of step wall** (GDN fla backward dominates), **dequant
27% of wall** (matches Session 12), peak VRAM 6.69GB, 36s. `--inspect 3` first
confirmed the nothink prompt masking + `<|im_end|>` turn-end. The Qwen3.5/3.6
hybrid GDN models now QLoRA-train end-to-end on EXL3.

**Code changes (branch `training/gdn-vl-mrope-partial-rotary`; all
backward-compatible, full-rotary / non-VL / CPU paths byte-identical):**
1. **VL text-tower support — mRoPE accepted for text-only training.** The
   `Qwen_Qwen3.5-2B/4` quant is the `Qwen3_5ForConditionalGeneration` (VL)
   variant (text tower `model.language_model`, vision tower present but never
   built/targeted). mRoPE differs from 1D NeoX RoPE only by giving different
   position indices to different frequency sections (image/video); for a
   pure-text sequence all sections share one position, so it reduces EXACTLY to
   1D RoPE — which `native_llama._apply_rope` already computes. Relaxed the
   `backbone.assert_block_supported` mRoPE assert + one-time startup note; the
   validate gate confirms the forward still matches the mRoPE-aware oracle.
   (Image+text multimodal still unsupported by design — needs 3D positions +
   the vision forward.) **Nobody has to strip the vision tower to train the LM.**
2. **Partial rotary** (`partial_rotary_factor < 1`, Qwen-VL = 0.25 → rotary_dim
   64 of head_dim 256). `_apply_rope` now rotates the leading `rotary_dim =
   2*inv_freq.numel()` dims and passes the rest through (recursion hits the
   full-rotary branch); assert relaxed to `rotary_dim <= head_dim`.
3. **Inference-tensor-in-backward fix (the important one — would crash ALL bf16
   GDN/MoE training, not just VL).** Frozen conv/norm weights load under
   `torch.inference_mode`; autograd refuses to save them for backward. The
   laundering casts (`w.to(dtype)` / `w.float()`) are NO-OPs when the stored
   dtype already equals the target (bf16 weight in a bf16 forward, fp32 norm on
   the fp32 path), so the raw inference tensor reaches `F.conv1d` / the GDN
   gated RMSNorm and backward dies ("Inference tensors cannot be saved for
   backward"). Fixed with a shared `backbone._frozen_normal()` =
   `detach().clone()` at spec-build in `block_metadata` (conv1d_weight/bias,
   a_log, dt_bias) + `norm_spec` / `gdn_norm_spec` (all norms), dtype-independent
   so it can't silently regress on a future dtype combo. Only bites in bf16, the
   actual training dtype — so it blocked the GDN/MoE training smoke entirely and
   was invisible to fp32 gates. Validated by the backward PASS on all three arches.

**Still open (next box session):** MoE training smokes with routed-expert
adapters (`--targets ... expert_gate_proj expert_up_proj expert_down_proj
--expert-r <small>`) on Qwen3.6-35B-A3B / Gemma4-MoE — verify the expert-adapter
param count, per-step dequant hit (expect much higher MoE dequant share), and a
save → `--resume` round-trip; then a real SFT + eval-split run per the standing
eval-prereq rules. The MoE validate-gate improvement above. Feature-test backlog
untouched this session (S17 quant-aware A/B, S16 DPO/KTO smokes).

### Session 23 — MoE routed-expert TRAINING SMOKE — PASS (Qwen3.6-35B-A3B)

> Branch `training/gdn-vl-mrope-partial-rotary`. First routed-expert QLoRA
> training run on EXL3. Model `/mnt/two/weights/Qwen_Qwen3.6-35B-A3B/6`
> (40L×256e top-8, GDN+MoE, VL text tower), semancy, `--parallel split
> --use-per-device 18 23` + `expandable_segments`, `--prompt-format
> qwen3.5-nothink`, r32/α64, **`--expert-r 2`**, targets = 7 defaults +
> `expert_gate_proj expert_up_proj expert_down_proj`. All smoke goals met.

- **Param count (routed experts fire):** 195,624,960 trainable (vs 31.26M for
  the dense-only GDN smoke). The saved adapter has 61,940 tensors, **61,440 of
  them routed-expert** = 40L × 256e × 3proj × 2 (A+B) exactly — none dropped.
  `expert-r 2` shapes correct (`down_proj.lora_A` `(2,512)`, `lora_B` `(2048,2)`).
  Non-expert targets saved under GDN names (`linear_attn.in_proj_qkv/in_proj_z`)
  — the target aliasing adapts hybrid GDN layers with the familiar q/k/v names.
  PEFT-standard keys (`base_model...experts.N.gate_proj.lora_A.weight`).
- **Trains healthy:** first loss 2.46 (NOT ~11 random → masking + nothink format
  correct on Qwen3.6 without a separate `--inspect`), dropping, `|dB|` climbs
  0→2.38 monotonically, grad norms 100–400 (cold-AdamW). Coherent base sample.
  28/12 layer split (head on cuda:1). Peak VRAM 21.1 / 14.3 GB — comfortable.
- **Save → `--resume` round-trip PASS:** checkpoints at `--save-every` step 10 &
  20 (10 target types). Resume restores **30,970 adapters + trainer state** (step
  counter + best_val; "optimizer state not restored" → cold AdamW, expected) and
  the 195.6M param count matches. Continued training steps 21–23 ran fine.
  **Gotcha:** `--steps` is the ABSOLUTE target, and resume restores the step
  counter, so `--resume` a step-20 ckpt needs `--steps > 20` (it warns cleanly
  "resume step 20 >= --steps N; nothing to do" and no-ops otherwise, doesn't
  crash). Also `--resume` restarts the DATA ITERATOR from the seeded-shuffle
  start (does not restore data position) → resumed steps re-see early examples
  (loss dipped to ~0.7 on already-seen rows; benign, LR was at the cosine tail so
  `|dB|` barely moved — measurement, not learning).
- **Dequant share (the MoE cost characterization):** `--profile-dequant 3` →
  **21.560 s/step = 37% of step wall** (324,660 trellis reconstructions / 3
  steps ≈ 108k/step). vs the dense GDN smoke's **0.506 s/step** → MoE dequant is
  **~43× higher** (every step reconstructs ~30,720 expert matrices from the
  trellis, uncacheable at that count). Step wall otherwise bwd-dominated
  (fwd 29% / bwd 67% / opt 3%; GDN fla backward). **This makes MoE the prime
  target for backlog A1 (dequant 3×→1× per linear per step)** — a big win here.

**Still open (next box session):** the same routed-expert smoke on **Gemma4-MoE**
(30L×128e alt-residual; needs the starve-split `--use-per-device 8 23` +
`expandable_segments`) to confirm the alt-residual MoE training path; then a real
Qwen3.6-35B-A3B **SFT + eval-split** run (add `--eval-split test --save-best
--profile-dequant`). MoE validate-gate improvement. Feature-test backlog still
untouched (S17 quant-aware A/B, S16 DPO/KTO smokes).
### Session 24 — BOX-VERIFIED + MERGED: fused decode kernels silently dropped runtime LoRA (fix + reframe)

> Branch `claude/qlora-bitrate-update-floor-2yb7q0`, merged to master
> 2026-07-11 alongside the GDN/VL branch (Session 22). Found while
> investigating a box report: a `--quant-aware noise` adapter on a 4 bpw base
> trained fine (loss descended) but "applying the lora to the quant did not
> noticeably modify its behavior". Root cause is NOT the noise mode — it is an
> inference-side bug that affects EVERY runtime-applied adapter on an EXL3
> base. Originally container-verified (tripwire tests + py_compile); **now
> box-verified 2026-07-11 — payoff PASS and perf measured, see the box-results
> block at the end of this section.**

**The bug.** `Linear.forward` is the only place a runtime LoRA
(`model/lora.py`, `lora_a_tensors`/`lora_b_tensors`) is applied — and the
fused decode paths bypass it, reading trellis storage directly:

- `attn.py` `project_qkv`: when `bsz*q_len <= 32`, k/v go through the fused
  `multi_kv` `exl3_mgemm` (built at load for any EXL3 k/v pair with matching
  shape/K and no bias — i.e. every Llama-family quant), and q (+gate) through
  `multi_qg` on gated-attention models. **k/v LoRA never ran at decode; q
  LoRA also dropped on gated-attn models.** o_proj was unaffected.
- `sliding_attn.py` `project_qkv`: same two branches (Gemma).
- `mlp.py` `GatedMLP.forward`: gate/up via `multi_gu` mgemm at
  `bsz*q_len <= 32` (**gate/up LoRA dropped**; down survived), and on
  single-slice models the fully-fused `BC_GatedMLP` bsz-1 graph computes the
  whole MLP (**gate/up AND down dropped**). Plain `MLP` (non-gated) was
  always per-linear — unaffected.
- `block_sparse_mlp.py` (MoE routed experts): the quantized dispatch is
  mgemm/BC at essentially all batch sizes; the per-linear torch path only
  runs unquantized. **Routed-expert LoRA is effectively never applied at
  inference.** (Shared experts are a `GatedMLP` — covered by the fix.)

Net effect on a q,k,v,o,gate,up,down adapter on a quantized Llama: decode ran
only the q + o (sometimes down) components. Worse, the `> 32` threshold is on
*total tokens in the forward*, so the short demo prompts in
`qlora_infer_native.py` (~20–25 tokens with template) took the fused path even
at prefill. The failure is silent: the adapter loads, prints its tensor count,
generation stays coherent — it's just (mostly) the base model. Training-side
forwards (`DiffLinear` closures) and any >32-token batched eval apply the full
adapter, which is why train/eval looked healthy while generations didn't move.

**Reframe of earlier findings (important):** on a bf16 base
`quant_type != "exl3"`, no `MultiLinear` is ever built, and every projection
takes the LoRA-aware path. So Session 3's arc-C finding — "only the bf16 base
produced strong steering; the 4bpw base didn't" — is exactly this bug's
signature and is confounded, along with any conclusion built on it (the
"attenuated LoRA on quant" reading that motivated parts of the quant-aware
arc). The merge-and-requantize concern remains real in theory, but the
*measured* attenuation evidence must be re-taken after this fix. Yesterday's
noise-mode test is unjudgeable; the Session 17 A/B/A2 needs the fixed
inference path.

**The fix.** `has_runtime_lora(*linears)` (`modules/linear.py`) + fall back to
the per-linear path when any involved Linear carries LoRA tensors:

- `attn.py`/`sliding_attn.py`: both fused branches guard on
  `has_runtime_lora(q,g)` / `has_runtime_lora(k,v)`.
- `mlp.py` `GatedMLP.forward`: `gu_lora`/`down_lora` computed ONCE across all
  slices (uniform branch choice — mixed branches disagree on the working
  shape of `x`); the `multi_gu` branch guards on `gu_lora`, the BC bsz-1
  branch additionally yields to the mgemm branch (which calls
  `downs[s].forward`) on `down_lora`.
- MoE routed experts: NOT fixed (a per-expert fallback or post-mgemm LoRA add
  is a bigger change); `LoRA.__init__` now prints a loud warning when target
  modules match `\.experts\.\d+\.` so an expert adapter can't be silently
  judged a no-op. Merge-path deployment is unaffected.

**Cost:** zero when no adapter is loaded (an empty-dict truthiness check per
forward; the fused kernels run exactly as before — the off path is
behaviorally identical). While an adapter IS loaded, decode takes the same
per-linear path prefill already uses (2 kernel launches instead of 1 fused
mgemm per pair, no BC graph) plus the two small LoRA GEMVs per adapted
projection that correctness requires anyway. Expect a modest decode tok/s hit
only while adapted — worst on small models where launch overhead dominates;
`unload()` restores full fused speed. If the hit matters later, the follow-up
is adding the LoRA contribution on top of the fused kernels instead of
falling back (keeps mgemm; BC stays disabled under LoRA since gate/up inject
before the activation).

**Tests** (`tests/test_lora_fused_path.py`; pass in-container): dependency-
free source tripwires on every guard (the failure mode is silent, so a
refactor dropping a guard must fail loudly) + torch-gated semantics of
`has_runtime_lora`. The end-to-end check needs the box.

**BOX RESULTS (2026-07-11) — payoff PASS, perf worse than "modest".** Verified
on the box (Llama-3.2-1B/3B 4bpw, native infer path):
1. **Payoff check — PASS, decisive.** Fresh 30/40-step `--uppercase-response`
   adapter on Llama-3.2-1B 4bpw (`out/allcaps_fixtest`, `|dB|` 0→4.6). Same
   adapter, same 4× effective scaling, only the fix code differs:
   **BEFORE** the fix the ADAPTED generation is normal case ≈ base (adapter
   silently dropped at decode); **AFTER**, it SHOUTS IN CAPS. The live 🎭
   training sample was likewise stuck normal-case because it uses
   `apply_to_native` → the same fused decode path. Diagnosis confirmed. (The
   caps carry UwU flavor only because the default dataset is `UwU_Alpaca` and
   we uppercased *its* responses — irrelevant to the fix.)
2. **Perf sanity — no-adapter path is free; while-adapted hit is LARGE, not
   "modest".** Decode tok/s (greedy, 200 tok): 1B r32 — no-adapter 268, adapter
   loaded 93 (**−65%**), after `unload()` 262 (−2%, noise). 3B r128 —
   no-adapter 133, adapter loaded 54 (**−59%**), after `unload()` 133 (−0.4%).
   So: **zero cost with no adapter** (off path behaviorally identical; base
   generations byte-identical before/after the fix, `unload()` restores full
   fused speed) but a **~60% decode slowdown WHILE a runtime adapter is loaded**
   on these small models — the fallback trades the fused mgemm for per-linear
   launches + LoRA GEMVs, worst where launch overhead dominates (small models,
   short decode). The "modest" wording above was optimistic. Mitigations already
   named: `unload()` when not steering, deploy via merge-and-requantize (no
   runtime adapter), and the follow-up optimization below. **(Backlog item added
   — see backlog "Fused-kernel LoRA (recover the decode perf)".)**

**Still open after this session:**
3. **Re-run the Session 17 A/B/A2** (none vs noise vs ste) — now that the
   inference path is fixed, both the as-trained steering judgment and the
   merge-and-requantize judgment are finally clean. (The `sem-no-QA` /
   `sem-QA-LORA` r256 3B adapters on disk look like a prior A/B pair — re-judge
   them on the fixed path.)
4. **Re-examine Session 3 arc C** (bf16 vs 4bpw steering gap) with the fixed
   path before trusting any remaining "attenuation at 4bpw" claims — the gap
   should shrink; whatever remains is the real quant effect.
5. **Fused-kernel LoRA perf follow-up** (new backlog item) — add the LoRA delta
   on top of the fused mgemm instead of falling back to the per-linear path, to
   recover most of the ~60% while-adapted decode hit measured above.

---

### Session 25 — BOX A/B on quant-aware LoRA → SHELVED (early-stopping wins)

> No branch/commit — an experiment, not a code change. The `--quant-aware`
> feature (Session 17) got its first-ever box run and its decision A/B. The
> user decided to **scrap quant-aware LoRA**. Code left in tree as a
> documented negative result. Experiment artifacts under `/mnt/two/qa_lora_exp/`
> (merged bf16 + requants + KL logs); merge script in the scratchpad (see below).

**Setup.** Llama-3.2-3B, deploy target **3bpw**, dataset `UnstableLlama/semancy`
(chat `messages`; 436 train / **116-row `test` split held out** — a real
generalization eval, not a val-frac carve). Adapters: r256/α256, **default
init** (so merge = plain `W + (α/r)·BA`), lr **5e-5**, 2 epochs (110 steps),
`--compute-dtype bfloat16`. Deploy path judged by **merge-into-bf16 →
requantize to 3bpw → eval**, plus **KL(quant‖its-own-bf16)** via
`eval/model_diff.py` (wiki2, 100 rows) as the clean quant-distortion metric.

**First box run of `--quant-aware` — the S17 box list items 1–2 PASS** (even
though the feature is being shelved, the mechanics are now box-verified):
σ measured vs the bf16 ref = **~15% relative at 3bpw** (median 14.8; on the
S17 curve between ~6% @4bpw and ~18% @2.5bpw), and the **determinism contract
holds** (grad norms steady ~3–7, no 1e16 blowup).

**Results (all merged+requantized at matched `-b 3.0`):**

| arm | test loss | `‖dB‖` | KL(quant‖bf16) | top-1 |
|-----|-----------|--------|----------------|-------|
| base (no adapter) | 3.533 | 0 | 0.060\* | — |
| `none` full (overfit) | 3.043 | 9.26 | 0.1036 | 0.847 |
| `noise` (quant-aware) | 2.817 | 9.29 | 0.0705 | 0.866 |
| **`none` early-stop @40** | 2.853 | 5.26 | **0.0576** | 0.876 |

\*base KL has a convert-settings caveat (`/3/` predates the `-b 3.0` run); the
other three are matched. Merge+requant was ~**lossless on task loss** for both
full arms (none 3.043→3.035, noise 2.817→2.813) — the deploy degradation the
S17 thesis worried about did NOT show up on task loss at 3bpw; it only showed
in KL.

**Verdict — scrap.** The plain **early-stopped** adapter matched `noise` on
generalization (2.853 vs 2.817) AND quantized *better* (KL 0.0576 vs 0.0705,
≈ the base model's own 3bpw distortion) for less than half the compute and no
QA machinery. The real driver of quant-fragility was **overfitting** (r256 on
436 rows → sharp, quant-fragile directions, KL 0.104), not quantization
geometry: `noise` only *partially* undid it (regularization, 0.104→0.070),
while early-stopping avoids it entirely (0.104→0.058). So `noise`'s apparent
"win" over the overtrained plain arm was regularization all along, and the
vanilla regularizer does it better. Combined with the Session-24 finding
(QA's original motivation — weak LoRAs on quants — was the fused-decode bug,
now fixed), quant-aware LoRA has no remaining justification here.

**Caveats / not covered:** single regime (3bpw, one 436-row dataset, r256);
S17 predicted the payoff grows at **2.5bpw** (~3× quant error) — the user
declined that check. **`ste`** mode untested (only `noise` ran), but it would
now have to beat early-stopping. If quant-aware is ever revisited, 2.5bpw +
`ste` is the only lane with a chance.

**Reusable artifact built:** `merge_lora_bf16.py` (currently in the session
scratchpad, NOT committed) — folds a PEFT/native default-init adapter into
bf16 HF weights (`W += (α/r)·B@A`, preserves shard layout so `convert.py`
consumes the output directly). Construction-validated (untouched tensors
bit-identical; target delta matches `B@A`). This is the missing
merge-and-requantize deploy tool referenced since Session 3; worth committing
to `training/` if the deploy path is wanted. **PiSSA adapters need the 2r
offset form** — the script asserts on a rank mismatch rather than
mis-merging.

### Session 26 — MERGED turbo's v1.0.0-prep dev refactor; LoRA guards extended to the new fused paths; MoE expert-adapter blocker CLOSED (code)

> Branch `dev-merge` (commits `5beda4d` merge + `0dc258e` guards). Merged
> upstream/dev at `1d44bd6` (95 commits: CUDA-graph decode paths everywhere,
> FA2 removed, int8/mul1 mode on by default, extension split into compilation
> units — 142 C++ files; we touch zero C++). Only 2 textual conflicts
> (xformers.py — same ImportError fix both sides, took theirs; mlp.py — BC
> branch reordered, guards re-placed). All our hooks survived the automerge
> (`has_runtime_lora` guards, `lora_full_weight`, `get_weight_tensor_slice`;
> `ext.reconstruct_slice` signature unchanged).

**The real risk was semantic, not textual:** upstream added NEW fused paths
that bypass `Linear.forward` — exactly the Session-24 silent-no-op class.
All now guarded at their per-call dispatch (graphs stay cached; adapters can
attach/detach between calls):

- `attn.py` / `sliding_attn.py`: `bc_attn_step` / `bc_swa_step` graph-captured
  decode blocks (all projections through o_proj as one C++ call, bsz≤4 q_len≤16).
- `gated_delta_net.py`: `BC_GatedDeltaNetSplit` bsz-1 whole-layer fused decode
  (Qwen3.5 split layout; qkv/z/o trellis + merged base-only `ba_weight_t`).
  The non-split `BC_GatedDeltaNet` (`run_bsz1_a/b`) has no Python dispatch yet
  — re-audit when turbo wires it.
- `block_sparse_mlp.py`: **this closes backlog item "runtime LoRA not applied
  on fused MoE expert path" (Session 24 note) in code** — `experts_lora`
  forces the per-expert torch branch past `exl3_moe`, the BC single-expert
  graph/DQ kernels, and the bsz-1 graph; `sh_fused_lora` keeps the bsz-1 graph
  (which embeds shared experts + shared gate) honest; `add_sigmoid_gate_proj`
  falls back when the shared gate carries LoRA. `lora.py` warning downgraded
  to a slow-path notice (expert adapters now apply, unfused = slower decode —
  merge for deploy). **Router LoRA remains unsupported** (routing reads
  `routing_gate.inner.weight` raw on every path) — documented, not guarded.

**Verified on the box (this machine, 2×3090):**
- CPU training suite 64/64; `test_lora_fused_path.py` tripwires extended to
  every new guard, 10/10.
- Ext rebuilt clean from merged C++ (`setup.py build_ext --inplace`).
- End-to-end fused-path LoRA smoke (Llama-3.2-1B 4bpw, adapter
  `/mnt/two/Weights/qlora_test/base`, bsz-1 decode = the new graph path):
  base coherent → adapter visibly pirates the output → unload restores
  bit-identical base. Guards engage and release.

**Known-stale upstream tests, do not chase:** `test_ext_norm.py`,
`test_rope.py`, `test_kv_quant.py`, `test_cache_rotate.py`,
`test_gated_delta_rule.py` (~488 failures) call pre-refactor kernel
signatures and fail identically on a pristine upstream/dev checkout —
upstream test debt, not a merge regression.

**Still on the box list:** MoE expert-adapter END-TO-END (guard fires, output
changes, decode slower-but-correct) — the gemma4moe semancy adapters were
deleted, so this waits for the next trained expert adapter. GDN adapter-loaded
decode smoke (Qwen3.5) likewise pending a GDN-target adapter. Expect a small
follow-up merge when turbo tags v1.0.0.

---

## 0d. Multi-GPU strategy (rationale)

"Multi-GPU" splits by *goal*, and QLoRA changes which tool fits, because only the
tiny LoRA params train and the frozen quantized base is small:

- **DDP (data parallel) — easy, the right default for throughput.** Replicate the
  small quantized model per GPU, shard the batch, all-reduce only the LoRA grads
  (a few MB). Built (`qlora_train_native_ddp.py`), confirmed on 2× 3090. We
  hand-average the LoRA grads rather than wrapping in
  `nn.parallel.DistributedDataParallel`, because the module is mostly frozen
  buffers + a custom `autograd.Function` + grad checkpointing, which DDP's
  bucketing handles awkwardly.
- **Pipeline / layer-split — moderate, for models too big for one GPU.** exllamav3
  already splits layers across GPUs for *inference*; the native training forward
  would need to be made device-aware (move hidden states across block boundaries;
  autograd handles cross-device grads). Not built.
- **FSDP — hard, and usually the WRONG tool here.** Its value is sharding huge
  *trainable* params + optimizer; here the trainable surface is tiny and the frozen
  base is a packed trellis that doesn't shard like bf16. You'd gain ~nothing and do
  real engineering to make the packed format FSDP-compatible (cf. Answer.AI's
  FSDP-QLoRA, a genuine research project for exactly this). EXL3's compression also
  partly dissolves FSDP's main use case: a 70B at 2.5bpw is ~22GB → fits one 24GB
  card, so you may never need to shard the model — DDP for throughput +
  pipeline-split for long context is enough.

**Implications (the real prize):** EXL3 makes a bitrate regime *trainable* that
BNB NF4 can't reach (NF4 is unusable ≤3bpw; EXL3's trellis stays coherent at
2.5–3bpw). So QLoRA on a 2.5bpw 70B fits a single 24GB card, and you train the
adapter against the *exact* weights you deploy (no train/serve quant mismatch).
Expected outcome: rough parity with BNB at 4-bit, clear EXL3 win in the low-bitrate
regime. The flagship experiment to substantiate it: same model fine-tuned BNB-NF4
vs EXL3-4bpw vs EXL3-~2.5bpw at matched VRAM, compared on a real downstream metric
+ tokens/sec.

---

---

## 1. TL;DR status (historical — see §0 for the resolved status)

> This section describes the state *before* the transformers-free native path was
> built and run. The "Blocker" below was resolved by §0/§0b, not by fixing the
> transformers-5.x forward. Kept for context.

- **The QLoRA-on-EXL3 mechanism is built and verified.** Differentiable EXL3
  linear, fused cross-entropy head, adapter attach/save/load — all gradcheck-
  verified on CPU, and the per-layer forward matches the EXL3 kernel to 0.07%.
- **Native exllamav3 inference + native LoRA loading both work** (coherent base
  generation, adapter applies).
- **Blocker:** the only *differentiable* forward we have for training is the HF
  Transformers integration, and it is **broken on every transformers version
  available on this machine**:
  - transformers **5.x**: EXL3 quantizer engages, per-layer weights correct,
    but the assembled forward produces garbage (RoPE/attention mismatch).
  - transformers **4.56 / 4.57**: quantizer does **not** engage at all — model
    loads with random weights.
- **Plan (option 1, chosen):** go back to transformers **5.x** (the only version
  where the quantizer engages), diagnose the localized forward bug (almost
  certainly RoPE), patch it, then train for real.

The previously-trained adapter at `.../4/pirate` is **garbage** (trained against
the broken 5.x forward, final loss ~10.37 ≈ random). Discard it.

---

## 2. Key paths & environment

**Model (EXL3, 4bpw):** `/mnt/two/Weights/meta-llama-Llama-3.2-1B-Instruct/4/`
- Llama-3.2-1B-Instruct, **tied embeddings** (`tie_word_embeddings: true`).
- `config.json` is complete and correct (`max_position_embeddings: 131072`,
  `rope_scaling: {rope_type: llama3, factor: 32, ...}`, `quantization_config:
  {quant_method: exl3, version 0.0.21, bits 4, head_bits 6}`).
- **`config.json` says `transformers_version: 4.45.0.dev0`** — the model (and its
  EXL3 calibration) was produced against transformers 4.45. This is the leading
  suspect for the 5.x forward mismatch.

**Bad adapter (discard):** `/mnt/two/Weights/meta-llama-Llama-3.2-1B-Instruct/4/pirate`

**Two venvs:**
- **`~/exl3/tabbyAPI/venv`** ("tabby") — the user's main venv. Uses exllamav3
  **natively** (transformers-independent). Do **NOT** further mutate it. (It was
  temporarily changed during this session; ideally restore it with
  `pip install "transformers==5.10.2" kernels`.)
- **`~/exl3/qlora-venv`** — the isolated venv we built for this work. Current
  consistent state:
  - torch **2.8.0+cu128**, triton 3.4.0
  - flash-attn **2.8.3.post1** (prebuilt wheel, cu12torch2.8 cxx11abiTRUE cp312)
  - transformers **4.56.1**, tokenizers 0.22, datasets, accelerate
  - pydantic **2.10.6** (pinned; 2.13 breaks formatron 0.5.0)
  - **xformers uninstalled** (optional fallback backend; was version-conflicting)
  - **no `kernels`** (conflicts with huggingface_hub strict dataclasses)
  - exllamav3 installed **editable** (`-e`) pointing at `~/exl3/private/exllamav3`;
    CUDA extension JIT-built and cached in `~/.cache/torch_extensions`.

**Env pitfalls (learned the hard way):**
- Do **not** re-run `pip install -e exllamav3` — its deps (xformers/
  flash-linear-attention) drag torch up to 2.12 and break the prebuilt EXL3 `.so`
  (ABI mismatch: `undefined symbol: ...c10_cuda_check_implementation`). If torch
  moves, pin it back: `pip install "torch==2.8.0" --index-url https://download.pytorch.org/whl/cu128`.
- xformers must match torch exactly; simplest is to leave it uninstalled (the
  package's existing `except ModuleNotFoundError` guard handles absence).
- Keep pydantic `<2.11`.

---

## 3. What was built (all committed on the branch)

### Training library — `exllamav3/training/`
- **`qlora_linear.py`**
  - `EXL3LoRAFunction` — memory-efficient `autograd.Function`. Forward
    `y = x @ W_eff + scale·(x@A@B) + bias`; backward recomputes `W_eff` from a
    `weight_fn` closure instead of storing it. Adapters can be fp32 master
    weights while compute is bf16/fp16 (cast inside fwd/bwd; no-op for the
    float64 gradcheck). **gradcheck-verified.**
  - `reference_forward` (plain-autograd ground truth), `qlora_linear_forward`,
    `QLoRALinear` (standalone nn.Module).
  - Key fact: `W_eff = LinearEXL3.get_weight_tensor()`, shape `[in, out]`,
    so `y = x @ W_eff`. **Verified equal to the EXL3 kernel forward to
    rel_err 0.00067** (and `W.t()` gives 1.41 — orientation confirmed).
- **`fused_ce.py`** — `FusedLinearCrossEntropy`: streaming linear cross-entropy
  over token chunks; never materializes `[tokens, vocab]` logits; recomputes the
  frozen head weight in backward. `qlora_causal_lm_loss(model, ...)` wires it via
  `get_decoder()` / `get_output_embeddings()` (unwraps DataParallel). Promotes to
  ≥fp32 internally. **All correctness tests pass** (matches `F.cross_entropy`,
  ignore_index, chunk-invariant, gradcheck, shifted-CausalLM wiring).
- **`hf_qlora.py`**
  - `Exl3LoRALinear` — trainable wrapper over a frozen `Exl3HfLinear`; base
    weight reconstructed on the fly; only `lora_a`/`lora_b` (fp32) train; B=0 init.
  - `attach_qlora(model, r, alpha, target_modules, ...)` — swaps matching EXL3
    linears for trainable wrappers, freezes everything else.
  - `prepare_model_for_qlora_training(model)` — gradient checkpointing +
    `enable_input_require_grads()` + `use_cache=False`.
  - `save_lora_adapter` / `load_lora_adapter` — PEFT format, compatible with both
    PEFT and the native `exllamav3.model.lora.LoRA` loader (verified orientation).

### Examples — `examples/`
- **`qlora_train.py`** — HF Trainer QLoRA. Defaults: dataset
  `TeeZee/dolly-15k-pirate-speech`, completion-only label masking, bf16 compute,
  fp32 adapters, fused-CE `compute_loss`, gradient checkpointing, live pirate
  sampling every N steps (`--sample-every 0` to disable). Monkeypatches
  `transformers.trainer.validate_quantization_for_training` to bypass the
  "purely quantized" guard (works on 5.x; see §5 note for 4.56).
- **`qlora_infer.py`** — HF before/after (depends on a working HF forward; broken
  until the forward bug is fixed).
- **`qlora_infer_native.py`** — **WORKS.** Native exllamav3 forward + native
  `LoRA.from_directory`. Use this to validate any adapter regardless of the HF
  mess.

### Tests — `tests/` (all pass on CPU, torch only)
- `test_qlora_grad.py` (tiers 1–2 always; tier 3 GPU/model opt-in),
  `test_qlora_train_loop.py`, `test_fused_ce.py`.

### Library fix kept (legit, not a workaround)
- `exllamav3/integration/transformers.py`: `Exl3HfLinear.weight` is now a frozen
  `nn.Parameter` (was a bare tensor) — fixes a crash in modern transformers'
  tied-weight finalizer (`get_parameter('...weight')` → "is not an nn.Parameter").

### Docs
- `doc/qlora_feasibility.md` — the design rationale / roadmap.
- `doc/qlora_handoff.md` — this file.

---

## 4. The bug to fix (the whole ballgame)

On **transformers 5.10.2** (the only version where the quantizer engages):
- `AutoModelForCausalLM.from_pretrained` engages `Exl3HfQuantizer`; 113
  `Exl3HfLinear` modules present; one probed layer matches the kernel to 0.07%.
- `embed_tokens`: healthy (`mean_abs 0.016`, fp16, cuda, no NaN).
- final-norm weight `mean_abs 2.35` (plausible for Llama-3.2; unverified).
- **But the full forward is garbage:** `"The capital of France is"` →
  `loss 15.7` (random ≈ `ln(128256)=11.76`), top-5 next-token = junk
  (`ĠComfort`, `Ġtrack`, …). Generation is word-salad. Training `train_loss ≈ 10.37`.

**Localization already established:** `qlora_causal_lm_loss` builds logits from
the **decoder's hidden states** × the **verified-correct** `lm_head` weight
(`get_weight_tensor`). It still gives ~10.37 → **the backbone (decoder) produces
bad hidden states**, not just the head. Backbone linears + embeddings are correct
→ the break is in the stock-transformers assembly: **RoPE / attention / norm**.

**Leading hypothesis: RoPE.** The model + EXL3 calibration are from transformers
4.45 (`config.json`), and 5.x changed `llama3` rope handling
(`modeling_rope_utils.standardize_rope_params`, etc.). Wrong positional encoding
→ wrong attention → garbage hidden states. (A later 5.x reinstall even *crashed*
in `standardize_rope_params` accessing `max_position_embeddings` — an extra clue
that rope handling is the fragile area, though that particular crash was env
churn.)

**Quantizer-engagement matrix (important):**
| transformers | quantizer engages? | forward correct? |
|---|---|---|
| 5.10.2 | **yes** (113 layers) | no (rope-garbage) |
| 4.57.x | no (random weights) | n/a |
| 4.56.1 | no (random weights) | n/a |

So 5.x is the only viable base; the task is to fix its forward.

---

## 5. Plan for option 1 (fix the 5.x forward)

**Step 0 — get a clean transformers 5.x env where the quantizer engages.**
Either switch `~/exl3/qlora-venv` to 5.x or make a parallel one. In qlora-venv:
```
pip install "transformers==5.10.2"
```
Watch for dep churn (it may pull newer tokenizers/hub; keep `pydantic<2.11`,
keep xformers uninstalled, keep `kernels` uninstalled). Re-confirm import:
```
python -c "import exllamav3, transformers; print(transformers.__version__)"
```
Sanity that the quantizer engages (want a count in the hundreds, not 0):
```
python - <<'PY'
import torch
from transformers import AutoModelForCausalLM
from exllamav3.integration.transformers import patch_transformers, Exl3HfLinear
patch_transformers()
m=AutoModelForCausalLM.from_pretrained("/mnt/two/Weights/meta-llama-Llama-3.2-1B-Instruct/4/", device_map="cuda", dtype=torch.float16)
print("EXL3 linears:", sum(isinstance(x,Exl3HfLinear) for x in m.modules()))
PY
```

**Step 1 — localize where hidden states go bad** (the probe that never ran):
```
CUDA_VISIBLE_DEVICES=0 python - <<'PY'
import torch
from transformers import AutoModelForCausalLM, AutoTokenizer
from exllamav3.integration.transformers import patch_transformers
patch_transformers()
d="/mnt/two/Weights/meta-llama-Llama-3.2-1B-Instruct/4/"
tok=AutoTokenizer.from_pretrained(d)
m=AutoModelForCausalLM.from_pretrained(d, device_map="cuda", dtype=torch.float16)
ids=tok("The capital of France is", return_tensors="pt").input_ids.to(m.device)
out=m(input_ids=ids, output_hidden_states=True)
for i,h in enumerate(out.hidden_states):
    v=h[0,-1].float()
    print(f"h{i:2d} norm {v.norm():8.2f} absmax {v.abs().max():8.2f} nan {bool(torch.isnan(v).any())}")
print("top5:", tok.convert_ids_to_tokens(out.logits[0,-1].topk(5).indices.tolist()))
PY
```
Interpretation:
- norms explode / NaN at layer N → that block's attention/MLP (rope!).
- norms sane but top-5 junk → final norm or lm_head.
- already bad at h0/h1 → embedding / first block.

**Step 2 — confirm RoPE by differencing against the native (correct) forward.**
The native exllamav3 model loads and forwards correctly; use it as the oracle.
Compare HF vs native hidden states / attention for the same `input_ids` at layer 0
(q/k after rope). exllamav3's own rope implementation
(`exllamav3/util/rope.py`, `exllamav3_ext` rope, `RopeSettings/RopeStyle`) is the
reference for what the weights expect (llama3 scaling: factor 32, low 1, high 4,
orig_max 8192, theta 5e5).

**Step 3 — fix.** Most likely one of:
- Force transformers to compute the llama3 rope the 4.45-compatible way (override
  `config.rope_scaling`, or set the rotary implementation explicitly), or
- Patch the integration to inject a correct rotary embedding for these models, or
- If it turns out to be attention (e.g. an `attn_implementation` default change in
  5.x), set `attn_implementation="eager"`/`"sdpa"` explicitly at load.

Iterate against Step 1's probe until `loss` on "The capital of France is" is low
(~2–4) and top-5 is `[' Paris', ...]`.

**Step 4 — train for real & verify.**
```
CUDA_VISIBLE_DEVICES=0 python examples/qlora_train.py \
  --model /mnt/two/Weights/meta-llama-Llama-3.2-1B-Instruct/4/ \
  --out   /mnt/two/Weights/meta-llama-Llama-3.2-1B-Instruct/4/pirate2 \
  --sample-every 0
```
Expect first loss ~2–4 and dropping. Then verify the adapter on the **native**
path (transformers-independent, always works):
```
CUDA_VISIBLE_DEVICES=0 python training/qlora_infer_native.py \
  --model /mnt/two/Weights/meta-llama-Llama-3.2-1B-Instruct/4/ \
  --adapter /mnt/two/Weights/meta-llama-Llama-3.2-1B-Instruct/4/pirate2
```
Success = BASE coherent English, ADAPTED coherent pirate ("Arrr", "matey", "th'").

**Trainer guard note:** on 5.x the "purely quantized" check is
`validate_quantization_for_training` (already monkeypatched in
`qlora_train.py`). If on some version it instead raises from `Trainer.__init__`
directly (as seen on 4.56, `trainer.py:566`), patch that path too / subclass to
skip. Not expected on 5.10.2.

---

## 6. Fallback (option 2, if 5.x forward proves unfixable)

Write a small **transformers-free differentiable Llama forward** (RMSNorm, GQA +
llama3 RoPE, SwiGLU) on exllamav3's native weights + `EXL3LoRAFunction` +
`FusedLinearCrossEntropy`. Validate logits against the native forward for one
input. ~200 lines, immune to transformers version drift. More work, but it can't
be broken upstream.

---

## 7. Quick reference — what's proven vs assumed

Proven (don't re-verify):
- `x @ get_weight_tensor()` == EXL3 kernel forward (rel_err 6.7e-4), orientation `[in,out]`.
- `EXL3LoRAFunction` and `FusedLinearCrossEntropy` backprops correct (gradcheck).
- Native inference + native `LoRA.from_directory` of our PEFT adapter work.
- CPU training-loop mechanics (mock EXL3 weight) reduce loss, freeze base, move adapters.

Assumed / unverified:
- That RoPE is the specific 5.x forward bug (strong hypothesis, not yet pinned).
- final-norm correctness on 5.x.
