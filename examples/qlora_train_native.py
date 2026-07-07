"""
QLoRA fine-tuning of an EXL3 model with NO HuggingFace Transformers in the loop.

This trains low-rank adapters on a frozen EXL3 model using exllamav3's own
weights and a transformers-free differentiable forward
(:class:`exllamav3.training.native_llama.NativeLlamaQLoRA`). It exists because
the Transformers-based path couples training to a specific transformers version
(the EXL3 Llama-3.2 weights were calibrated against 4.45 and 5.x mis-handles the
llama3 RoPE); the native path reuses the exact RoPE/norms/scale that
exllamav3's correct inference forward uses, so it can't be broken upstream.

Requirements (CUDA box with the exllamav3 extension built):
    pip install datasets            # note: NO transformers / accelerate needed

Usage:
    python examples/qlora_train_native.py \
        --model /path/to/exl3_model \
        --out   out/exl3_qlora_adapter

Defaults fine-tune on superdrew100/UwU_Alpaca_data: the Alpaca-cleaned
instruction set with every answer rewritten in over-the-top "UwU" furry speak
(caps, emoji, "OwO", "*twitches whiskers*"). Because it keeps Alpaca's clean
question->on-topic-answer structure, the model stays coherent while the style
is unmistakable at scale 1.0 -- unlike play-script style sets, whose responses
are tangential monologues that teach the model to ramble. (Note: the persona
has mild PG-13 innuendo in places.)

The data loader is dataset-agnostic: it reads instruction / context / response
columns whose names are configurable via --instruction-key / --context-key /
--response-key, so swapping in another instruction set (e.g. Dolly-schema
TeeZee/dolly-15k-pirate-speech via --instruction-key instruction --context-key
context --response-key response) needs no code change. Validate first with
examples/qlora_validate_native.py, then check the trained adapter with
examples/qlora_infer_native.py -- both are also transformers-free.

The adapter is saved in PEFT format, loadable by exllamav3.model.lora.LoRA
(and by PEFT).
"""

import argparse
import csv
import datetime
import math
import os
import random
import re
import shutil
import sys
import time
from collections import deque
import torch

from exllamav3 import Config, Model, Tokenizer
from exllamav3.training.native_llama import NativeLlamaQLoRA


class ThroughputMeter:
    """Rolling tok/s over a sliding window of recent steps, for a live readout.

    Tracks supervised (loss-bearing, labels != -100) and total (non-pad) tokens
    separately, so the per-step line can show real throughput rather than the
    run-average the final ``[PERF]`` line reports. Window-based (not cumulative)
    so the number reflects current steady state, not warmup. Time fed in should
    be the train-step compute only (exclude eval/sample/save) for a clean rate.
    """

    def __init__(self, window=20):
        self.buf = deque(maxlen=window)   # (dt, supervised_tokens, total_tokens)

    def update(self, dt, supervised, total):
        self.buf.append((float(dt), int(supervised), int(total)))

    def rates(self):
        """Return (supervised_tok_per_s, total_tok_per_s) over the window."""
        tt = sum(b[0] for b in self.buf)
        if tt <= 0:
            return 0.0, 0.0
        return sum(b[1] for b in self.buf) / tt, sum(b[2] for b in self.buf) / tt


class StepTimer:
    """Wall-clock breakdown of every training step into sections: ``data``
    (batch build/collate), ``fwd`` (loss forward), ``bwd`` (backward), ``opt``
    (grad clip + optimizer + scheduler step).

    ``mark(section)`` charges the time since the previous mark to ``section``;
    sections repeat within a step under grad accumulation and accumulate. On
    CUDA each mark synchronizes the active devices first, so async GPU work is
    charged to the section that launched it (a few extra syncs per step, ~µs
    each -- the loop already syncs at ``loss.item()`` / ``gnorm.item()``).

    Keeps cumulative totals (for the ``[PERF]`` summary and the run-log CSV)
    plus a rolling window of recent steps (for the live per-step line), so a
    run answers "where does the time go" without a separate profiling run.
    """

    SECTIONS = ("data", "fwd", "bwd", "opt")

    def __init__(self, devices=None, window=20):
        # devices: CUDA device indices to synchronize at each mark (the split
        # load spans several); None -> current device only.
        self.devices = devices
        self.total = {s: 0.0 for s in self.SECTIONS}
        self.steps = 0
        self.win = deque(maxlen=window)
        self._cur = None
        self._t = None

    def _now(self):
        if torch.cuda.is_available():
            for d in (self.devices or [None]):
                torch.cuda.synchronize(d)
        return time.perf_counter()

    def begin_step(self):
        self._cur = {s: 0.0 for s in self.SECTIONS}
        self._t = self._now()

    def mark(self, section):
        t = self._now()
        self._cur[section] += t - self._t
        self._t = t

    def end_step(self):
        for s in self.SECTIONS:
            self.total[s] += self._cur[s]
        self.steps += 1
        self.win.append(self._cur)
        self._cur = None

    def step_line(self):
        """Compact rolling mean for the per-step line, e.g.
        ``1.84s: f 52% b 39% o 8%`` (data shown only when it reaches 1%)."""
        if not self.win:
            return ""
        n = len(self.win)
        avg = {s: sum(w[s] for w in self.win) / n for s in self.SECTIONS}
        tot = sum(avg.values())
        if tot <= 0:
            return ""
        parts = []
        for key, label in (("data", "d"), ("fwd", "f"), ("bwd", "b"), ("opt", "o")):
            pct = 100.0 * avg[key] / tot
            if key != "data" or pct >= 1.0:
                parts.append(f"{label} {pct:.0f}%")
        return f"{tot:.2f}s: " + " ".join(parts)

    def summary(self):
        """Run-total split for the [PERF] line, e.g. ``data 1% fwd 51% bwd 40% opt 8%``."""
        tot = sum(self.total.values())
        if tot <= 0:
            return "n/a"
        return " ".join(f"{s} {100.0 * self.total[s] / tot:.0f}%" for s in self.SECTIONS)


# Canonical schema for the per-run CSV log. Fixed order so the "mega CSV" stays
# consistent across runs/arms; the BNB arm inlines an identical copy (separate
# venv) and the DDP script imports these. Unknown keys are ignored and missing
# fields written blank, so adding a column later only needs an entry here.
RUN_LOG_FIELDS = [
    "timestamp", "arm", "status", "model", "arch", "out",
    "dataset", "eval_split", "eval_dataset", "eval2_dataset",
    "r", "alpha", "use_rslora", "init_lora", "lr", "scheduler", "warmup_steps", "weight_decay",
    "batch", "grad_accum", "world_size", "eff_batch",
    "epochs", "steps_planned", "steps_done", "seq_len",
    "targets", "compute_dtype", "attn_impl", "parallel", "shuffle", "pack", "pack_algo", "ga_loss",
    "max_samples", "train_embeddings", "train_head", "prompt_format",
    "trainable_params", "n_train", "n_val", "n_eval2",
    "start_loss", "end_loss", "best_val", "best_val_step",
    "start_val", "start_eval2", "final_val", "final_eval2",
    "total_s", "s_per_step", "sup_tok_s", "tot_tok_s", "peak_vram_gb",
    # Wall-clock section totals (seconds) from StepTimer, and the measured
    # dequant (trellis reconstruction) time per step when --profile-dequant ran.
    "t_data_s", "t_fwd_s", "t_bwd_s", "t_opt_s", "dequant_s_per_step",
    # Failure forensics: where the run died and the exception summary. Blank
    # for completed runs; status=failed rows carry them, so the CSV doubles as
    # a lab notebook of what was tried and why it fell over.
    "phase", "error",
    "notes",
]


def append_run_log(path, record):
    """Append one run's metadata as a row to a CSV (header written once on
    create). Pure stdlib so the DDP script imports it and the BNB arm inlines a
    copy. Keys outside RUN_LOG_FIELDS are ignored and missing fields left blank.
    If an existing file's header doesn't match the current schema (columns were
    added/removed), the old file is moved aside to ``<path>.bak`` and a fresh one
    started, so the CSV never ends up with misaligned rows."""
    if not path:
        return
    path = os.path.abspath(path)
    os.makedirs(os.path.dirname(path) or ".", exist_ok=True)
    if os.path.exists(path):
        with open(path, newline="", encoding="utf-8") as f:
            header = next(csv.reader(f), None)
        if header is not None and header != RUN_LOG_FIELDS:
            bak = path + ".bak"
            os.replace(path, bak)
            print(f"[run-log] schema changed; moved old log to {bak}")
    is_new = not os.path.exists(path)
    with open(path, "a", newline="", encoding="utf-8") as f:
        w = csv.DictWriter(f, fieldnames=RUN_LOG_FIELDS, extrasaction="ignore")
        if is_new:
            w.writeheader()
        w.writerow({k: record.get(k, "") for k in RUN_LOG_FIELDS})
    print(f"[run-log] appended 1 row to {path}")


# Mutable context for the failure logger. _run_main() fills this in as the run
# progresses (args first, then per-milestone phase updates, then per-step
# progress), so a crash ANYWHERE -- dataset typo, OOM at step 3, a guard's
# SystemExit -- still writes a meaningful run-log row: the CSV records failed
# experiments and why, not just the ones that finished. A run that completes
# (or is Ctrl-C'd through the normal path) sets ``logged`` and the failure
# logger stays silent. Note a hard process kill (segfault, OOM-killer, SLURM
# preemption) can't be caught -- those runs leave no row.
_FAIL_CTX = {"run_log": None, "record": {}, "phase": "startup", "logged": False}


def _log_failure(status, exc):
    """Append a run-log row for a run that died, plus the full traceback to a
    sidecar ``<run_log>.errors.log`` (tracebacks don't fit a CSV cell)."""
    if _FAIL_CTX["logged"] or not _FAIL_CTX["run_log"]:
        return
    _FAIL_CTX["logged"] = True
    import traceback
    err = f"{type(exc).__name__}: {exc}".strip()[:400]
    rec = dict(_FAIL_CTX["record"])
    rec.update(status=status, phase=_FAIL_CTX["phase"], error=err)
    try:
        append_run_log(_FAIL_CTX["run_log"], rec)
        elog = os.path.abspath(_FAIL_CTX["run_log"]) + ".errors.log"
        with open(elog, "a", encoding="utf-8") as f:
            f.write(f"\n===== {datetime.datetime.now().isoformat(timespec='seconds')}"
                    f" | phase: {_FAIL_CTX['phase']} | {err}\n")
            f.write(traceback.format_exc())
        print(f"[run-log] failure recorded (phase: {_FAIL_CTX['phase']}); "
              f"traceback appended to {elog}")
    except Exception as log_exc:  # never mask the original error with a log error
        print(f"[run-log] could not record failure: {log_exc}")


def checkpoint_dir(out, step):
    """Path of the retained per-step checkpoint under ``out``. Zero-padded so the
    lexicographic order matches the numeric order (handy for ``ls`` and for the
    prune-by-age logic below). Distinct from ``out`` itself (which --save-every /
    --save-best overwrite); these accumulate a history you can roll back to."""
    return os.path.join(out, f"checkpoint-{step:08d}")


def list_checkpoints(out):
    """Existing ``checkpoint-<step>`` dirs under ``out``, oldest-step first."""
    if not os.path.isdir(out):
        return []
    found = []
    for name in os.listdir(out):
        if name.startswith("checkpoint-") and os.path.isdir(os.path.join(out, name)):
            tail = name[len("checkpoint-"):]
            if tail.isdigit():
                found.append((int(tail), os.path.join(out, name)))
    return [p for _, p in sorted(found)]


def prune_checkpoints(out, keep):
    """Keep only the ``keep`` most-recent checkpoint dirs under ``out`` (delete the
    oldest). ``keep <= 0`` means keep everything. Adapters are small, but
    --train-embeddings/--train-head make a checkpoint large, so capping matters."""
    if keep is None or keep <= 0:
        return
    existing = list_checkpoints(out)
    for path in existing[:max(0, len(existing) - keep)]:
        shutil.rmtree(path, ignore_errors=True)
        print(f"  [checkpoint] pruned old {path}")


TRAINER_STATE_FILE = "trainer_state.pt"


def save_trainer_state(directory, *, step, opt, sched, best_val, best_val_step, ema,
                       offload_opt=None):
    """Persist resumable training state next to the adapter so --resume continues
    the optimizer + LR schedule instead of cold-restarting them (which would
    wrongly replay warmup/cosine from step 0). Small for LoRA (AdamW moments are a
    few MB at low rank). Written into every save target, so any checkpoint dir --
    the best at --out, a --save-every copy, or a --checkpoint-every history dir --
    is a complete resume point. ``offload_opt`` is the optional CPU-offload optimizer
    for the embed/head group (its state is large -- the embed/head Adam moments --
    but lives on CPU); stored under a separate key so a run without it still loads."""
    state = {
        "step": int(step),
        "optimizer": opt.state_dict(),
        "scheduler": sched.state_dict() if sched is not None else None,
        "best_val": best_val,
        "best_val_step": best_val_step,
        "ema": ema,
    }
    if offload_opt is not None:
        state["offload_optimizer"] = offload_opt.state_dict()
    torch.save(state, os.path.join(directory, TRAINER_STATE_FILE))


def load_trainer_state(directory):
    """Load the trainer-state dict written by ``save_trainer_state`` (to CPU; the
    caller moves optimizer tensors onto each param's device). Returns ``None`` when
    the dir has only adapter weights (e.g. a checkpoint from before this existed,
    or a foreign PEFT adapter) so resume falls back to weights-only."""
    path = os.path.join(directory, TRAINER_STATE_FILE)
    if not os.path.exists(path):
        return None
    return torch.load(path, map_location="cpu", weights_only=False)


def restore_optimizer_state(opt, opt_state):
    """Load an optimizer state_dict and move each state tensor onto its param's
    current device -- params can be split across GPUs under --parallel split, so a
    single map_location won't do. Matches saved state to params by order, so the
    param_groups must be built identically (same --r/--targets/--train-*)."""
    opt.load_state_dict(opt_state)
    for p, st in opt.state.items():
        for k, v in st.items():
            if isinstance(v, torch.Tensor):
                st[k] = v.to(p.device)


def turn_end_token(tokenizer):
    """End-of-assistant-turn marker for completion-only SFT, per chat format.

    The model must learn to emit a stop token after the response or generation
    never terminates. The right token is architecture-specific: the Llama-3
    family ends a turn with ``<|eot_id|>``; Mistral/Tekken and most others use
    their EOS (``</s>``). We pick ``<|eot_id|>`` only when it actually exists as
    a special token (preserving the proven Llama path), otherwise the tokenizer's
    EOS. Encoded with ``encode_special_tokens=True`` it maps to the single
    special id, matching the generator's stop condition.
    """
    if "<|eot_id|>" in tokenizer.extended_piece_to_id:
        return "<|eot_id|>"
    if tokenizer.eos_token:
        return tokenizer.eos_token
    return ""


def format_prompt_and_eot(model, tokenizer, prompt_format):
    """Return ``(build_prompt(user, system=None) -> str, eot_str)`` for the
    chosen chat format. ``system`` is optional and folded into the template's
    system turn when given (falsy/None omits it entirely -- identical output
    to before system support existed).

    - ``auto`` (default): the model's own template (``default_chat_prompt`` --
      Llama-3, Mistral ``[INST]``, mistral3 ``[SYSTEM_PROMPT]``/``[INST]``, etc.)
      and the architecture-correct turn-end token (:func:`turn_end_token`).
      Unchanged from prior behavior.
    - ``mistral``: the explicit Mistral V7+/V13 instruct format
      ``<s>[SYSTEM_PROMPT]{system}[/SYSTEM_PROMPT][INST]{user}[/INST]{response}</s>``
      (no spaces; ``[INST]``/``[/INST]``/``[SYSTEM_PROMPT]`` are control tokens;
      the system block is omitted when there's no system text). This is what
      ``auto`` already emits for the ``mistral3`` arch (Mistral Small/Medium 3.x,
      incl. Mistral-Medium-3.5-128B) -- the explicit option just doesn't depend
      on arch detection. EOS ends the turn.
    - ``metharme``: the Pygmalion/Metharme format
      ``<s><|system|>{system}<|user|>{user}<|model|>{response}</s>`` (the
      ``<|system|>`` block omitted when there's no system text). The
      ``<|system|>``/``<|user|>``/``<|model|>`` markers are plain text on a base
      model (not registered special tokens) -- the model learns them as a
      literal pattern, which is the standard way these tunes are trained. EOS
      ends the turn.
    - ``gemma4-nothink``: the Gemma4 turn format with the thought channel
      pre-closed empty (``<|turn>system\\n{system}<turn|>\\n<|turn>user\\n{user}
      <turn|>\\n<|turn>model\\n<|channel>thought\\n<channel|>{response}``, system
      turn omitted when there's no system text), so the model is trained to
      answer directly instead of emitting a reasoning span. Matches the
      ``"gemma4"`` case in ``examples/common.py`` / ``PromptFormat_gemma4`` in
      ``examples/chat_templates.py`` used for inference. ``<turn|>`` (a
      registered special token) ends the turn, not EOS.

    For ``mistral``/``metharme``/``gemma4-nothink`` a literal BOS is prepended so
    the sequence starts with one; the caller's BOS-normalization then collapses
    any duplicate the tokenizer auto-adds.
    """
    if prompt_format == "mistral":
        bos = tokenizer.bos_token or ""
        eos = tokenizer.eos_token or ""
        def build(user, system=None):
            sys_part = f"[SYSTEM_PROMPT]{system}[/SYSTEM_PROMPT]" if system else ""
            return f"{bos}{sys_part}[INST]{user}[/INST]"
        return build, eos
    if prompt_format == "metharme":
        bos = tokenizer.bos_token or ""
        eos = tokenizer.eos_token or ""
        def build(user, system=None):
            sys_part = f"<|system|>{system}" if system else ""
            return f"{bos}{sys_part}<|user|>{user}<|model|>"
        return build, eos
    if prompt_format == "gemma4-nothink":
        bos = tokenizer.bos_token or ""
        def build(user, system=None):
            sys_part = f"<|turn>system\n{system}<turn|>\n" if system else ""
            return (f"{bos}{sys_part}<|turn>user\n{user}<turn|>\n<|turn>model\n"
                     f"<|channel>thought\n<channel|>")
        return build, "<turn|>"
    if prompt_format == "auto":
        return ((lambda user, system=None: model.default_chat_prompt(user, system_prompt=system)),
                turn_end_token(tokenizer))
    raise ValueError(f"unknown prompt-format '{prompt_format}' "
                      f"(expected auto/mistral/metharme/gemma4-nothink)")


# Stage directions / inline actions, e.g. "[as CAMBIO]", "[TRINCULO grabs ...]",
# "*stares at the ceiling*". Style datasets built from play scripts carry these,
# and the model happily learns to emit them, producing disjoint non-answers.
_STAGE_DIR = re.compile(r"\[[^\]]*\]|\*[^*]*\*")
_WHITESPACE = re.compile(r"\s+")


def clean_style_text(s):
    """Strip stage directions and collapse runaway whitespace/newlines."""
    s = _STAGE_DIR.sub(" ", s)
    s = _WHITESPACE.sub(" ", s)
    return s.strip()


def extract_single_turn(messages):
    """Pull (system_text, user_text, assistant_text) from an OpenAI-style
    ``messages`` list.

    For single-turn rows (e.g. UnstableLlama/semancy: one user, one assistant,
    no system message) this is exact. We take the last user turn that precedes
    the first assistant turn as the prompt and that assistant turn as the
    target, so the completion-only mask still supervises only the answer. The
    first system message (if any) is returned separately so the caller can
    fold it into the chat template via ``build_prompt(user, system=...)``;
    rows with no system message get ``""`` and behave exactly as before.
    ``user_text``/``asst_text`` come back ``""`` if either turn is missing so
    the caller can skip the row.
    """
    sys_text, user_text, asst_text = "", "", ""
    for m in messages or []:
        role = (m.get("role") or "").lower()
        content = (m.get("content") or "").strip()
        if role == "system":
            if not sys_text:
                sys_text = content    # keep the first system turn only
        elif role == "user":
            user_text = content       # remember the most recent user turn
        elif role == "assistant":
            asst_text = content
            break                     # first assistant reply is the target
    return sys_text, user_text, asst_text


def build_optimizer(param_groups, lr, optim="adamw"):
    """Build the optimizer over the trainable param groups.

    ``adamw`` is torch's AdamW: ``m``/``v`` in fp32 = 8 bytes per trainable param.
    For a 262M-param r=64 adapter that is ~2.1 GB of optimizer state (split across
    devices under ``--parallel split``), allocated lazily on the first
    ``optimizer.step()`` -- which is why a run can pass step 0 / the first few
    steps and then OOM once the moments materialize.

    ``adamw8bit`` / ``paged_adamw8bit`` are bitsandbytes 8-bit AdamW: the moments
    are quantized to ~2 bytes/param (~4x less state, ~1.6 GB freed at r=64), with
    negligible quality cost (the QLoRA paper trains with paged 8-bit Adam). The
    ``paged_`` variant additionally offloads optimizer state to host memory on a
    spike, smoothing transient peaks. Both need ``bitsandbytes`` importable.
    """
    if optim == "adamw":
        return torch.optim.AdamW(param_groups, lr=lr)
    try:
        import bitsandbytes as bnb
    except Exception as e:
        raise SystemExit(
            f"--optim {optim} needs bitsandbytes, which is not importable "
            f"({e}). Install it in this venv (pip install bitsandbytes) or use "
            f"--optim adamw."
        )
    cls = bnb.optim.PagedAdamW8bit if optim == "paged_adamw8bit" else bnb.optim.AdamW8bit
    return cls(param_groups, lr=lr)


def build_cpu_offload_optimizer(params, lr):
    """A torchao ZeRO-Offload optimizer for the fully-trained embedding / LM head.

    Keeps the optimizer state (and the bf16 master weights) on CPU and runs the
    AdamW step there, so the ~12 bytes/param of fp32 Adam state for the (huge,
    untied ~0.8B-each) embed/head matrices never sits on the GPU -- only the bf16
    parameter and its transient grad do. The base optimizer is torchao's AdamW with
    ``bf16_stochastic_round=True`` (bound via ``partial`` so it applies regardless of
    whether CPUOffloadOptimizer forwards kwargs): bf16 master updates stay an
    unbiased estimate of fp32, so small embedding updates aren't rounded away. The
    embed/head params must already be bf16 (NativeLlamaQLoRA(modules_to_save_dtype=
    bfloat16)) for the rounding to apply.

    State-only offload (NOT offload_gradients) so gradient accumulation still works.
    CPUOffloadOptimizer is a wrapper, not a real optimizer: it has no LR-scheduler
    support and forbids gradient clipping on its params, so the caller mirrors the
    schedule's LR via set_offload_lr() each step and excludes these params from the
    clip. Single-process only (CUDA); not for the DDP arm.
    """
    try:
        import functools
        import torchao.optim as aoopt
        from torchao.optim import CPUOffloadOptimizer
    except Exception as e:
        raise SystemExit(
            f"--offload-embed-head-optim needs torchao, which is not importable "
            f"({e}). Install it in this venv (pip install torchao) or drop the flag "
            f"(the embed/head optimizer then stays on GPU; use --optim adamw8bit to "
            f"shrink it instead)."
        )
    # The fp32 AdamW clone that supports bf16 stochastic rounding is `_AdamW` in
    # current torchao (README: `_AdamW(..., bf16_stochastic_round=True)`); older/newer
    # layouts may call it `AdamW`. The 8-bit variants (AdamW8bit/4bit) use CUDA-only
    # quant kernels and can't run on the CPU-offloaded step, so they're not used here.
    AOAdamW = getattr(aoopt, "_AdamW", None) or getattr(aoopt, "AdamW", None)
    if AOAdamW is None:
        raise SystemExit(
            "torchao.optim exposes no _AdamW/AdamW for bf16 stochastic rounding; "
            "available: " + ", ".join(n for n in dir(aoopt) if "dam" in n.lower())
            + ". Tell me which to use.")
    base = functools.partial(AOAdamW, bf16_stochastic_round=True)
    opt = CPUOffloadOptimizer(params, base, lr=lr)
    set_offload_lr(opt, lr)   # don't rely on lr= forwarding to the base optimizer
    return opt


def set_offload_lr(opt, lr):
    """Set the LR on every param group of a CPUOffloadOptimizer (which is not
    compatible with torch's LR schedulers). Handles the tensor-LR case torchao uses
    for its fused/compiled path."""
    for g in opt.param_groups:
        cur = g.get("lr")
        if isinstance(cur, torch.Tensor):
            cur.fill_(lr)
        else:
            g["lr"] = lr


def make_lr_scheduler(optimizer, name, total_steps, warmup_steps):
    """A transformers-free LR scheduler (none/linear/cosine) with linear warmup.

    Matches HuggingFace's ``get_{linear,cosine}_schedule_with_warmup`` exactly so
    behavior is well understood: LR ramps 0->1 over ``warmup_steps``, then decays
    to 0 (linear) or follows a half-cosine to 0 (cosine) over the remaining
    ``total_steps - warmup_steps``. ``none``/``constant`` holds the base LR after
    warmup. Driven by one ``scheduler.step()`` per optimizer step.
    """
    name = (name or "none").lower()
    warmup_steps = max(0, int(warmup_steps))
    total_steps = max(1, int(total_steps))

    def lr_lambda(step):
        if step < warmup_steps:
            return float(step) / float(max(1, warmup_steps))
        if name in ("none", "constant"):
            return 1.0
        progress = float(step - warmup_steps) / float(max(1, total_steps - warmup_steps))
        progress = min(1.0, max(0.0, progress))
        if name == "linear":
            return 1.0 - progress
        if name == "cosine":
            return 0.5 * (1.0 + math.cos(math.pi * progress))
        raise ValueError(f"unknown scheduler '{name}' (expected none/linear/cosine)")

    return torch.optim.lr_scheduler.LambdaLR(optimizer, lr_lambda)


def resolve_steps_and_warmup(args, num_train_examples, effective_batch):
    """Finalize args.steps (from --epochs if given) and compute warmup steps.

    ``--epochs`` (when > 0) overrides ``--steps`` so the schedule length matches
    the requested number of passes over the data: one optimizer step consumes
    ``effective_batch`` examples, so an epoch is ``ceil(N / effective_batch)``
    steps. ``--warmup-steps`` (when > 0) wins over ``--warmup-ratio``.
    """
    if getattr(args, "epochs", 0) and args.epochs > 0:
        eff = max(1, int(effective_batch))
        steps_per_epoch = max(1, math.ceil(num_train_examples / eff))
        args.steps = max(1, math.ceil(args.epochs * steps_per_epoch))
    warmup = (args.warmup_steps if getattr(args, "warmup_steps", 0) and args.warmup_steps > 0
              else int(round(getattr(args, "warmup_ratio", 0.0) * args.steps)))
    return args.steps, max(0, warmup)


def build_sft_examples(model, tokenizer, dataset_name, max_samples, seq_len,
                       instruction_key="instruction", context_key="context",
                       response_key="response", split="train",
                       clean_text=True, min_response_words=3,
                       uppercase_response=False, messages_key=None,
                       prompt_format="auto", shuffle=False, shuffle_seed=0,
                       config_name=None):
    """
    Load an instruction dataset and tokenize for completion-only SFT using the
    model's native chat template (Llama-3, Mistral, etc. -- whatever
    ``model.default_chat_prompt`` emits for this architecture). Prompt tokens are
    masked with -100 so loss is computed only over the (styled) response, which
    is terminated with the architecture-correct turn-end token (see
    :func:`turn_end_token`) so the model learns to stop.

    Two input layouts are supported:
      * flat columns -- instruction_key / context_key / response_key (Alpaca,
        Dolly, ...); context_key may be absent in the dataset (treated as empty).
      * OpenAI ``messages`` -- pass ``messages_key`` (e.g. "messages") for
        single-turn user/assistant rows (UnstableLlama/semancy); the user turn
        becomes the prompt and the assistant turn the supervised response. When
        set it takes precedence over the flat-column keys. A leading ``system``
        message, if present, is folded into the chat template's system turn
        (see :func:`extract_single_turn`); rows without one are unaffected.

    clean_text strips stage directions / inline actions and normalizes
    whitespace (helps play-script style sets like the Shakespeare default, whose
    raw rows otherwise teach the model to emit "[stage directions]"). Rows whose
    cleaned response has fewer than min_response_words tokens are dropped.

    shuffle (with shuffle_seed) permutes the rows once after loading, BEFORE any
    --val-frac carve and before training, so the held-out split is a random
    sample rather than the first N rows and training order is randomized. It is
    deterministic given the seed, so the EXL3 and BNB arms (which call the same
    HF datasets shuffle) stay matched. Default off preserves the original order;
    the existing shuffle-on-cap (random subset when capping) is unchanged.

    Returns a list of dicts with python int lists: input_ids / labels.
    """
    import os
    from datasets import load_dataset

    # Accept either a Hub dataset id or a local file (e.g. a styled set produced
    # by examples/make_style_dataset.py). load_dataset() can't sniff a bare local
    # path, so pick the builder from the extension when the path exists.
    if os.path.exists(dataset_name):
        ext = os.path.splitext(dataset_name)[1].lower()
        builder = {".json": "json", ".jsonl": "json",
                   ".parquet": "parquet", ".csv": "csv"}.get(ext, "json")
        ds = load_dataset(builder, data_files=dataset_name, split=split)
    elif config_name:
        ds = load_dataset(dataset_name, config_name, split=split)
    else:
        ds = load_dataset(dataset_name, split=split)
    # Shuffle the full set when asked, or (as before) when capping rows so the
    # subset is random rather than the first max_samples. shuffle_seed defaults to
    # 0, matching the prior cap behavior exactly when --shuffle is off.
    if shuffle or (max_samples and max_samples < len(ds)):
        ds = ds.shuffle(seed=shuffle_seed)
    if max_samples and max_samples < len(ds):
        ds = ds.select(range(max_samples))

    build_prompt, eot = format_prompt_and_eot(model, tokenizer, prompt_format)

    examples = []
    for ex in ds:
        if messages_key:
            sys_text, instr, resp = extract_single_turn(ex.get(messages_key))
            ctx = ""
        else:
            sys_text = ""
            instr = (ex.get(instruction_key) or "").strip()
            ctx = (ex.get(context_key) or "").strip()
            resp = (ex.get(response_key) or "").strip()
        if clean_text:
            instr, ctx, resp = (clean_style_text(instr), clean_style_text(ctx),
                                clean_style_text(resp))
        if not resp or len(resp.split()) < min_response_words:
            continue
        if messages_key and not instr:
            continue  # malformed messages row: no user turn to prompt with
        # Smoke test: a maximally dense+consistent transform (every token of every
        # response changes), so there's no low-loss path that ISN'T uppercased and
        # it must surface in generation. Only the response is transformed, so it
        # proves a learned *behavior*, not input echoing.
        if uppercase_response:
            resp = resp.upper()
        user = instr if not ctx else f"{instr}\n\n{ctx}"

        # default_chat_prompt() already includes <|begin_of_text|> and ends with
        # the assistant header, so encode specials and don't add another BOS.
        # Tokenize the prompt and the response SEPARATELY and concatenate, so the
        # prompt/response boundary is exact -- masking by the prompt-string length
        # is vulnerable to tokenizer boundary merges that mis-align the mask.
        prompt_text = build_prompt(user, system=sys_text or None)
        prompt_ids = tokenizer.encode(
            prompt_text, add_bos=False, encode_special_tokens=True
        )[0].tolist()
        resp_ids = tokenizer.encode(
            resp + eot, add_bos=False, encode_special_tokens=True
        )[0].tolist()

        # Normalize BOS. With encode_special_tokens=True the underlying HF
        # tokenizer adds <|begin_of_text|> itself (Llama-3 has add_bos_token=true),
        # *in addition to* the literal one default_chat_prompt() embeds and *again*
        # on the separately-encoded response -- so the prompt would start with two
        # BOS and the response with a spurious one. Standard Llama-3 (and the BNB
        # arm, which uses add_special_tokens=False) is exactly one BOS at the very
        # start and none mid-sequence. Drop the duplicates; no-op for tokenizers
        # that don't auto-prepend BOS.
        bos = tokenizer.bos_token_id
        if bos is not None:
            while len(prompt_ids) >= 2 and prompt_ids[0] == bos and prompt_ids[1] == bos:
                prompt_ids = prompt_ids[1:]
            if resp_ids and resp_ids[0] == bos:
                resp_ids = resp_ids[1:]

        input_ids = (prompt_ids + resp_ids)[:seq_len]
        labels = [-100] * len(prompt_ids) + list(resp_ids)
        labels = labels[:seq_len]
        if all(l == -100 for l in labels):
            continue  # response got truncated away; skip
        examples.append({"input_ids": input_ids, "labels": labels})

    return examples


def build_lm_examples(tokenizer, dataset_name, split, seq_len,
                      text_key="text", max_samples=0, config_name=None,
                      max_blocks=0):
    """Plain-text language-modeling eval set (e.g. wikitext) for a second,
    task-independent held-out loss.

    Concatenates the dataset's text column and packs it into non-overlapping
    ``seq_len`` blocks with every token supervised (no completion mask), so the
    resulting loss is a straight nats/token cross-entropy -- on the same scale as
    the SFT eval loss, which lets you watch the two move together (does the task
    fit track or diverge from general LM ability?). Tokenization matches the SFT
    path's underlying tokenizer, so the EXL3 and BNB arms produce identical
    blocks and hence a comparable number.

    Returns a list of dicts (input_ids / labels), same shape as
    :func:`build_sft_examples`, so the same eval loop consumes it.
    """
    import os
    from datasets import load_dataset

    if os.path.exists(dataset_name):
        ext = os.path.splitext(dataset_name)[1].lower()
        builder = {".json": "json", ".jsonl": "json",
                   ".parquet": "parquet", ".csv": "csv"}.get(ext, "json")
        ds = load_dataset(builder, data_files=dataset_name, split=split)
    elif config_name:
        # Many text corpora need a config (e.g. wikitext -> "wikitext-2-raw-v1").
        ds = load_dataset(dataset_name, config_name, split=split)
    else:
        ds = load_dataset(dataset_name, split=split)
    if max_samples and max_samples < len(ds):
        ds = ds.select(range(max_samples))

    bos = tokenizer.bos_token_id
    # Each packed block is scored as an independent sequence (batch-1, no KV
    # carryover), so it should begin like a real sequence does. Match how the SFT
    # path / the model expects input: exactly one leading BOS -- but only for
    # models that actually use one (bos_token_id is None, e.g. Qwen -> none). The
    # block stays seq_len long: one BOS + (seq_len-1) content tokens.
    add_block_bos = bos is not None
    content_len = seq_len - 1 if add_block_bos else seq_len
    buf, examples = [], []
    for row in ds:
        text = row.get(text_key) or ""
        if not text.strip():
            continue
        ids = tokenizer.encode(text, add_bos=False,
                               encode_special_tokens=False)[0].tolist()
        # Drop any BOS the tokenizer auto-prepended; we re-add exactly one per
        # block below, never mid-stream.
        if bos is not None and ids and ids[0] == bos:
            ids = ids[1:]
        buf.extend(ids)
        while len(buf) >= content_len:
            block = buf[:content_len]
            buf = buf[content_len:]
            if add_block_bos:
                block = [bos] + block
            examples.append({"input_ids": block, "labels": list(block)})
            # Cap the number of packed blocks directly (independent of seq_len),
            # so eval2 can be sized to roughly match the primary eval set rather
            # than ballooning -- max_samples only caps source rows, which is
            # unpredictable after packing.
            if max_blocks and len(examples) >= max_blocks:
                return examples
    return examples


def pack_examples(examples, seq_len, pad_id, algo="bfd"):
    """Pack tokenized SFT examples into ``seq_len`` blocks (sample packing).

    Each input example (from :func:`build_sft_examples`) is one *document*;
    documents are concatenated into blocks of at most ``seq_len`` tokens, so a
    short-answer dataset stops wasting most of every forward on pad tokens -- the
    same real tokens are processed in far fewer, fuller sequences.

    ``algo`` picks the bin-packing strategy:
      * ``"bfd"`` (default) -- best-fit decreasing: documents sorted longest-first,
        each placed into the block with the least remaining room that still fits
        (found by bisect over remaining capacities, so it's O(n log n)-ish and
        deterministic). This is the multipack approach of Axolotl (FFD) /
        Chronicals (BFD) and lifts fill from ~80-85% (next-fit) to typically 97%+
        -- directly ~1.15-1.2x more real tokens per step. Reordering documents
        across blocks is harmless: attention is document-isolated, positions
        reset per document, and the training loop shuffles blocks anyway.
      * ``"nextfit"`` -- the pre-Session-11 behavior (arrival order, seal a block
        when the next document doesn't fit), kept for A/B comparison.

    Correctness is preserved by the native forward, NOT here: each block carries
      * ``seg_ids``      -- per-token document index, so attention is restricted to
                            the same document (block-diagonal / flash-varlen). Pad
                            positions inherit the LAST document's seg id, so a pad
                            query still attends back into a real doc and is never
                            fully masked (no softmax NaN); pads are still blocked as
                            keys by the attention mask.
      * ``position_ids`` -- reset to 0..len-1 PER document, so RoPE sees each
                            document at its true positions, not its block offset.
    The completion-only ``-100`` prompt masks are already in each document's
    labels; at a document join the shifted CE predicts the next document's first
    (masked) prompt token, so boundaries contribute no loss and need no fixup.

    Every block is padded to ``seq_len`` so blocks are uniform. Deterministic for
    a given input order (BFD ties keep dataset order), so DDP ranks packing the
    same list get identical blocks. Returns a list of dicts (input_ids / labels /
    seg_ids / position_ids), consumed by :func:`collate`.
    """
    docs = []
    for ex in examples:
        ids, labs = ex["input_ids"], ex["labels"]
        if len(ids) > seq_len:                         # shouldn't happen (build_sft
            ids, labs = ids[:seq_len], labs[:seq_len]  # truncates), but guard
        docs.append((ids, labs))

    # Phase 1: assign document indices to blocks.
    if algo == "nextfit":
        assignments, cur, cur_len = [], [], 0
        for i, (ids, _) in enumerate(docs):
            if cur and cur_len + len(ids) > seq_len:
                assignments.append(cur)
                cur, cur_len = [], 0
            cur.append(i)
            cur_len += len(ids)
        if cur:
            assignments.append(cur)
    elif algo == "bfd":
        import bisect
        order = sorted(range(len(docs)), key=lambda i: (-len(docs[i][0]), i))
        assignments = []
        rems, block_by_rem = [], []       # remaining capacity (sorted) -> block idx
        for i in order:
            n = len(docs[i][0])
            j = bisect.bisect_left(rems, n)   # smallest remaining that fits (best fit)
            if j == len(rems):
                assignments.append([i])
                b, rem = len(assignments) - 1, seq_len - n
            else:
                rem = rems.pop(j) - n
                b = block_by_rem.pop(j)
                assignments[b].append(i)
            k = bisect.bisect_left(rems, rem)
            rems.insert(k, rem)
            block_by_rem.insert(k, b)
        for a in assignments:
            a.sort()                      # within-block docs in dataset order
    else:
        raise ValueError(f"unknown packing algo '{algo}' (expected bfd/nextfit)")

    # Phase 2: materialize blocks (identical layout for both algorithms).
    blocks = []
    for doc_idxs in assignments:
        cur_ids, cur_labels, cur_seg, cur_pos = [], [], [], []
        for seg, i in enumerate(doc_idxs):
            ids, labs = docs[i]
            cur_ids += ids
            cur_labels += labs
            cur_seg += [seg] * len(ids)
            cur_pos += list(range(len(ids)))
        pad = seq_len - len(cur_ids)
        last_seg = cur_seg[-1] if cur_seg else 0
        blocks.append({
            "input_ids": cur_ids + [pad_id] * pad,
            "labels": cur_labels + [-100] * pad,
            "seg_ids": cur_seg + [last_seg] * pad,
            "position_ids": cur_pos + [0] * pad,
        })
    return blocks


def collate(batch, pad_id):
    """Right-pad a batch; pad input_ids with pad_id, labels with -100.

    Returns ``(input_ids, labels, attention_mask, position_ids, seg_ids)``. For
    plain (unpacked) examples ``position_ids`` and ``seg_ids`` are ``None`` (the
    forward derives positions from the mask, with no block-diagonal constraint).
    For packed blocks (carrying ``seg_ids`` from :func:`pack_examples`) they are
    returned so the forward resets RoPE per document and isolates documents.
    """
    maxlen = max(len(b["input_ids"]) for b in batch)
    packed = "seg_ids" in batch[0]
    input_ids, labels, attn = [], [], []
    seg_ids = [] if packed else None
    pos_ids = [] if packed else None
    for b in batch:
        n = len(b["input_ids"])
        pad = maxlen - n
        input_ids.append(b["input_ids"] + [pad_id] * pad)
        labels.append(b["labels"] + [-100] * pad)
        attn.append([1] * n + [0] * pad)
        if packed:
            last_seg = b["seg_ids"][-1] if b["seg_ids"] else 0
            seg_ids.append(b["seg_ids"] + [last_seg] * pad)
            pos_ids.append(b["position_ids"] + [0] * pad)
    return (
        torch.tensor(input_ids, dtype=torch.long),
        torch.tensor(labels, dtype=torch.long),
        torch.tensor(attn, dtype=torch.long),
        torch.tensor(pos_ids, dtype=torch.long) if packed else None,
        torch.tensor(seg_ids, dtype=torch.long) if packed else None,
    )


def sample(model, cache, tokenizer, generator, build_prompt, prompt, max_new_tokens=48):
    """Quick native generation for live progress feedback (uses the same chat
    format as training, so a metharme-trained adapter previews meaningfully)."""
    text = build_prompt(prompt)
    resp = generator.generate(
        prompt=text, max_new_tokens=max_new_tokens,
        add_bos=False, completion_only=True,
    )
    return resp.strip().replace("\n", " ")


def main():
    """Run the trainer with failure capture: any exception or non-zero
    SystemExit appends a ``status=failed`` row (with phase + error summary) to
    the run-log CSV and the full traceback to ``<run_log>.errors.log`` before
    re-raising, so failed experiments are documented automatically. Ctrl-C
    outside the training loop's own handler is recorded as ``interrupted``."""
    try:
        _run_main()
    except KeyboardInterrupt as e:
        _log_failure("interrupted", e)
        raise SystemExit(130)
    except SystemExit as e:
        # SystemExit(0) is the normal Ctrl-C exit path (already logged);
        # a message/non-zero code is a guard-rail abort worth recording.
        if e.code not in (0, None):
            _log_failure("failed", e)
        raise
    except BaseException as e:
        _log_failure("failed", e)
        raise


def _run_main():
    # Line-buffer stdout/stderr so the per-step progress lines (and interleaved
    # eval/sample/checkpoint lines) flush on each newline. Python block-buffers
    # stdout when it isn't a TTY -- i.e. exactly when the run is redirected to a
    # file or piped through tee -- which otherwise holds every step line in an
    # ~8KB buffer and dumps them all at once when the process exits.
    for stream in (sys.stdout, sys.stderr):
        try:
            stream.reconfigure(line_buffering=True)
        except (AttributeError, ValueError):
            pass  # not a TextIOWrapper (already line-buffered, or wrapped)

    # This is the single-process trainer (--parallel single|split). Launched under
    # torchrun (RANK/WORLD_SIZE in env) it would silently run N independent copies,
    # so redirect to the DDP entry point with a clear one-liner instead of the
    # confusing argparse error you'd get from a stray --parallel ddp.
    if os.environ.get("RANK") is not None or os.environ.get("WORLD_SIZE") is not None:
        raise SystemExit(
            "qlora_train_native.py is single-process (--parallel single|split). "
            "For multi-GPU DDP under torchrun use examples/qlora_train_native_ddp.py "
            "(note: --lora-r not --r; no --parallel / --sample-every)."
        )
    ap = argparse.ArgumentParser()
    ap.add_argument("--model", required=True, help="Path to a local EXL3 model dir")
    ap.add_argument("--out", default="out/exl3_qlora_adapter")
    ap.add_argument("--device", default="cuda:0",
                    help="single-device load target (ignored when --parallel split)")
    ap.add_argument("--parallel", choices=["single", "split"], default="single",
                    help="single: one GPU; split: layer-autosplit the frozen base "
                         "across visible GPUs (memory, for models too big for one card)")
    ap.add_argument("--reserve-per-device", nargs="*", type=float, default=None, metavar="GB",
                    help="(split) GB to reserve per device; negative excludes a device")
    ap.add_argument("--use-per-device", nargs="*", type=float, default=None, metavar="GB",
                    help="(split) GB budget per device; caps a card to force/tune the split")
    ap.add_argument("--r", type=int, default=32)
    ap.add_argument("--alpha", type=float, default=64.0)
    ap.add_argument("--use-rslora", action="store_true",
                    help="Rank-stabilized LoRA scaling: scale = alpha/sqrt(r) "
                         "instead of alpha/r. At a FIXED rank this is just an "
                         "alpha rescale (r=64: alpha/8 -> same scale), but it "
                         "keeps the effective scale stable across rank sweeps.")
    ap.add_argument("--init-lora", choices=["default", "pissa", "qerr", "eva"],
                    default="default",
                    help="Adapter initialization. default: kaiming A / zero B. "
                         "pissa: top-r principal components of the frozen base "
                         "(trained against a frozen-offset residual; adapter "
                         "exports as a converted rank-2r standard LoRA). "
                         "qerr: top-r SVD of the quantization error vs the "
                         "ORIGINAL model (needs --init-ref-model); training "
                         "starts from the closest rank-r repair of the bf16 "
                         "model. eva: A = top-r right-singular vectors of each "
                         "target's input activations, streamed from a short "
                         "pre-pass of the training data through the quantized "
                         "forward (B stays 0, so step 0 is exactly the base). "
                         "All need a validated step-0 gate: run "
                         "qlora_validate_native.py --init-lora first.")
    ap.add_argument("--init-svd-niter", type=int, default=16,
                    help="Randomized-SVD subspace iterations for --init-lora "
                         "(PiSSA's fast-SVD recipe; 0 = exact full SVD, much "
                         "slower). eva caps this at 8 for its incremental "
                         "sketch updates. Default 16.")
    ap.add_argument("--init-ref-model", default=None,
                    help="Path to the ORIGINAL (unquantized) HF model dir; "
                         "required by --init-lora qerr to form the "
                         "quantization error.")
    ap.add_argument("--init-eva-tokens", type=int, default=65536,
                    help="Token budget for the --init-lora eva activation "
                         "pre-pass (drawn in order from the training set; "
                         "no gradients). Default 65536.")
    ap.add_argument("--lr", type=float, default=2e-4)
    ap.add_argument("--weight-decay", type=float, default=0.01,
                    help="AdamW weight decay on the LoRA params (default 0.01).")
    ap.add_argument("--optim", choices=["adamw", "adamw8bit", "paged_adamw8bit"],
                    default="adamw",
                    help="Optimizer. 'adamw' = torch AdamW (fp32 moments, 8 "
                         "bytes/param). 'adamw8bit' / 'paged_adamw8bit' = "
                         "bitsandbytes 8-bit AdamW (~2 bytes/param) -- cuts "
                         "optimizer state ~4x, the lever for fitting bigger r / "
                         "longer context on tight VRAM. 'paged_' offloads optimizer "
                         "state to host on spikes (needs bitsandbytes installed).")
    ap.add_argument("--scheduler", choices=["none", "linear", "cosine"],
                    default="none",
                    help="LR schedule after warmup: none (constant), linear "
                         "decay to 0, or cosine decay to 0.")
    ap.add_argument("--warmup-ratio", type=float, default=0.0,
                    help="Fraction of total steps spent linearly warming up the "
                         "LR from 0 (e.g. 0.05-0.1). Ignored if --warmup-steps>0.")
    ap.add_argument("--warmup-steps", type=int, default=0,
                    help="Absolute warmup steps; overrides --warmup-ratio when >0.")
    ap.add_argument("--epochs", type=float, default=0.0,
                    help="If >0, set --steps to cover this many passes over the "
                         "training data (one step = batch*grad-accum examples), "
                         "so the schedule length matches the epoch count.")
    ap.add_argument("--steps", type=int, default=1000,
                    help="Training steps (ignored when --epochs>0). ~steps*batch "
                         "examples seen; aim for >=1 epoch to pick up a style.")
    ap.add_argument("--batch", type=int, default=4)
    ap.add_argument("--grad-accum", type=int, default=1)
    ap.add_argument(
        "--dataset",
        default="superdrew100/UwU_Alpaca_data",
        help="HF dataset id. Default is the UwU-furry Alpaca style set.",
    )
    ap.add_argument("--dataset-split", default="train")
    ap.add_argument("--instruction-key", default="instruction",
                    help="Column holding the prompt/instruction")
    ap.add_argument("--context-key", default="input",
                    help="Optional extra-context column; absent columns are ignored "
                         "(Alpaca uses 'input', Dolly uses 'context')")
    ap.add_argument("--response-key", default="output",
                    help="Column holding the target response (Alpaca: 'output', "
                         "Dolly: 'response')")
    ap.add_argument("--messages-key", default=None,
                    help="Column holding OpenAI-style single-turn messages (e.g. "
                         "'messages' for UnstableLlama/semancy). When set, the "
                         "user turn is the prompt and the assistant turn the "
                         "supervised response; --instruction/context/response-key "
                         "are ignored.")
    ap.add_argument("--prompt-format",
                    choices=["auto", "mistral", "metharme", "gemma4-nothink"],
                    default="auto",
                    help="Chat format. auto: the model's native template "
                         "(Llama-3, Mistral [INST], mistral3 [SYSTEM_PROMPT]/[INST]). "
                         "mistral: explicit <s>[INST]{q}[/INST]{a}</s> (= auto for "
                         "the mistral3 arch, e.g. Mistral-Medium-3.5). metharme: "
                         "Pygmalion <|user|>{q}<|model|>{a}</s>. gemma4-nothink: "
                         "<|turn>user\\n{q}<turn|>\\n<|turn>model\\n<|channel>thought\\n"
                         "<channel|>{a} with the thought span pre-closed empty (no "
                         "reasoning trained). EOS ends the turn for mistral/metharme; "
                         "<turn|> ends the turn for gemma4-nothink.")
    ap.add_argument("--clean-text", action="store_true",
                    help="Strip [stage directions]/*actions* and normalize "
                         "whitespace before training (OFF by default). Helps "
                         "play-script style sets; leave off for reasoning / code / "
                         "markdown data, where brackets and structure are content.")
    ap.add_argument("--no-clean-text", action="store_true",
                    help=argparse.SUPPRESS)  # deprecated: cleaning is now opt-in
    ap.add_argument("--min-response-words", type=int, default=3,
                    help="Drop rows whose cleaned response is shorter than this")
    ap.add_argument("--uppercase-response", action="store_true",
                    help="Smoke test: train the model to RESPOND IN ALL CAPS. A "
                         "maximally dense/consistent transform that must show in "
                         "generation if the training path works at all.")
    ap.add_argument("--max-samples", type=int, default=4000)
    ap.add_argument("--shuffle", action="store_true",
                    help="Shuffle the training rows once (deterministically) "
                         "before the --val-frac carve and before training, so the "
                         "held-out split is a random sample and training order is "
                         "randomized. Matched across arms given the same seed.")
    ap.add_argument("--shuffle-seed", type=int, default=0,
                    help="Seed for --shuffle (also the random-subset seed when "
                         "--max-samples caps the rows). Default 0.")
    ap.add_argument("--seq-len", type=int, default=512)
    ap.add_argument("--pack", action="store_true",
                    help="Sample packing: concatenate multiple training documents "
                         "into each --seq-len sequence instead of padding each to "
                         "--seq-len, so short-answer data stops wasting most of the "
                         "forward on pad tokens. Documents stay isolated (per-doc "
                         "RoPE reset + block-diagonal attention; flash-varlen on "
                         "CUDA fp16/bf16). Only the training set is packed; the "
                         "held-out eval stays per-example for comparable losses.")
    ap.add_argument("--pack-algo", choices=["bfd", "nextfit"], default="bfd",
                    help="Bin-packing strategy for --pack. bfd (default): best-fit "
                         "decreasing -- typically 97%%+ fill vs ~80-85%% for the old "
                         "next-fit, i.e. ~1.15-1.2x more real tokens per step. "
                         "nextfit: the pre-Session-11 arrival-order behavior, kept "
                         "for A/B comparison.")
    ap.add_argument("--inspect", type=int, default=0, metavar="N",
                    help="Tokenization check: decode the first N built examples "
                         "(prompt span vs supervised response span + whether the "
                         "response was truncated by --seq-len), then exit without "
                         "training. Run this once to verify a new dataset/schema.")
    ap.add_argument("--targets", nargs="*", default=None,
                    help="Target module leaf names (default: attn+mlp projections)")
    ap.add_argument("--train-embeddings", action="store_true",
                    help="Also FULLY train the input embeddings (modules_to_save), "
                         "not just LoRA. Saved to modules_to_save.safetensors. Big "
                         "(vocab x hidden) -- raises VRAM and, under DDP, the "
                         "per-step grad all-reduce. On a tied model this also "
                         "trains the head (shared weight).")
    ap.add_argument("--train-head", action="store_true",
                    help="Also FULLY train the LM head (modules_to_save). Switches "
                         "the loss off the fused frozen-head path to a supervised-"
                         "position cross-entropy so the head gets a gradient. On a "
                         "tied model this is equivalent to --train-embeddings.")
    ap.add_argument("--lora-embed", action="store_true",
                    help="Train a rank-r LoRA on the input embedding instead of "
                         "fully (mutually exclusive with --train-embeddings). Far "
                         "cheaper: r*(vocab+hidden) params, GPU-resident, no offload "
                         "needed. A low-rank shift of the whole embedding (use "
                         "PEFT-style trainable-tokens instead if you only added new "
                         "tokens). Saved to lora_modules.safetensors (merge-path).")
    ap.add_argument("--lora-head", action="store_true",
                    help="Train a rank-r LoRA on the LM head instead of fully "
                         "(mutually exclusive with --train-head). Adds a low-rank "
                         "delta to the head logits at the supervised positions; "
                         "memory scales with supervised tokens, params are tiny. "
                         "Saved to lora_modules.safetensors (merge-path).")
    ap.add_argument("--offload-embed-head-optim", action="store_true",
                    help="Put the fully-trained embedding/LM-head optimizer on CPU "
                         "(torchao CPUOffloadOptimizer) with bf16 stochastic-rounding "
                         "master weights, so the embed/head Adam state never sits on "
                         "the GPU -- frees ~12 bytes/param of the (huge, untied) "
                         "embed/head matrices. Requires torchao and "
                         "--train-embeddings/--train-head. Single-process only (not "
                         "the DDP arm); these params are excluded from grad clipping "
                         "and follow the same LR schedule as the LoRA group.")
    ap.add_argument("--offload-activations", action="store_true",
                    help="Offload the grad-checkpointed block activations to CPU RAM "
                         "(torch save_on_cpu, pinned) to free GPU memory for longer "
                         "context / bigger batch. Needs gradient checkpointing (on by "
                         "default) + CUDA. Synchronous copies, so a modest wall-clock "
                         "cost; wraps only the decoder block loop.")
    ap.add_argument("--use-liger", action="store_true",
                    help="Route RMSNorm (2D/3D norms) and SwiGLU (silu only) through "
                         "Liger Triton kernels for lower activation memory + speed. "
                         "Needs liger-kernel + CUDA fp16/bf16; eager/fp32/CPU paths "
                         "are unchanged. Changes numerics slightly -- run "
                         "qlora_validate_native.py --use-liger to confirm parity first.")
    ap.add_argument("--compute-dtype", default="bfloat16",
                    choices=["float32", "float16", "bfloat16"])
    ap.add_argument("--no-grad-ckpt", action="store_true")
    ap.add_argument("--attn-impl", choices=["auto", "eager", "flash"], default="auto",
                    help="Attention kernel: auto (FlashAttention-2 when the "
                         "flash_attn package is importable and the run is CUDA "
                         "fp16/bf16, else eager), flash (require it), or eager "
                         "(the reference; O(t^2) memory). Flash is O(t) memory -- "
                         "the lever for long-context training.")
    ap.add_argument("--ce-chunk", type=int, default=1024)
    ap.add_argument("--head-vocab-chunk", type=int, default=0,
                    help="Reconstruct + matmul the frozen LM head in vocab-column "
                         "chunks of this many columns (0 = off, single-shot). Bounds "
                         "the head's peak memory on the OUTPUT device -- the full "
                         "[hidden, vocab] reconstruction + fp32 upcast is the spike "
                         "for big-vocab models (e.g. Gemma 262k). Try 32768. Same "
                         "loss/grad as off; no extra dequant cost (vocab-outer loop).")
    ap.add_argument("--max-grad-norm", type=float, default=1.0)
    ap.add_argument("--sample-every", type=int, default=25,
                    help="Generate a sample completion every N steps (0 to disable)")
    ap.add_argument("--sample-prompt", default="Tell me about your day.")
    ap.add_argument("--save-every", type=int, default=0,
                    help="Overwrite the adapter at --out every N steps (0 = only "
                         "at the end). The adapter is also saved on Ctrl-C. This "
                         "keeps a single latest copy; use --checkpoint-every for a "
                         "retained history.")
    ap.add_argument("--checkpoint-every", type=int, default=0,
                    help="Every N steps, save a RETAINED checkpoint to "
                         "--out/checkpoint-<step> (kept; not overwritten), so you "
                         "build a history to roll back to or pick from. Independent "
                         "of --save-every (latest at --out) and --save-best (best at "
                         "--out). 0 disables.")
    ap.add_argument("--keep-checkpoints", type=int, default=0,
                    help="Cap the number of --checkpoint-every dirs to keep, "
                         "deleting the oldest (0 = keep all). Useful with "
                         "--train-embeddings/--train-head, where each checkpoint is "
                         "large.")
    ap.add_argument("--resume", default=None,
                    help="Adapter dir to resume from (continues those weights). If "
                         "the dir holds a trainer_state.pt (any --checkpoint-every / "
                         "--save-* dir from this trainer), the optimizer, LR "
                         "schedule and step counter are ALSO restored so the run "
                         "continues seamlessly; pass --reset-optimizer to skip that "
                         "(cold AdamW, schedule from step 0). --r/--targets must "
                         "match the checkpoint.")
    ap.add_argument("--reset-optimizer", action="store_true",
                    help="With --resume, load only the weights and start the "
                         "optimizer/LR-schedule/step fresh (the old resume "
                         "behavior). Use when changing LR/schedule or resuming "
                         "across a different device topology.")
    ap.add_argument("--eval-split", default=None,
                    help="Use this split of the dataset (e.g. 'test') as the "
                         "held-out eval set, instead of carving --val-frac off "
                         "train. Real held-out data; takes precedence over "
                         "--val-frac.")
    ap.add_argument("--eval-dataset", default=None,
                    help="Dataset id/path for --eval-split (defaults to --dataset).")
    ap.add_argument("--eval2-dataset", default=None,
                    help="A SECOND held-out eval set, reported alongside the "
                         "primary one each --eval-every and at the end, so you can "
                         "watch them move together (e.g. your test set vs "
                         "wikitext). --save-best stays keyed on the PRIMARY eval.")
    ap.add_argument("--eval2-split", default="test",
                    help="Split for --eval2-dataset (default 'test').")
    ap.add_argument("--eval2-config", default=None,
                    help="HF dataset config for --eval2-dataset (e.g. "
                         "'wikitext-2-raw-v1' for the 'wikitext' dataset).")
    ap.add_argument("--eval2-text-key", default=None,
                    help="If set, treat --eval2-dataset as PLAIN TEXT and compute "
                         "a language-modeling loss over packed --seq-len blocks "
                         "(every token supervised) -- e.g. 'text' for wikitext. "
                         "If unset, --eval2-dataset is built as a second SFT eval "
                         "using the same instruction/messages keys.")
    ap.add_argument("--eval2-max-samples", type=int, default=0,
                    help="Cap source rows for --eval2-dataset (0 = all).")
    ap.add_argument("--eval2-max-blocks", type=int, default=0,
                    help="Cap the number of packed LM blocks for --eval2-text-key "
                         "(0 = all). Use this to size eval2 to roughly match the "
                         "primary eval set (e.g. wikitext packs into far more "
                         "blocks than your test set has examples); --eval2-max-"
                         "samples caps source rows, which is unpredictable after "
                         "packing.")
    ap.add_argument("--val-frac", type=float, default=0.0,
                    help="Hold out this fraction of train for held-out eval loss "
                         "(deterministic; the SAME split as qlora_train_bnb.py "
                         "given the same dataset/seed). Ignored if --eval-split is "
                         "set. 0 = no eval.")
    ap.add_argument("--eval-every", type=int, default=0,
                    help="Also report held-out loss every N steps (needs "
                         "--val-frac > 0). 0 = only at the end.")
    ap.add_argument("--save-best", action="store_true",
                    help="Save the adapter only when held-out loss improves "
                         "(needs --val-frac + --eval-every), so a long run keeps "
                         "the best checkpoint instead of an overfit endpoint.")
    ap.add_argument("--run-log", default="qlora_runs.csv",
                    help="Append one metadata row per run to this CSV (model, "
                         "hyperparameters, start/end/best-val loss, timing, tok/s, "
                         "peak VRAM, ...). Written on normal finish, on Ctrl-C, AND "
                         "on failure (status=failed + error; traceback goes to "
                         "<run-log>.errors.log). Empty string disables.")
    ap.add_argument("--profile-dequant", type=int, default=0, metavar="N",
                    help="Measure frozen-weight (trellis) reconstruction time for "
                         "the first N training steps, print its share of the step "
                         "wall time, then disable. Adds a device sync around every "
                         "reconstruction while active, so expect those N steps to "
                         "run slower; the reported %% is still representative.")
    ap.add_argument("--ga-loss", choices=["token", "mean"], default="token",
                    help="Gradient-accumulation loss weighting. token (default): "
                         "weight each micro-batch by its supervised-token share, "
                         "so the step gradient equals one big batch (the Oct-2024 "
                         "HF/Unsloth GA fix). mean: the pre-Session-11 mean-of-"
                         "means (over-weights tokens in short micro-batches), "
                         "kept for reproducing old runs. No-op at --grad-accum 1.")
    args = ap.parse_args()

    # Seed the failure logger with everything knowable before work starts, so a
    # crash at ANY later point (bad dataset name, OOM, unsupported arch guard)
    # still produces a run-log row identifying the attempt. Progress fields
    # (steps_done, end_loss, peak VRAM, phase) are refreshed as the run advances.
    _FAIL_CTX["run_log"] = args.run_log
    _FAIL_CTX["phase"] = "startup"
    _FAIL_CTX["record"] = {
        "timestamp": datetime.datetime.now().isoformat(timespec="seconds"),
        "arm": "exl3-native", "model": args.model, "out": args.out,
        "dataset": args.dataset, "eval_split": args.eval_split or "",
        "eval_dataset": args.eval_dataset or "",
        "eval2_dataset": args.eval2_dataset or "",
        "r": args.r, "alpha": args.alpha,
        "use_rslora": int(bool(args.use_rslora)), "init_lora": args.init_lora,
        "lr": args.lr,
        "scheduler": args.scheduler, "weight_decay": args.weight_decay,
        "batch": args.batch, "grad_accum": args.grad_accum, "world_size": 1,
        "eff_batch": args.batch * args.grad_accum, "epochs": args.epochs,
        "steps_planned": args.steps, "seq_len": args.seq_len,
        "compute_dtype": args.compute_dtype, "attn_impl": args.attn_impl,
        "parallel": args.parallel, "shuffle": int(bool(args.shuffle)),
        "pack": int(bool(args.pack)),
        "pack_algo": args.pack_algo if args.pack else "",
        "ga_loss": args.ga_loss, "max_samples": args.max_samples,
        "train_embeddings": int(bool(args.train_embeddings)),
        "train_head": int(bool(args.train_head)),
        "prompt_format": args.prompt_format,
    }

    # Text cleaning is opt-in (--clean-text). --no-clean-text is the old default
    # and now a no-op, kept so existing commands don't break.
    if args.no_clean_text:
        print(" -- note: --no-clean-text is deprecated; cleaning is now OFF by "
              "default. Drop the flag, or use --clean-text to enable cleaning.")
    clean_text = args.clean_text

    cdt = {"float32": torch.float32, "float16": torch.float16,
           "bfloat16": torch.bfloat16}[args.compute_dtype]

    # 1. Load native model + tokenizer (the forward that's correct on EXL3).
    _FAIL_CTX["phase"] = "load_model"
    config = Config.from_directory(args.model)
    model = Model.from_config(config)

    # The KV cache must be created BEFORE model.load() so each attention layer
    # allocates its cache during loading; otherwise generation asserts on a
    # missing k_cache. Only needed for the live samples.
    cache = None
    if args.sample_every:
        from exllamav3 import Cache
        cache = Cache(model, max_num_tokens=4096)

    if args.parallel == "split":
        load_kwargs = {}
        if args.reserve_per_device is not None:
            load_kwargs["reserve_per_device"] = args.reserve_per_device
        if args.use_per_device is not None:
            load_kwargs["use_per_device"] = args.use_per_device
        model.load(progressbar=True, **load_kwargs)
        active_devices = list(model.active_devices)
        print(f" -- layer-autosplit: active devices {active_devices}, "
              f"output device {model.output_device}")
    else:
        model.load(device=args.device, progressbar=True)
        active_devices = [torch.device(args.device).index]
    tokenizer = Tokenizer.from_config(config)
    pad_id = tokenizer.pad_token_id
    if pad_id is None or pad_id < 0:
        pad_id = tokenizer.eos_token_id or 0

    # 2. Build the differentiable QLoRA model (frozen base + trainable adapters).
    if args.offload_embed_head_optim and not (args.train_embeddings or args.train_head):
        raise SystemExit("--offload-embed-head-optim has nothing to offload without "
                         "--train-embeddings and/or --train-head.")
    # bf16 embed/head master weights when the CPU-offload optimizer (bf16 stochastic
    # rounding) drives them; fp32 otherwise.
    ms_dtype = torch.bfloat16 if args.offload_embed_head_optim else torch.float32
    _FAIL_CTX["phase"] = "build_net"
    _FAIL_CTX["record"]["arch"] = getattr(config, "architecture", "")
    net = NativeLlamaQLoRA(
        model, r=args.r, alpha=args.alpha, target_modules=args.targets,
        use_rslora=args.use_rslora,
        compute_dtype=cdt, gradient_checkpointing=not args.no_grad_ckpt,
        train_embeddings=args.train_embeddings, train_head=args.train_head,
        attn_impl=args.attn_impl, head_vocab_chunk=args.head_vocab_chunk,
        modules_to_save_dtype=ms_dtype,
        lora_embed=args.lora_embed, lora_head=args.lora_head,
        offload_activations=args.offload_activations, use_liger=args.use_liger,
    )
    net.train()
    if args.head_vocab_chunk and net._head_slice is None:
        print(" -- note: --head-vocab-chunk set but this head can't slice; using "
              "the single-shot fused head.")
    if args.init_lora in ("pissa", "qerr"):
        # SVD init from the loaded weights. On resume this is recomputed and then
        # OVERWRITTEN by load_adapter below (pissa restores its exact offsets from
        # the checkpoint sidecar) -- a few wasted seconds, kept for simplicity.
        # (eva runs after the dataset is built -- it needs an activation pre-pass.)
        _FAIL_CTX["phase"] = "init_lora"
        net.apply_init_lora(args.init_lora, ref_model_dir=args.init_ref_model,
                            svd_niter=args.init_svd_niter)
    if args.resume:
        net.load_adapter(args.resume)
    ms = [n for n, p in [("embed", net.embed_weight), ("head", net.head_weight)] if p is not None]
    print(f" -- trainable params: {net.num_trainable():,} "
          f"(r={args.r}, alpha={args.alpha}, targets={net.target_modules}"
          f"{', modules_to_save=' + str(ms) if ms else ''})")
    print(f" -- {net.describe_attn()}")
    if args.parallel == "split":
        from collections import Counter
        dist = Counter(str(d) for d in net._block_devices)
        print(f" -- decoder block devices: {dict(dist)}  (final norm + head on {net.device})")

    # 3. Data.
    _FAIL_CTX["phase"] = "build_dataset"
    examples = build_sft_examples(
        model, tokenizer, args.dataset, args.max_samples, args.seq_len,
        instruction_key=args.instruction_key, context_key=args.context_key,
        response_key=args.response_key, split=args.dataset_split,
        clean_text=clean_text,
        min_response_words=args.min_response_words,
        uppercase_response=args.uppercase_response,
        messages_key=args.messages_key,
        prompt_format=args.prompt_format,
        shuffle=args.shuffle, shuffle_seed=args.shuffle_seed,
    )
    print(f" -- {len(examples)} SFT examples{' (shuffled)' if args.shuffle else ''}")
    assert examples, "no usable training examples"

    # Tokenization check: decode the prompt span (labels==-100) and the supervised
    # response span (labels!=-100) separately, so the mask boundary and any
    # --seq-len truncation are visible before committing to a run. Specials are
    # shown so the chat template / <|eot_id|> stop token can be eyeballed.
    if args.inspect:
        _, eot = format_prompt_and_eot(model, tokenizer, args.prompt_format)
        eot_id = tokenizer.encode(eot, add_bos=False,
                                  encode_special_tokens=True)[0].tolist() if eot else []
        # encode() auto-prepends BOS (see build_sft_examples); strip it so the
        # "ends with turn-end token" check compares the real eot id(s), not [BOS, eot].
        bos = tokenizer.bos_token_id
        if eot_id and bos is not None and eot_id[0] == bos:
            eot_id = eot_id[1:]
        for i, ex in enumerate(examples[:args.inspect]):
            ids, labs = ex["input_ids"], ex["labels"]
            n_prompt = sum(1 for l in labs if l == -100)
            sup = [t for t, l in zip(ids, labs) if l != -100]
            prompt_ids = ids[:n_prompt]
            dec = lambda seq: tokenizer.decode(torch.tensor([seq]),
                                               decode_special_tokens=True)
            ends_eot = bool(eot_id) and sup[-len(eot_id):] == eot_id
            print(f"\n===== example {i} | {len(ids)} tokens "
                  f"({n_prompt} prompt / {len(sup)} supervised) =====")
            print(f"  PROMPT  (masked, -100): {dec(prompt_ids)!r}")
            print(f"  RESPONSE(supervised)  : {dec(sup)!r}")
            print(f"  ends with turn-end token ({eot!r})? {ends_eot}"
                  + ("" if ends_eot else
                     "   <-- WARNING: response truncated by --seq-len; "
                     "raise --seq-len so the model learns to stop"))
        if args.pack:
            # Inspect decodes per-document (the tokenization check is per doc);
            # add a one-line packing summary so the fill ratio is visible too.
            real_tokens = sum(len(ex["input_ids"]) for ex in examples)
            blocks = pack_examples(examples, args.seq_len, pad_id, algo=args.pack_algo)
            cap = max(1, len(blocks) * args.seq_len)
            print(f"\n -- packing ({args.pack_algo}): {len(examples)} docs -> "
                  f"{len(blocks)} blocks of "
                  f"{args.seq_len} tok ({100.0 * real_tokens / cap:.1f}% filled); "
                  f"block 0 holds {len(set(blocks[0]['seg_ids']))} docs")
        print(f"\n -- inspect only ({args.inspect} shown); exiting before training.")
        return

    # Held-out eval set. Prefer the dataset's own eval split (real held-out data);
    # otherwise carve a deterministic val_frac off the front of train (same rows
    # as qlora_train_bnb.py, so the arms' eval losses stay comparable).
    val_examples = []
    if args.eval_split:
        val_examples = build_sft_examples(
            model, tokenizer, args.eval_dataset or args.dataset, 0, args.seq_len,
            instruction_key=args.instruction_key, context_key=args.context_key,
            response_key=args.response_key, split=args.eval_split,
            clean_text=clean_text,
            min_response_words=args.min_response_words,
            uppercase_response=args.uppercase_response,
            messages_key=args.messages_key,
            prompt_format=args.prompt_format,
        )
        print(f" -- held-out eval: {len(val_examples)} examples from "
              f"split '{args.eval_split}'; {len(examples)} for training")
    elif args.val_frac > 0:
        n_val = max(1, int(len(examples) * args.val_frac))
        val_examples, examples = examples[:n_val], examples[n_val:]
        print(f" -- held out {len(val_examples)} val examples; "
              f"{len(examples)} for training")
        assert examples, "val_frac too large; no training examples left"

    # Optional SECOND held-out eval set (task-independent monitor, e.g. wikitext).
    # Plain-text LM loss when --eval2-text-key is given, else a second SFT eval.
    val2_examples = []
    eval2_label = ""
    if args.eval2_dataset:
        eval2_label = args.eval2_dataset.split("/")[-1]
        if args.eval2_text_key:
            val2_examples = build_lm_examples(
                tokenizer, args.eval2_dataset, args.eval2_split, args.seq_len,
                text_key=args.eval2_text_key, max_samples=args.eval2_max_samples,
                config_name=args.eval2_config, max_blocks=args.eval2_max_blocks)
            kind = f"LM blocks over '{args.eval2_text_key}'"
        else:
            val2_examples = build_sft_examples(
                model, tokenizer, args.eval2_dataset, args.eval2_max_samples,
                args.seq_len, instruction_key=args.instruction_key,
                context_key=args.context_key, response_key=args.response_key,
                split=args.eval2_split, clean_text=clean_text,
                min_response_words=args.min_response_words,
                uppercase_response=args.uppercase_response,
                messages_key=args.messages_key, prompt_format=args.prompt_format,
                config_name=args.eval2_config)
            kind = "SFT"
        print(f" -- eval2 ({eval2_label}): {len(val2_examples)} {kind} examples "
              f"from split '{args.eval2_split}'")

    # Sample packing (training set ONLY -- eval stays per-example for comparable
    # losses). Done after the val carve so a packed block never straddles the
    # train/val boundary; resolve_steps below then counts packed blocks as the
    # training unit, so --epochs still means "passes over the data".
    if args.pack:
        n_docs = len(examples)
        real_tokens = sum(len(ex["input_ids"]) for ex in examples)
        examples = pack_examples(examples, args.seq_len, pad_id, algo=args.pack_algo)
        cap = max(1, len(examples) * args.seq_len)
        print(f" -- packed ({args.pack_algo}) {n_docs} docs -> {len(examples)} blocks "
              f"of {args.seq_len} tok ({100.0 * real_tokens / cap:.1f}% filled, "
              f"~{real_tokens / max(1, len(examples)):.0f} real tok/block)")
        assert examples, "no training blocks after packing"

    # eva init runs HERE (not with pissa/qerr above): it streams a no-grad
    # activation pre-pass over the actual training batches. Skipped on resume --
    # the checkpoint's A/B already carry the init, and unlike pissa there are no
    # frozen offsets to reconstruct.
    if args.init_lora == "eva" and not args.resume:
        _FAIL_CTX["phase"] = "init_lora"

        def eva_prepass():
            used, i = 0, 0
            while used < args.init_eva_tokens and i < len(examples):
                batch = examples[i:i + args.batch]
                i += len(batch)
                input_ids, _, attn, pos_ids, seg_ids = collate(batch, pad_id)
                used += int(attn.sum())
                yield dict(input_ids=input_ids, attention_mask=attn,
                           position_ids=pos_ids, seg_ids=seg_ids)

        net.apply_init_lora("eva", svd_niter=args.init_svd_niter,
                            eva_batches=eva_prepass())
    elif args.init_lora == "eva":
        print(" -- eva init skipped on --resume (the checkpoint's adapters "
              "already carry it)")

    # Finalize step count (from --epochs) and warmup before building the schedule.
    args.steps, warmup_steps = resolve_steps_and_warmup(
        args, len(examples), args.batch * args.grad_accum)
    print(f" -- {args.steps} steps, scheduler={args.scheduler}, "
          f"warmup={warmup_steps}, weight_decay={args.weight_decay}")

    # 4. Optional generator for live samples (KV-cache inference path). The cache
    #    was allocated before load() above. Use the training chat format so the
    #    preview is meaningful for a metharme-trained adapter.
    build_prompt, _ = format_prompt_and_eot(model, tokenizer, args.prompt_format)
    generator = None
    if args.sample_every:
        from exllamav3 import Generator
        generator = Generator(model=model, cache=cache, tokenizer=tokenizer)
        net.eval()
        with torch.inference_mode():
            base = sample(model, cache, tokenizer, generator, build_prompt, args.sample_prompt)
        net.train()
        print(f"\n\U0001f3ad  baseline (step 0): {args.sample_prompt}\n     -> {base}\n")

    # 5. Optimizer over the trainable params, plus the LR schedule. Weight decay
    #    on the LoRA params only (param_groups puts embed/head in a 0-WD group).
    #    With --offload-embed-head-optim the embed/head group is split off onto a
    #    separate CPU-offload optimizer (offload_opt) and the main optimizer/scheduler
    #    drives only the LoRA group; offload_opt mirrors the schedule's LR per step.
    offload_opt = None
    if args.offload_embed_head_optim:
        lora_groups = [{"params": net.lora_parameters(), "weight_decay": args.weight_decay}]
        opt = build_optimizer(lora_groups, args.lr, args.optim)
        offload_opt = build_cpu_offload_optimizer(net.modules_to_save_parameters(), args.lr)
        print(f" -- embed/head optimizer offloaded to CPU (torchao, bf16 stochastic "
              f"rounding); excluded from grad clip, follows the LoRA LR schedule")
    else:
        opt = build_optimizer(net.param_groups(args.weight_decay), args.lr, args.optim)
    sched = make_lr_scheduler(opt, args.scheduler, args.steps, warmup_steps)

    # 5a. Optionally restore optimizer/schedule/step from the resumed checkpoint so
    #     the run continues instead of cold-restarting warmup/cosine. resume_state
    #     seeds best_val/ema below; resume_step shifts the loop's start.
    resume_step, resume_state = 0, None
    if args.resume and not args.reset_optimizer:
        resume_state = load_trainer_state(args.resume)
        if resume_state is not None:
            restore_optimizer_state(opt, resume_state["optimizer"])
            # The CPU-offload optimizer manages its own (CPU) state placement, so
            # load it directly rather than through restore_optimizer_state (which would
            # move state onto the params' GPU devices). Absent in pre-offload runs.
            if offload_opt is not None and resume_state.get("offload_optimizer") is not None:
                offload_opt.load_state_dict(resume_state["offload_optimizer"])
            if resume_state.get("scheduler") is not None:
                sched.load_state_dict(resume_state["scheduler"])
            resume_step = int(resume_state["step"])
            print(f" -- resumed trainer state from {args.resume}: continuing at "
                  f"step {resume_step + 1}/{args.steps} (best_val "
                  f"{resume_state['best_val']}, lr {sched.get_last_lr()[0]:.2e})")
            if resume_step >= args.steps:
                print(f" -- WARNING: resume step {resume_step} >= --steps "
                      f"{args.steps}; nothing to do. Raise --steps/--epochs.")
        else:
            print(f" -- {args.resume} has no trainer_state.pt; resuming weights "
                  f"only (cold optimizer + schedule from step 0).")

    def batches():
        order = list(range(len(examples)))
        while True:
            random.Random(0).shuffle(order)
            for i in range(0, len(order) - args.batch + 1, args.batch):
                yield [examples[j] for j in order[i:i + args.batch]]

    # |dB| telemetry baseline. With an SVD init the raw ‖B‖ is dominated by the
    # constant init component (a whole run moves it in the 4th decimal), so the
    # step line logs the distance from the init instead: B0 is zero for the
    # default init (‖B-B0‖ == ‖B‖, matching historical logs), the exact fp32
    # sidecar masters for pissa (survives --resume), or a CPU fp32 snapshot
    # taken here (qerr; on a qerr --resume this measures movement since the
    # resume, not since the original init). CPU on purpose -- the snapshot must
    # not eat VRAM, and the per-step transfer is microseconds per wrapper.
    b0_refs = []
    with torch.no_grad():
        for w in net._wrappers:
            if w.r <= 0:
                continue
            if w.init_b0_master is not None:
                b0_refs.append((w, w.init_b0_master))
            elif args.init_lora != "default" and w.lora_b.abs().max().item() > 0:
                b0_refs.append((w, w.lora_b.detach().float().cpu().clone()))
            else:
                b0_refs.append((w, None))

    def adapter_b_norm():
        # Per-wrapper sums live on each wrapper's own device (they differ under a
        # layer split), so reduce each to a Python float before summing -- adding
        # tensors across cuda:0/cuda:1 would raise a cross-device error.
        with torch.no_grad():
            tot = 0.0
            for w, b0 in b0_refs:
                if b0 is None:
                    tot += w.lora_b.float().pow(2).sum().item()
                else:
                    tot += (w.lora_b.detach().float().cpu() - b0).pow(2).sum().item()
            return tot ** 0.5

    def save(tag):
        # Always leave net in train mode after; saving touches the adapter only.
        net.save_adapter(args.out, base_model_name_or_path=args.model)
        save_trainer_state(args.out, step=step, opt=opt, sched=sched,
                           best_val=best_val, best_val_step=best_val_step, ema=ema,
                           offload_opt=offload_opt)
        print(f"{tag} Adapter written to {args.out}")

    def eval_loss(exs):
        # Mean per-example loss over an eval set, one example at a time (no
        # padding effects). qlora_train_bnb.py computes this identically. Works
        # for both SFT (completion-masked) and plain-LM (all-supervised) sets.
        if not exs:
            return None
        net.eval()
        total, n = 0.0, 0
        with torch.no_grad():
            for ex in exs:
                input_ids, labels, attn, pos_ids, seg_ids = collate([ex], pad_id)
                l = net.compute_loss(input_ids, labels, attention_mask=attn,
                                     chunk=args.ce_chunk,
                                     position_ids=pos_ids, seg_ids=seg_ids)
                total += l.item()
                n += 1
        net.train()
        return total / n

    def evaluate():
        return eval_loss(val_examples)

    bgen = batches()
    opt.zero_grad(set_to_none=True)
    if offload_opt is not None:
        offload_opt.zero_grad(set_to_none=True)
    # Seed from the resumed state so best-tracking and the EMA continue rather than
    # reset (resume_state is None under --reset-optimizer / a weights-only dir).
    ema = resume_state["ema"] if resume_state else None
    step = resume_step
    best_val = resume_state["best_val"] if resume_state else float("inf")
    best_val_step = resume_state["best_val_step"] if resume_state else 0
    start_loss = end_loss = None
    start_val = start_eval2 = None
    last_eval_step, last_val, last_eval2 = -1, None, None
    tok_seen, tot_seen, t0 = 0, 0, time.time()
    run_started = datetime.datetime.now().isoformat(timespec="seconds")
    meter = ThroughputMeter()

    # (peak_vram_gb / log_run are defined once below, after the baseline eval --
    # an earlier duplicate pair that used to sit here was dead code and is gone.)

    # Baseline eval at step 0 (the adapter is a no-op at init, B=0, so this is the
    # base model's held-out loss) -- a reference point for the trained numbers.
    _FAIL_CTX["phase"] = "baseline_eval"
    if val_examples or val2_examples:
        start_val = evaluate()
        start_eval2 = eval_loss(val2_examples) if val2_examples else None
        parts = []
        if start_val is not None:
            parts.append(f"held-out {start_val:.4f}")
        if start_eval2 is not None:
            parts.append(f"{eval2_label} {start_eval2:.4f}")
        print("    [eval] step 0 (baseline): " + " | ".join(parts))

    # Start the training timer + VRAM peak AFTER the baseline eval so neither is
    # counted against training throughput.
    t0 = time.time()
    if torch.cuda.is_available():
        for d in active_devices:
            torch.cuda.reset_peak_memory_stats(d)

    def peak_vram_gb():
        if not torch.cuda.is_available():
            return 0.0
        return max((torch.cuda.max_memory_allocated(d) / 1e9 for d in active_devices),
                   default=0.0)

    def log_run(status, dt, final_val, final_eval2):
        # One CSV row capturing the run's identity, hyperparameters and results.
        # Called on normal finish and on Ctrl-C; crashes are covered separately
        # by _log_failure (main()'s wrapper), which this call disarms.
        # NOTE: start_val/start_eval2 were silently missing from this record for
        # several sessions (a duplicate-definition merge artifact shadowed the
        # copy that had them); restored in Session 11.
        _FAIL_CTX["logged"] = True
        rnd = lambda x, n=6: round(x, n) if isinstance(x, (int, float)) else ""
        append_run_log(args.run_log, {
            "timestamp": run_started, "arm": "exl3-native", "status": status,
            "model": args.model, "arch": getattr(config, "architecture", ""),
            "out": args.out, "dataset": args.dataset,
            "eval_split": args.eval_split or "", "eval_dataset": args.eval_dataset or "",
            "eval2_dataset": args.eval2_dataset or "",
            "r": args.r, "alpha": args.alpha,
            "use_rslora": int(bool(args.use_rslora)), "init_lora": args.init_lora,
            "lr": args.lr,
            "scheduler": args.scheduler, "warmup_steps": warmup_steps,
            "weight_decay": args.weight_decay, "batch": args.batch,
            "grad_accum": args.grad_accum, "world_size": 1,
            "eff_batch": args.batch * args.grad_accum, "epochs": args.epochs,
            "steps_planned": args.steps, "steps_done": step, "seq_len": args.seq_len,
            "targets": " ".join(net.target_modules), "compute_dtype": args.compute_dtype,
            "attn_impl": args.attn_impl, "parallel": args.parallel,
            "shuffle": int(bool(args.shuffle)), "pack": int(bool(args.pack)),
            "pack_algo": args.pack_algo if args.pack else "",
            "ga_loss": args.ga_loss,
            "max_samples": args.max_samples,
            "train_embeddings": int(bool(args.train_embeddings)),
            "train_head": int(bool(args.train_head)), "prompt_format": args.prompt_format,
            "trainable_params": net.num_trainable(), "n_train": len(examples),
            "n_val": len(val_examples), "n_eval2": len(val2_examples),
            "start_loss": rnd(start_loss), "end_loss": rnd(end_loss),
            "best_val": rnd(best_val) if best_val != float("inf") else "",
            "best_val_step": best_val_step or "",
            "start_val": rnd(start_val), "start_eval2": rnd(start_eval2),
            "final_val": rnd(final_val), "final_eval2": rnd(final_eval2),
            "total_s": rnd(dt, 1), "s_per_step": rnd(dt / step, 4) if step else "",
            "sup_tok_s": round(tok_seen / dt) if dt else "",
            "tot_tok_s": round(tot_seen / dt) if dt else "",
            "peak_vram_gb": rnd(peak_vram_gb(), 3),
            "t_data_s": rnd(timer.total["data"], 1), "t_fwd_s": rnd(timer.total["fwd"], 1),
            "t_bwd_s": rnd(timer.total["bwd"], 1), "t_opt_s": rnd(timer.total["opt"], 1),
            "dequant_s_per_step": rnd(dequant_s_per_step, 3)
                if dequant_s_per_step is not None else "",
            "phase": "", "error": "", "notes": "",
        })

    # Per-step wall-clock section breakdown (data/fwd/bwd/opt). Under --parallel
    # split the step spans several devices; sync them all at each mark.
    timer = StepTimer(devices=active_devices if torch.cuda.is_available() else None)

    # Optional dequant profiling: time every frozen-weight reconstruction for the
    # first N steps to answer "how much of the step is trellis reconstruction".
    dq_profile = None
    dequant_s_per_step = None
    if args.profile_dequant > 0:
        from exllamav3.training import backbone as _backbone
        dq_profile = {"calls": 0, "s": 0.0}
        _backbone.profile_dequant(dq_profile)
        print(f" -- profiling dequant (trellis reconstruction) for the first "
              f"{args.profile_dequant} steps; adds sync overhead while active")
    try:
        for step in range(resume_step + 1, args.steps + 1):
            _FAIL_CTX["phase"] = f"train step {step}"
            step_t0 = time.time()
            accum_loss = 0.0
            step_sup = step_tot = 0
            timer.begin_step()
            # Draw the WHOLE accumulation window first so each micro-batch can be
            # weighted by its share of the window's supervised tokens (--ga-loss
            # token, the Oct-2024 HF/Unsloth grad-accumulation fix): compute_loss
            # returns a mean over each micro-batch's own supervised tokens, so
            # averaging those means (the old behavior, kept as --ga-loss mean)
            # over-weights tokens in short micro-batches. Weighting each loss by
            # n_sup/total_sup makes the step gradient identical to one big batch.
            # Counts use the SHIFTED labels ([:, 1:]) to match the CE denominator.
            # A no-op when grad_accum == 1 (weight = 1).
            window = [collate(next(bgen), pad_id) for _ in range(args.grad_accum)]
            n_sups = [int((w[1][:, 1:] != -100).sum()) for w in window]
            total_sup = max(sum(n_sups), 1)
            timer.mark("data")
            for (input_ids, labels, attn, pos_ids, seg_ids), n_sup in zip(window, n_sups):
                loss = net.compute_loss(input_ids, labels, attention_mask=attn,
                                        chunk=args.ce_chunk,
                                        position_ids=pos_ids, seg_ids=seg_ids)
                # .item() before backward (harmless to the graph) so the fwd/bwd
                # sections split cleanly at the sync.
                loss_val = loss.item()
                timer.mark("fwd")
                w_i = (n_sup / total_sup) if args.ga_loss == "token" \
                    else (1.0 / args.grad_accum)
                (loss * w_i).backward()
                timer.mark("bwd")
                # accum_loss uses the same weights, so under "token" it is the
                # true per-token mean over the whole accumulation window.
                accum_loss += loss_val * w_i
                step_sup += int((labels != -100).sum())   # supervised tokens
                step_tot += int(attn.sum())                # total (non-pad) tokens

            # grad norm BEFORE clipping is a direct check that gradients reach the
            # adapters (a flat ~0 here would mean the backward graph is broken).
            # Under --offload-embed-head-optim the embed/head params are excluded
            # (torchao's CPUOffloadOptimizer forbids grad clipping on its params);
            # the LoRA grads are what the norm/clip should reflect anyway.
            clip_params = (net.lora_parameters() if offload_opt is not None
                           else net.trainable_parameters())
            gnorm = torch.nn.utils.clip_grad_norm_(
                clip_params, args.max_grad_norm or float("inf")
            ).item()
            if offload_opt is not None:
                # Mirror the schedule's current LR (the one opt.step() is about to use)
                # onto the offload optimizer, which has no scheduler support, then step
                # both. Set before stepping so embed/head move at the same LR as LoRA.
                set_offload_lr(offload_opt, sched.get_last_lr()[0])
                offload_opt.step()
            opt.step()
            sched.step()
            opt.zero_grad(set_to_none=True)
            if offload_opt is not None:
                offload_opt.zero_grad(set_to_none=True)
            timer.mark("opt")
            timer.end_step()

            # Rolling tok/s over the train-step compute only (eval/sample/save
            # below are excluded so the rate reflects steady-state throughput).
            tok_seen += step_sup
            tot_seen += step_tot
            meter.update(time.time() - step_t0, step_sup, step_tot)
            _, tot_tps = meter.rates()

            if start_loss is None:
                start_loss = accum_loss
            end_loss = accum_loss
            ema = accum_loss if ema is None else 0.9 * ema + 0.1 * accum_loss
            print(f"  step {step:>5}/{args.steps} | loss {accum_loss:6.4f} | "
                  f"ema {ema:6.4f} | grad {gnorm:7.4f} | lr {sched.get_last_lr()[0]:.2e} | "
                  f"|dB| {adapter_b_norm():7.3f} | {tot_tps:,.0f} tok/s | {timer.step_line()}")

            # Keep the failure record current so a later crash (or kill -9 at
            # least leaves the errors.log short a row, see _FAIL_CTX note)
            # carries how far the run got and its memory/loss state.
            _FAIL_CTX["record"].update(
                steps_done=step, end_loss=round(accum_loss, 6),
                peak_vram_gb=round(peak_vram_gb(), 3))
            if start_loss is not None and "start_loss" not in _FAIL_CTX["record"]:
                _FAIL_CTX["record"]["start_loss"] = round(start_loss, 6)

            # End of the dequant profiling window: report reconstruction time
            # against the timed step wall clock, then disable the hook.
            if dq_profile is not None and (step - resume_step) >= args.profile_dequant:
                n_prof = step - resume_step
                wall = sum(timer.total.values())
                dequant_s_per_step = dq_profile["s"] / max(1, n_prof)
                print(f"  [profile] dequant: {dq_profile['calls']:,} reconstructions, "
                      f"{dq_profile['s']:.2f}s over {n_prof} steps = "
                      f"{dequant_s_per_step:.3f}s/step "
                      f"({100.0 * dq_profile['s'] / max(wall, 1e-9):.0f}% of step wall "
                      f"time) -- profiling off from here")
                from exllamav3.training import backbone as _backbone
                _backbone.profile_dequant(None)
                dq_profile = None

            if (args.eval_every and step % args.eval_every == 0
                    and (val_examples or val2_examples)):
                vl = evaluate() if val_examples else None
                v2 = eval_loss(val2_examples) if val2_examples else None
                last_eval_step, last_val, last_eval2 = step, vl, v2
                parts = []
                if vl is not None:
                    parts.append(f"held-out {vl:.4f}")
                    # Track best val for the run log regardless of --save-best;
                    # only write the checkpoint when --save-best is set.
                    if vl < best_val:
                        best_val = vl
                        best_val_step = step
                        if args.save_best:
                            save(f"[best step {step}, val {vl:.4f}]")
                if v2 is not None:
                    parts.append(f"{eval2_label} {v2:.4f}")
                print(f"    [eval] step {step}: " + " | ".join(parts))

            if args.sample_every and step % args.sample_every == 0:
                net.eval()
                net.apply_to_native()      # make generation reflect the adapter
                with torch.inference_mode():
                    txt = sample(model, cache, tokenizer, generator, build_prompt, args.sample_prompt)
                net.remove_from_native()
                net.train()
                print(f"\n  \U0001f3ad  [step {step}] {args.sample_prompt}\n     -> {txt}\n")

            if args.save_every and step % args.save_every == 0:
                save(f"[checkpoint step {step}]")

            if args.checkpoint_every and step % args.checkpoint_every == 0:
                cdir = checkpoint_dir(args.out, step)
                net.save_adapter(cdir, base_model_name_or_path=args.model)
                save_trainer_state(cdir, step=step, opt=opt, sched=sched,
                                   best_val=best_val, best_val_step=best_val_step,
                                   ema=ema, offload_opt=offload_opt)
                print(f"  [checkpoint] step {step} -> {cdir} (resumable)")
                prune_checkpoints(args.out, args.keep_checkpoints)
    except KeyboardInterrupt:
        # Stopping early at the loss plateau is a normal workflow; don't discard
        # the adapter trained so far -- unless --save-best already kept the
        # best-val checkpoint, in which case saving now would clobber it with
        # later (likely overfit) weights.
        if args.save_best and val_examples:
            print(f"\nInterrupted at step {step}; keeping best-val adapter.")
        else:
            print(f"\nInterrupted at step {step}; saving adapter before exit.")
            if step > 0:
                save("[interrupted]")
        log_run("interrupted", time.time() - t0, None, None)
        raise SystemExit(0)

    # 6. Save adapter (PEFT format; loadable by exllamav3.model.lora.LoRA).
    #    With --save-best we already kept the best-val checkpoint; don't clobber
    #    it with the (likely overfit) final-step weights.
    dt = time.time() - t0
    _FAIL_CTX["phase"] = "final_eval"
    # Final held-out numbers. Reuse the last in-loop eval when it already ran on
    # the final step (avoids a duplicate full pass that looks like a hang after
    # "Done."); otherwise compute once, announcing it so the GPU churn is expected.
    if last_eval_step == step:
        val_loss, final_eval2 = last_val, last_eval2
    elif val_examples or val2_examples:
        print(" -- computing final held-out eval (GPU busy, not hung) ...")
        val_loss = evaluate()
        final_eval2 = eval_loss(val2_examples) if val2_examples else None
    else:
        val_loss, final_eval2 = None, None
    if not (args.save_best and val_examples):
        save("Done.")
    if val_loss is not None:
        tag = f" (best kept: {best_val:.4f})" if args.save_best else ""
        print(f"\n[EVAL] held-out loss (EXL3 arm): {val_loss:.4f}{tag} "
              f"over {len(val_examples)} examples")
    if final_eval2 is not None:
        print(f"[EVAL] eval2 ({eval2_label}) loss: {final_eval2:.4f} "
              f"over {len(val2_examples)} examples")
    if torch.cuda.is_available():
        peak_str = " / ".join(
            f"cuda:{d} {torch.cuda.max_memory_allocated(d) / 1e9:.2f}GB"
            for d in active_devices
        )
    else:
        peak_str = "n/a"
    print(f"[PERF] {tok_seen / dt if dt else 0:,.0f} sup tok/s, "
          f"{tot_seen / dt if dt else 0:,.0f} tot tok/s | "
          f"peak VRAM {peak_str} | {dt:.0f}s for {step} steps | "
          f"step time: {timer.summary()}")
    log_run("completed", dt, val_loss, final_eval2)
    print("Verify with: python examples/qlora_infer_native.py "
          f"--model {args.model} --adapter {args.out}")


if __name__ == "__main__":
    main()
