#!/usr/bin/env python3
"""VSM-LM-v2 — full 10K training run.

Viable System Model architecture: S4 intelligence scan, S3 gated
control, S1 multi-scale operations. No prediction heads.

Compared against:
  - Forward CompressorLM:  best eval 5.043 @ step 9500
  - Reverse CompressorLM:  best eval 5.342 @ step 9500

Checkpoints save full VSM instrumentation:
  - S3 gate values per phase (mean, std, min, max)
  - S4 attention entropy
  - Register norm trajectory
  - Per-phase delta and gated norms
  - Activation norms at phase boundaries
  - Eval loss
  - Compile gate test (4 prompts)

Usage:
    uv run python scripts/run_vsm_10k.py
"""

from __future__ import annotations

import json
import sys
import time
from datetime import UTC, datetime
from pathlib import Path

import numpy as np
import torch
import torch.nn.functional as F

sys.path.insert(0, str(Path(__file__).resolve().parent.parent / "src"))

DATA_DIR = Path("/Users/mwhitford/data/fractal-bitnet/shards")

# ══════════════════════════════════════════════════════════════════════
# Config — matches CompressorLM runs for direct comparison
# ══════════════════════════════════════════════════════════════════════

VOCAB_SIZE = 50277
D_MODEL = 256
SEQ_LEN = 4096
D_FF = 768
WINDOW = 8
STRIDES = (1, 8, 64)
N_HEADS = 8

BATCH_SIZE = 2
GRAD_ACCUM = 4
LEARNING_RATE = 6e-4
WEIGHT_DECAY = 0.1
N_STEPS = 10000
WARMUP_STEPS = 500
N_ITERATIONS = 2
SEED = 42

LOG_INTERVAL = 50
EVAL_INTERVAL = 500
CHECKPOINT_INTERVAL = 1000


def banner(text: str) -> None:
    print("\n" + "=" * 60)
    print(f"  {text}")
    print("=" * 60 + "\n", flush=True)


# ══════════════════════════════════════════════════════════════════════
# Data loader (shuffled)
# ══════════════════════════════════════════════════════════════════════

class ShardedDataLoader:
    def __init__(self, data_dir, batch_size, seq_len, split="train", seed=42):
        self.data_dir = Path(data_dir)
        self.batch_size = batch_size
        self.seq_len = seq_len
        shards = sorted(self.data_dir.glob("shard_*.npy"))
        self.shards = shards[:54] if split == "train" else shards[54:]
        rng = np.random.RandomState(seed)
        self._indices = []
        for si, shard_path in enumerate(self.shards):
            shard_len = len(np.load(shard_path, mmap_mode="r"))
            n_seqs = shard_len // (seq_len + 1)
            for j in range(n_seqs):
                self._indices.append((si, j * (seq_len + 1)))
        rng.shuffle(self._indices)
        self._idx_pos = 0
        self._loaded_shards = {}

    def _get_shard(self, idx):
        if idx not in self._loaded_shards:
            self._loaded_shards[idx] = np.load(self.shards[idx], mmap_mode="r")
        return self._loaded_shards[idx]

    def next_batch(self):
        B, T = self.batch_size, self.seq_len
        sequences = []
        for _ in range(B):
            if self._idx_pos >= len(self._indices):
                self._idx_pos = 0
            si, pos = self._indices[self._idx_pos]
            self._idx_pos += 1
            shard = self._get_shard(si)
            seq = shard[pos : pos + T + 1].astype(np.int64)
            sequences.append(seq)
        buf = torch.from_numpy(np.stack(sequences)).long()
        return buf[:, :T], buf[:, 1 : T + 1]

    def reset(self):
        self._idx_pos = 0


def estimate_loss(model, eval_loader, device, n_batches=10):
    model.eval()
    total = 0
    for _ in range(n_batches):
        x, y = eval_loader.next_batch()
        x, y = x.to(device), y.to(device)
        with torch.no_grad():
            _, loss = model(x, y)
        total += loss.item()
    model.train()
    return total / n_batches


# ══════════════════════════════════════════════════════════════════════
# Instrumentation
# ══════════════════════════════════════════════════════════════════════

def get_grad_norms(model):
    """Gradient norms by VSM system."""
    norms = {}

    # S1: per-phase
    for i, name in enumerate(model.phase_names):
        total = sum(
            p.grad.data.norm(2).item() ** 2
            for p in model.s1_layers[i].parameters() if p.grad is not None
        ) ** 0.5
        norms[f"S1_{name}"] = total

    # S3: total and per-iteration gate heads
    norms["S3"] = sum(
        p.grad.data.norm(2).item() ** 2
        for p in model.s3.parameters() if p.grad is not None
    ) ** 0.5

    # S3: per-iteration gate head grad norms (are they diverging?)
    n_phases = model.s3.n_phases
    for it in range(model.n_iterations):
        for pi, name in enumerate(model.phase_names):
            head_idx = it * n_phases + pi
            head = model.s3.gate_heads[head_idx]
            total = sum(
                p.grad.data.norm(2).item() ** 2
                for p in head.parameters() if p.grad is not None
            ) ** 0.5
            norms[f"S3_iter{it}_{name}"] = total

    # S4
    norms["S4"] = sum(
        p.grad.data.norm(2).item() ** 2
        for p in model.s4.parameters() if p.grad is not None
    ) ** 0.5

    # S5: embeddings
    norms["S5_embed"] = sum(
        p.grad.data.norm(2).item() ** 2
        for p in model.token_embed.parameters() if p.grad is not None
    ) ** 0.5

    # S5: register_init
    if model.register_init.grad is not None:
        norms["S5_register"] = model.register_init.grad.norm().item()

    return norms


@torch.no_grad()
def measure_gate_divergence(model):
    """Measure how much iter0 and iter1 gate heads have diverged.

    Returns cosine similarity between corresponding gate head weights.
    Low similarity = the channels have specialized.
    """
    divergence = {}
    n_phases = model.s3.n_phases
    for pi, name in enumerate(model.phase_names):
        iter0_head = model.s3.gate_heads[pi]
        iter1_head = model.s3.gate_heads[n_phases + pi]
        w0 = iter0_head.weight.data.flatten()
        w1 = iter1_head.weight.data.flatten()
        cos = F.cosine_similarity(w0.unsqueeze(0), w1.unsqueeze(0)).item()
        divergence[f"gate_cosine_{name}"] = round(cos, 6)
    return divergence


@torch.no_grad()
def measure_dynamics(model, eval_loader, device, n_batches=5):
    """Full VSM instrumentation via forward_instrumented."""
    model.eval()
    all_metrics = []
    for _ in range(n_batches):
        x_ids, y = eval_loader.next_batch()
        x_ids = x_ids.to(device)
        _, _, metrics = model.forward_instrumented(x_ids)
        all_metrics.append(metrics)

    # Average across batches
    keys = all_metrics[0].keys()
    avg = {k: round(sum(d[k] for d in all_metrics) / len(all_metrics), 6)
           for k in keys}
    model.train()
    return avg


def compile_gate_test(model, tokenizer, device):
    """Test if model produces lambda notation."""
    prompts = [
        "λ",
        "The dog chased the cat",
        "Every student read a book",
        "compile: The cat sat on the mat",
    ]
    results = []
    model.eval()
    for prompt in prompts:
        ids = tokenizer.encode(prompt, return_tensors="pt").to(device)
        out = model.generate(ids, max_new_tokens=30, temperature=0.8)
        text = tokenizer.decode(out[0], skip_special_tokens=True)
        has_lambda = "λ" in text[len(prompt):] or "\\" in text[len(prompt):]
        results.append({"prompt": prompt, "output": text, "has_lambda": has_lambda})
    model.train()
    n_lambda = sum(1 for r in results if r["has_lambda"])
    return {"score": f"{n_lambda}/{len(prompts)}", "results": results}


# ══════════════════════════════════════════════════════════════════════
# Main
# ══════════════════════════════════════════════════════════════════════

def main():
    device = "mps" if torch.backends.mps.is_available() else "cpu"

    from transformers import AutoTokenizer
    from verbum.vsm_lm_v2 import VSMLMV2

    results_dir = Path("results/vsm-lm-v2")
    results_dir.mkdir(parents=True, exist_ok=True)
    checkpoint_dir = Path("checkpoints/vsm-lm-v2")
    checkpoint_dir.mkdir(parents=True, exist_ok=True)

    torch.manual_seed(SEED)
    np.random.seed(SEED)

    start = time.time()
    banner("VSM-LM v2 — Two-channel compressor 10K STEPS")

    tokenizer = AutoTokenizer.from_pretrained("EleutherAI/pythia-160m-deduped")

    tokens_total = N_STEPS * BATCH_SIZE * GRAD_ACCUM * SEQ_LEN
    print(f"  Device: {device}")
    print(f"  Architecture: VSM-LM-v2 (per-iter gates + per-iter S4) (S5→S4→S3→S1→S2)")
    print(f"  S1 strides: {STRIDES}")
    print(f"  S1 order: type → parse → apply (fine→coarse)")
    print(f"  S4: once (pre-iteration)")
    print(f"  S3: per-dimension gating")
    print(f"  Iterations: {N_ITERATIONS}")
    print(f"  Seq len: {SEQ_LEN}")
    print(f"  Batch: {BATCH_SIZE} × {GRAD_ACCUM} accum = {BATCH_SIZE * GRAD_ACCUM}")
    print(f"  Steps: {N_STEPS}")
    print(f"  Tokens: {tokens_total:,}")
    print(f"  Data: SHUFFLED", flush=True)

    # ── Build model ───────────────────────────────────────────────────
    banner("BUILDING MODEL")

    model = VSMLMV2(
        vocab_size=VOCAB_SIZE, d_model=D_MODEL, max_len=SEQ_LEN,
        n_heads=N_HEADS, d_ff=D_FF, window=WINDOW, strides=STRIDES,
        n_iterations=N_ITERATIONS,
    ).to(device)

    print(model.describe())
    print()
    params = model.count_parameters()
    for k, v in params.items():
        print(f"  {k:25s}: {v:>12,}")
    print(flush=True)

    # ── Data ──────────────────────────────────────────────────────────
    train_loader = ShardedDataLoader(DATA_DIR, BATCH_SIZE, SEQ_LEN, "train", seed=SEED)
    eval_loader = ShardedDataLoader(DATA_DIR, BATCH_SIZE, SEQ_LEN, "eval", seed=SEED + 1)

    # ── Optimizer ─────────────────────────────────────────────────────
    optimizer = torch.optim.AdamW(
        model.parameters(), lr=LEARNING_RATE, weight_decay=WEIGHT_DECAY,
        betas=(0.9, 0.95),
    )

    def lr_schedule(step):
        if step < WARMUP_STEPS:
            return step / WARMUP_STEPS
        progress = (step - WARMUP_STEPS) / max(1, N_STEPS - WARMUP_STEPS)
        return max(0.1, 0.5 * (1 + np.cos(np.pi * progress)))

    scheduler = torch.optim.lr_scheduler.LambdaLR(optimizer, lr_schedule)

    # ── Training ──────────────────────────────────────────────────────
    banner("TRAINING")

    model.train()
    train_losses = []
    eval_losses = []
    checkpoints_data = []

    for step in range(1, N_STEPS + 1):
        optimizer.zero_grad()
        accum_loss = 0

        for _ in range(GRAD_ACCUM):
            x, y = train_loader.next_batch()
            x, y = x.to(device), y.to(device)
            _, loss = model(x, y)
            (loss / GRAD_ACCUM).backward()
            accum_loss += loss.item() / GRAD_ACCUM

        torch.nn.utils.clip_grad_norm_(model.parameters(), 1.0)
        optimizer.step()
        scheduler.step()
        train_losses.append(accum_loss)

        if step % LOG_INTERVAL == 0:
            elapsed = time.time() - start
            tps = step * BATCH_SIZE * GRAD_ACCUM * SEQ_LEN / elapsed
            reg_norm = model.register_init.data.norm().item()
            print(
                f"  step {step:5d}/{N_STEPS}  "
                f"loss={accum_loss:.4f}  "
                f"lr={scheduler.get_last_lr()[0]:.2e}  "
                f"reg={reg_norm:.4f}  "
                f"tok/s={tps:.0f}  "
                f"elapsed={elapsed:.0f}s",
                flush=True,
            )

        if step % EVAL_INTERVAL == 0:
            eval_loader.reset()
            el = estimate_loss(model, eval_loader, device)
            eval_losses.append({"step": step, "loss": el})
            print(f"  ── eval loss at step {step}: {el:.4f} ──", flush=True)

        if step % CHECKPOINT_INTERVAL == 0:
            # Gradient norms (including per-iteration gate heads)
            grad_norms = get_grad_norms(model)

            # Gate head divergence (are iter0/iter1 gates specializing?)
            gate_div = measure_gate_divergence(model)

            # Full dynamics
            eval_loader.reset()
            dynamics = measure_dynamics(model, eval_loader, device)

            # Compile gate
            compile = compile_gate_test(model, tokenizer, device)

            ckpt_info = {
                "step": step,
                "train_loss": accum_loss,
                "eval_loss": eval_losses[-1]["loss"] if eval_losses else None,
                "grad_norms": grad_norms,
                "gate_divergence": gate_div,
                "dynamics": dynamics,
                "compile_gate": compile["score"],
            }
            checkpoints_data.append(ckpt_info)

            # Print summary
            print(f"  ── checkpoint {step} ──")
            print(f"     grad norms: {json.dumps({k: round(v, 4) for k, v in grad_norms.items()})}")
            print(f"     expansion: {dynamics['overall_expansion']:.2f}x")

            # Per-iteration S4 entropy
            for it in range(N_ITERATIONS):
                s4_key = f"iter{it}_s4_attn_entropy"
                if s4_key in dynamics:
                    print(f"     iter{it} S4 entropy: {dynamics[s4_key]:.4f}")

            # Register trajectory (per-iteration S4 scans)
            reg_parts = [f"init={dynamics['register_init_norm']:.4f}"]
            for it in range(N_ITERATIONS):
                s4_key = f"iter{it}_register_after_s4"
                if s4_key in dynamics:
                    reg_parts.append(f"S4.{it}={dynamics[s4_key]:.4f}")
                reg_parts.append(f"iter{it}={dynamics[f'iter{it}_register_norm']:.4f}")
            print(f"     register: {' → '.join(reg_parts)}")

            # Gate summary (per-iteration — now with separate heads)
            for it in range(N_ITERATIONS):
                gate_str = "  ".join(
                    f"{name}={dynamics[f'iter{it}_{name}_gate_mean']:.3f}"
                    f"±{dynamics[f'iter{it}_{name}_gate_std']:.3f}"
                    for name in model.phase_names
                )
                print(f"     iter{it} gates: {gate_str}")

            # Gating ratio (gated_norm / delta_norm)
            for it in range(N_ITERATIONS):
                ratio_str = "  ".join(
                    f"{name}={dynamics[f'iter{it}_{name}_gated_norm'] / max(dynamics[f'iter{it}_{name}_delta_norm'], 1e-8):.3f}"
                    for name in model.phase_names
                )
                print(f"     iter{it} throughput: {ratio_str}")

            # Gate head divergence (key v2 metric)
            div_str = "  ".join(
                f"{name}={gate_div[f'gate_cosine_{name}']:.3f}"
                for name in model.phase_names
            )
            print(f"     gate divergence (cosine iter0↔iter1): {div_str}")
            print(f"     compile gate: {compile['score']}")

            # Save checkpoint
            ckpt_path = checkpoint_dir / f"step_{step:06d}.pt"
            torch.save({
                "step": step,
                "model_state_dict": model.state_dict(),
                "optimizer_state_dict": optimizer.state_dict(),
                "loss": accum_loss,
                "dynamics": dynamics,
                "grad_norms": grad_norms,
                "gate_divergence": gate_div,
                "compile_gate": compile["score"],
                "compile_gate_results": compile["results"],
                "train_losses": train_losses[:],
                "eval_losses": eval_losses[:],
            }, ckpt_path)
            print(f"     saved: {ckpt_path}", flush=True)

            model.train()

    # ── Summary ───────────────────────────────────────────────────────
    elapsed = time.time() - start
    banner(f"DONE — {elapsed:.0f}s ({elapsed / 3600:.1f}h)")

    summary = {
        "timestamp": datetime.now(UTC).isoformat(),
        "elapsed_s": elapsed,
        "architecture": "VSM-LM-v2 (two-channel compressor)",
        "strides": list(STRIDES),
        "n_iterations": N_ITERATIONS,
        "s4_mode": "per-iteration",
        "s3_mode": "per-dimension, per-iteration gates",
        "s1_order": "fine_to_coarse",
        "v2_changes": [
            "per-iteration gate heads (6 instead of 3)",
            "S4 per-iteration (scans enriched residual before iter1)",
        ],
        "params": params,
        "n_steps": N_STEPS,
        "seed": SEED,
        "train_losses": train_losses,
        "eval_losses": eval_losses,
        "checkpoints": checkpoints_data,
    }
    summary_path = results_dir / "summary.json"
    summary_path.write_text(json.dumps(summary, indent=2))
    print(f"  Saved: {summary_path}")

    # Comparison
    print()
    print("  Reference:")
    print("    Forward CompressorLM:  best eval 5.043 @ step 9500")
    print("    Reverse CompressorLM:  best eval 5.342 @ step 9500")
    print()
    if eval_losses:
        best = min(eval_losses, key=lambda e: e["loss"])
        last_dyn = checkpoints_data[-1]["dynamics"] if checkpoints_data else {}
        print(f"  This run (VSM-LM-v2):")
        print(f"    Best eval: {best['loss']:.3f} @ step {best['step']}")
        print(f"    Overall expansion: {last_dyn.get('overall_expansion', '?')}x")
        print(f"    S4 entropy: {last_dyn.get('s4_attn_entropy', '?')}")
        if last_dyn:
            for it in range(N_ITERATIONS):
                gate_str = ", ".join(
                    f"{name}={last_dyn.get(f'iter{it}_{name}_gate_mean', 0):.3f}"
                    for name in model.phase_names
                )
                print(f"    iter{it} gates: {gate_str}")


if __name__ == "__main__":
    main()
