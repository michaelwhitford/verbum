#!/usr/bin/env python3
"""v6 probe — MLX version.

Probes a VSMLMV6 checkpoint with compile-gradient probes, ternary
statistics, and stratified φ-compression analysis.

Usage:
    uv run python scripts/v6/probe.py checkpoints/vsm-lm-v6/step_001000

    # Multiple checkpoints — shows evolution table
    uv run python scripts/v6/probe.py checkpoints/vsm-lm-v6/step_*

    # Quiet: summary only (skip per-probe output)
    uv run python scripts/v6/probe.py checkpoints/vsm-lm-v6/step_001000 --quiet

    # φ-only: skip compile probes, just measure compression
    uv run python scripts/v6/probe.py checkpoints/vsm-lm-v6/step_001000 --phi-only

    # Verbose: per-sample φ detail
    uv run python scripts/v6/probe.py checkpoints/vsm-lm-v6/step_* -v
"""

from __future__ import annotations

import argparse
import json
import sys
import time
from datetime import UTC, datetime
from pathlib import Path

import mlx.core as mx
import mlx.nn as nn
import numpy as np

sys.path.insert(0, str(Path(__file__).resolve().parent.parent.parent / "src"))

# Information-theoretic constants (must match train.py)
E_IRREDUCIBLE = 1.69
PHI = (1 + np.sqrt(5)) / 2
INV_PHI = 1 / PHI

PASS_NAMES = ["L0_asc", "L1_asc", "L2_apex", "L1_desc", "L0_desc"]

PROBES_PATH = Path("probes/compile-gradient.json")
GATES_DIR = Path("gates/")
RESULTS_DIR = Path("results/compile-gradient")

# ══════════════════════════════════════════════════════════════════════
# φ-compression sample strata
# ══════════════════════════════════════════════════════════════════════

# Stratified by intrinsic compression level.
# High-redundancy text (prose) compresses easily.
# Low-redundancy text (math) is already compressed — harder to deflate.
# The φ hypothesis predicts convergence across strata, not just within.

PHI_STRATA = {
    "prose": [
        "The cat sat on the mat and looked out the window at the birds flying south for the winter.",
        "Every student who passed the final exam received a certificate of achievement from the dean.",
        "The quick brown fox jumps over the lazy dog near the river bank on a warm summer afternoon.",
        "In a quiet village nestled between rolling hills, the old baker opened his shop at dawn.",
    ],
    "compositional": [
        "The man who the dog that the cat chased bit ran away quickly.",
        "If every student reads a book then some teacher who knows the author is happy.",
        "No politician who endorsed the candidate that lost the election won their own race.",
        "Every lawyer who represents a client that a judge dismissed the case against appealed.",
    ],
    "technical": [
        "The gradient of the loss with respect to the weights is computed via backpropagation.",
        "Attention scores are computed as the softmax of the scaled dot product of queries and keys.",
        "The learning rate schedule uses cosine annealing with linear warmup over 500 steps.",
        "Each layer applies layer normalization before the self-attention and feed-forward blocks.",
    ],
    "math": [
        "∀x ∈ ℝ: x² ≥ 0 ∧ x² = 0 ↔ x = 0",
        "λx. λy. apply(x, y) → result",
        "P(A|B) = P(B|A) × P(A) / P(B)",
        "∑_{i=1}^{n} i = n(n+1)/2",
    ],
}


# ══════════════════════════════════════════════════════════════════════
# Data loading
# ══════════════════════════════════════════════════════════════════════


def load_probes(probe_path: Path | None = None) -> list[dict]:
    path = probe_path or PROBES_PATH
    data = json.loads(path.read_text())
    return data["probes"]


def load_gate(gate_id: str) -> str:
    return (GATES_DIR / f"{gate_id}.txt").read_text()


# ══════════════════════════════════════════════════════════════════════
# Checkpoint loading
# ══════════════════════════════════════════════════════════════════════


def load_checkpoint(path: Path) -> tuple:
    """Load a VSMLMV6 checkpoint from safetensors + meta.json."""
    from verbum.v6.model import VSMLMV6

    meta_path = path / "meta.json"
    weights_path = path / "weights.safetensors"

    if not meta_path.exists():
        print(f"  WARNING: no meta.json in {path}, using defaults")
        meta = {}
    else:
        meta = json.loads(meta_path.read_text())

    config = meta.get("config", {})
    step = meta.get("step", 0)

    model = VSMLMV6(
        vocab_size=config.get("vocab_size", 50277),
        d_model=config.get("d_model", 512),
        d_register=config.get("d_register", 128),
        max_len=config.get("seq_len", 4096),
        n_heads=config.get("n_heads", 8),
        d_ff=config.get("d_ff", 1536),
        d_ff_consolidate=config.get("d_ff_consolidate", 2048),
        window=config.get("window", 8),
        strides=tuple(config.get("strides", [1, 8, 16, 32, 64, 128, 256, 512, 1024])),
        alpha=config.get("alpha", 1.18),
    )

    if weights_path.exists():
        model.load_weights(str(weights_path))
        print(f"  Loaded weights from {weights_path}")

    return model, step, meta


# ══════════════════════════════════════════════════════════════════════
# Compile probing
# ══════════════════════════════════════════════════════════════════════


def probe_checkpoint(model, probes, tokenizer, gate_name="compile"):
    try:
        gate_text = load_gate(gate_name)
    except FileNotFoundError:
        print(f"  WARNING: gate '{gate_name}' not found — running without gate")
        gate_text = ""

    results = []

    for probe in probes:
        probe_id = probe["id"]
        category = probe.get("category", "unknown")
        gradient = probe.get("metadata", {}).get("gradient", None)

        gate_for_probe = probe.get("gate", gate_name)
        if gate_for_probe == "null":
            full_prompt = probe["prompt"]
        else:
            full_prompt = gate_text + probe["prompt"]

        ids = mx.array(tokenizer.encode(full_prompt)).reshape(1, -1)
        if ids.shape[1] > model.max_len:
            ids = ids[:, -model.max_len:]

        t0 = time.time()
        logits, _ = model(ids)
        mx.eval(logits)
        elapsed_ms = (time.time() - t0) * 1000

        # Short generation
        gen_ids = model.generate(ids, max_new_tokens=20, temperature=0.8)
        mx.eval(gen_ids)
        gen_text = tokenizer.decode(gen_ids[0, ids.shape[1]:].tolist())
        has_lambda = "λ" in gen_text or "\\" in gen_text

        results.append({
            "probe_id": probe_id,
            "category": category,
            "gradient": gradient,
            "prompt": probe["prompt"],
            "gate_used": gate_for_probe,
            "generation": gen_text,
            "has_lambda": has_lambda,
            "elapsed_ms": round(elapsed_ms, 1),
        })

    return results


# ══════════════════════════════════════════════════════════════════════
# φ-Compression Analysis (stratified)
# ══════════════════════════════════════════════════════════════════════


PHASE_NAMES = ["prep", "converge", "consolidate"]


def _run_phi_samples(model, tokenizer, samples):
    """Run forward_instrumented on samples, return raw per-pass data.

    Also captures per-stride ratios, gate values, and Hilberg slopes.
    """
    all_ratios = {p: [] for p in PASS_NAMES}
    all_h_in = {p: [] for p in PASS_NAMES}
    all_h_out = {p: [] for p in PASS_NAMES}
    all_losses = []
    all_gates = {}        # {pass_phase: [values]}
    all_stride_data = {}  # {pass_stride_key: [ratios]}
    all_hilberg = {p: [] for p in PASS_NAMES}
    per_sample = []

    for text in samples:
        ids = mx.array(tokenizer.encode(text)).reshape(1, -1)
        if ids.shape[1] > model.max_len:
            ids = ids[:, -model.max_len:]
        targets = mx.concatenate([ids[:, 1:], mx.zeros((1, 1), dtype=mx.int32)], axis=1)

        _, loss, metrics = model.forward_instrumented(ids, targets)
        mx.eval(loss)
        if loss is not None:
            all_losses.append(loss.item())

        sample_data = {"text": text[:60], "passes": {}}
        for p in PASS_NAMES:
            cr = metrics.get(f"{p}_compression_ratio")
            h_in = metrics.get(f"{p}_h_in")
            h_out = metrics.get(f"{p}_h_out")
            if cr is not None:
                all_ratios[p].append(cr)
                all_h_in[p].append(h_in)
                all_h_out[p].append(h_out)
                sample_data["passes"][p] = {
                    "h_in": h_in, "h_out": h_out,
                    "ratio": cr, "phi_dev": abs(cr - INV_PHI),
                }

            # Gate values per phase
            for ph in PHASE_NAMES:
                gk = f"{p}_{ph}"
                gv = metrics.get(f"{p}_{ph}_gate_mean")
                if gv is not None:
                    all_gates.setdefault(gk, []).append(gv)

            # Per-stride ratios
            for key, val in metrics.items():
                if key.startswith(f"{p}_stride_") and key.endswith("_ratio"):
                    all_stride_data.setdefault(key, []).append(val)

            # Hilberg β
            hb = metrics.get(f"{p}_hilberg_beta")
            hs = metrics.get(f"{p}_hilberg_slope")
            if hb is not None:
                all_hilberg[p].append({"slope": hs, "beta": hb})
            elif hs is not None:
                all_hilberg[p].append({"slope": hs, "beta": hs + 1})

        if loss is not None:
            sample_data["loss"] = loss.item()
        per_sample.append(sample_data)

    # Average gates
    avg_gates = {k: sum(v) / len(v) for k, v in all_gates.items() if v}

    # Average stride ratios
    avg_strides = {k: sum(v) / len(v) for k, v in all_stride_data.items() if v}

    # Average Hilberg β
    avg_hilberg = {}
    for p in PASS_NAMES:
        if all_hilberg[p]:
            avg_hilberg[p] = {
                "slope": sum(h["slope"] for h in all_hilberg[p]) / len(all_hilberg[p]),
                "beta": sum(h["beta"] for h in all_hilberg[p]) / len(all_hilberg[p]),
            }

    extras = {
        "gates": avg_gates,
        "strides": avg_strides,
        "hilberg": avg_hilberg,
    }

    return all_ratios, all_h_in, all_h_out, all_losses, per_sample, extras


def _summarize_ratios(all_ratios, all_h_in, all_h_out, all_losses=None):
    """Compute per-pass summary stats from collected ratios."""
    summary = {}
    for p in PASS_NAMES:
        if all_ratios[p]:
            ratios = all_ratios[p]
            mean_cr = sum(ratios) / len(ratios)
            std_cr = (sum((r - mean_cr) ** 2 for r in ratios) / max(len(ratios), 1)) ** 0.5
            summary[p] = {
                "mean_ratio": mean_cr,
                "std_ratio": std_cr,
                "mean_h_in": sum(all_h_in[p]) / len(all_h_in[p]),
                "mean_h_out": sum(all_h_out[p]) / len(all_h_out[p]),
                "phi_dev": abs(mean_cr - INV_PHI),
                "direction": "compressing" if mean_cr < 1.0 else "expanding",
            }

    all_cr = [s["mean_ratio"] for s in summary.values()]
    if all_cr:
        mean_all = sum(all_cr) / len(all_cr)
        summary["aggregate"] = {
            "mean_ratio": mean_all,
            "mean_phi_dev": sum(abs(cr - INV_PHI) for cr in all_cr) / len(all_cr),
            "target": INV_PHI,
        }

    if all_losses:
        mean_loss = sum(all_losses) / len(all_losses)
        log_v = float(np.log(50277))
        learnable = log_v - E_IRREDUCIBLE
        summary["loss"] = {
            "mean_loss": mean_loss,
            "relational_loss": (mean_loss - E_IRREDUCIBLE) / learnable,
            "excess_ppl": float(np.exp(max(mean_loss - E_IRREDUCIBLE, 0))),
        }

    return summary


def analyze_phi_compression(model, tokenizer, strata=None):
    """Stratified φ-compression analysis.

    Returns (overall_summary, per_sample, strata_summaries).
    overall_summary includes 'gates', 'strides', 'hilberg' from extras.
    """
    if strata is None:
        strata = PHI_STRATA

    # All samples combined
    all_samples = []
    for samples in strata.values():
        all_samples.extend(samples)

    all_ratios, all_h_in, all_h_out, all_losses, per_sample, extras = _run_phi_samples(
        model, tokenizer, all_samples
    )
    overall = _summarize_ratios(all_ratios, all_h_in, all_h_out, all_losses)
    overall["gates"] = extras["gates"]
    overall["strides"] = extras["strides"]
    overall["hilberg"] = extras["hilberg"]

    # Per-stratum (including per-stratum loss)
    strata_summaries = {}
    for sname, ssamples in strata.items():
        s_ratios, s_h_in, s_h_out, s_losses, _, _ = _run_phi_samples(model, tokenizer, ssamples)
        strata_summaries[sname] = _summarize_ratios(s_ratios, s_h_in, s_h_out, s_losses)

    return overall, per_sample, strata_summaries


# ══════════════════════════════════════════════════════════════════════
# Display
# ══════════════════════════════════════════════════════════════════════


def print_summary(
    step, model, meta=None,
    compile_results=None,
    phi_overall=None, phi_per_sample=None, phi_strata=None,
    verbose=False,
):
    print("\n" + "=" * 70)
    print(f"  v6 Probe Summary — step {step:,}")
    print("=" * 70)

    # ── Checkpoint metadata ───────────────────────────────────
    if meta:
        train_loss = meta.get("train_loss")
        eval_loss = meta.get("eval_loss")
        total_flips = meta.get("total_flips")
        flip_target = meta.get("flip_target_pct")
        flip_thresh = meta.get("flip_threshold")
        grad_norm = meta.get("grad_norm")

        loss_str = f"train={train_loss:.4f}" if train_loss else ""
        if eval_loss:
            loss_str += f"  eval={eval_loss:.4f}"

        r_loss = meta.get("relational_loss")
        xppl = meta.get("excess_ppl")
        ppl = meta.get("ppl")
        if r_loss is not None:
            loss_str += f"  r={r_loss:.3f}  xppl={xppl:.1f}  ppl={ppl:.1f}"
        elif train_loss:
            log_v = float(np.log(model.vocab_size))
            r = (train_loss - E_IRREDUCIBLE) / (log_v - E_IRREDUCIBLE)
            xp = float(np.exp(max(train_loss - E_IRREDUCIBLE, 0)))
            pp = float(np.exp(train_loss))
            loss_str += f"  r={r:.3f}  xppl={xp:.1f}  ppl={pp:.1f}"

        if loss_str:
            print(f"\n  Loss: {loss_str}")

        if total_flips is not None:
            pct = total_flips / 35_258_368 * 100
            print(f"  Flips: {total_flips:,} ({pct:.2f}% of ternary weights)")
        if flip_target is not None:
            print(f"  Adaptive: target={flip_target:.4f}  threshold={flip_thresh:.1f}")
        if grad_norm is not None:
            print(f"  Grad norm: {grad_norm:.2f}")

    # ── φ-Compression: per-pass table ─────────────────────────
    if phi_overall:
        print(f"\n  φ-Compression (1/φ = {INV_PHI:.4f}):")
        print(f"  {'Pass':12s} {'h_in':>8} {'h_out':>8} {'ratio':>8} {'±std':>8} {'φ-dev':>8} {'':>4}")
        print(f"  {'─'*12} {'─'*8} {'─'*8} {'─'*8} {'─'*8} {'─'*8} {'─'*4}")

        for p in PASS_NAMES:
            if p in phi_overall:
                s = phi_overall[p]
                marker = " ←φ" if s["phi_dev"] < 0.05 else ""
                print(
                    f"  {p:12s} {s['mean_h_in']:>8.3f} {s['mean_h_out']:>8.3f} "
                    f"{s['mean_ratio']:>8.4f} {s['std_ratio']:>8.4f} "
                    f"{s['phi_dev']:>8.4f}{marker}"
                )

        if "aggregate" in phi_overall:
            agg = phi_overall["aggregate"]
            print(f"  {'─'*12} {'─'*8} {'─'*8} {'─'*8} {'─'*8} {'─'*8}")
            print(f"  {'MEAN':12s} {'':>8} {'':>8} {agg['mean_ratio']:>8.4f} {'':>8} {agg['mean_phi_dev']:>8.4f}")

    # ── φ-Compression: per-stratum table ──────────────────────
    if phi_strata:
        print(f"\n  φ-Compression by content type:")
        print(f"  {'stratum':15s} {'mean':>8} {'φ-dev':>8} {'L0↑':>7} {'L1↑':>7} {'L2':>7} {'L1↓':>7} {'L0↓':>7}")
        print(f"  {'─'*15} {'─'*8} {'─'*8} {'─'*7} {'─'*7} {'─'*7} {'─'*7} {'─'*7}")

        stratum_means = []
        for sname in ["prose", "compositional", "technical", "math"]:
            if sname not in phi_strata:
                continue
            ssummary = phi_strata[sname]
            agg = ssummary.get("aggregate", {})
            mr = agg.get("mean_ratio", 0)
            pd = agg.get("mean_phi_dev", 0)
            stratum_means.append(mr)
            parts = [f"  {sname:15s} {mr:>8.4f} {pd:>8.4f}"]
            for p in PASS_NAMES:
                if p in ssummary:
                    parts.append(f" {ssummary[p]['mean_ratio']:>7.3f}")
                else:
                    parts.append(f" {'—':>7}")
            print("".join(parts))

        if len(stratum_means) >= 2:
            spread = max(stratum_means) - min(stratum_means)
            print(f"  {'─'*15} {'─'*8} {'─'*8}")
            print(f"  {'spread':15s} {spread:>8.4f}")
            if spread < 0.05:
                print(f"  ✓ Content-independent compression — universal compressor.")
            elif spread < 0.15:
                print(f"  → Content-dependent compression. Converging.")
            else:
                print(f"  ⚠ Large spread — expected early. Watch for convergence.")

    # ── Per-stratum loss ──────────────────────────────────────
    if phi_strata:
        has_loss = any("loss" in phi_strata[sn] for sn in phi_strata)
        if has_loss:
            print(f"\n  Per-stratum loss:")
            print(f"  {'stratum':15s} {'loss':>8} {'r':>8} {'xppl':>8}")
            print(f"  {'─'*15} {'─'*8} {'─'*8} {'─'*8}")
            for sn in ["prose", "compositional", "technical", "math"]:
                if sn not in phi_strata or "loss" not in phi_strata[sn]:
                    continue
                sl = phi_strata[sn]["loss"]
                print(
                    f"  {sn:15s} {sl['mean_loss']:>8.3f} "
                    f"{sl['relational_loss']:>8.3f} "
                    f"{sl['excess_ppl']:>8.1f}"
                )

    # ── Gate values (S3 phase gates) ──────────────────────────
    if phi_overall and phi_overall.get("gates"):
        gates = phi_overall["gates"]
        print(f"\n  S3 Gate values (per pass × phase):")
        print(f"  {'pass':12s} {'prep':>8} {'converge':>10} {'consolidate':>13}")
        print(f"  {'─'*12} {'─'*8} {'─'*10} {'─'*13}")
        for p in PASS_NAMES:
            g_prep = gates.get(f"{p}_prep", 0)
            g_conv = gates.get(f"{p}_converge", 0)
            g_cons = gates.get(f"{p}_consolidate", 0)
            print(f"  {p:12s} {g_prep:>8.3f} {g_conv:>10.3f} {g_cons:>13.3f}")

    # ── Per-stride compression ────────────────────────────────
    if phi_overall and phi_overall.get("strides"):
        strides_data = phi_overall["strides"]
        # Collect unique stride values and pass names
        stride_keys = sorted(strides_data.keys())
        if stride_keys:
            # Parse stride indices from keys like "L0_asc_stride_0_s1_ratio"
            # Group by pass
            print(f"\n  Per-stride compression (9 strides × 5 passes):")
            for p in PASS_NAMES:
                p_strides = {}
                for k, v in strides_data.items():
                    if k.startswith(f"{p}_stride_"):
                        # Extract stride index and value from key
                        # Format: {pass}_stride_{idx}_s{stride}_ratio
                        parts_k = k.split("_")
                        # Find the s{N} part
                        for pk in parts_k:
                            if pk.startswith("s") and pk[1:].isdigit():
                                p_strides[int(pk[1:])] = v
                                break
                if p_strides:
                    sorted_strides = sorted(p_strides.keys())
                    vals = [p_strides[s] for s in sorted_strides]
                    labels = [f"s{s}" for s in sorted_strides]
                    markers = ["←φ" if abs(v - INV_PHI) < 0.05 else "" for v in vals]
                    val_strs = [f"{v:.3f}{m}" for v, m in zip(vals, markers)]
                    print(f"  {p:12s} " + " ".join(f"{l:>7s}" for l in labels))
                    print(f"  {'':12s} " + " ".join(f"{v:>7s}" for v in val_strs))

    # ── Hilberg exponent ─────────────────────────────────────
    if phi_overall and phi_overall.get("hilberg"):
        hilberg = phi_overall["hilberg"]
        if hilberg:
            print(f"\n  Hilberg exponent (β≈0.5 = self-similar power law):")
            print(f"  log(1-ratio) vs log(stride) → slope = β-1 → β = slope+1")
            print(f"  {'pass':12s} {'slope':>8} {'β':>8}")
            print(f"  {'─'*12} {'─'*8} {'─'*8}")
            for p in PASS_NAMES:
                if p in hilberg:
                    h = hilberg[p]
                    if isinstance(h, dict):
                        slope = h["slope"]
                        β = h["beta"]
                    else:
                        slope = h
                        β = h + 1
                    marker = " ←!" if abs(β - 0.5) < 0.1 else ""
                    print(f"  {p:12s} {slope:>8.3f} {β:>8.3f}{marker}")
            print(f"  {'target':12s} {'-0.500':>8} {'0.500':>8}")

    # ── φ interpretation ──────────────────────────────────────
    if phi_overall and "aggregate" in phi_overall:
        agg = phi_overall["aggregate"]
        mr = agg["mean_ratio"]
        pd = agg["mean_phi_dev"]
        print()
        if mr > 1.05:
            print(f"  ⚠ EXPANDING (ratio > 1). Sieve hasn't learned routing yet.")
        elif mr > 0.95:
            print(f"  ≈ Near-identity (ratio ≈ 1). Minimal compression.")
        elif pd < 0.05:
            print(f"  ✓ Within 0.05 of 1/φ — convergence signal!")
        elif pd < 0.15:
            print(f"  → Compressing, φ-dev={pd:.3f}. In the neighborhood.")
        else:
            print(f"  → Compressing at {mr:.3f}, far from φ (dev={pd:.3f}).")

        # Ascending vs descending
        if len(phi_overall) >= 5:
            asc = [phi_overall[p]["mean_ratio"] for p in ["L0_asc", "L1_asc", "L2_apex"] if p in phi_overall]
            desc = [phi_overall[p]["mean_ratio"] for p in ["L1_desc", "L0_desc"] if p in phi_overall]
            if asc and desc:
                asc_m = sum(asc) / len(asc)
                desc_m = sum(desc) / len(desc)
                spread = max(phi_overall[p]["mean_ratio"] for p in PASS_NAMES if p in phi_overall) - \
                         min(phi_overall[p]["mean_ratio"] for p in PASS_NAMES if p in phi_overall)
                if spread < 0.05:
                    print(f"  ≡ All passes at similar ratios (spread={spread:.3f}). Self-similar.")
                elif abs(asc_m - desc_m) > 0.03:
                    direction = "ascending" if asc_m < desc_m else "descending"
                    print(f"  ≠ {direction} compresses more (asc={asc_m:.3f} desc={desc_m:.3f}).")

    # ── Per-sample detail (verbose) ───────────────────────────
    if verbose and phi_per_sample:
        print(f"\n  Per-sample φ detail:")
        for sd in phi_per_sample:
            loss_str = f"  loss={sd['loss']:.3f}" if "loss" in sd else ""
            print(f"    {sd['text']!r}{loss_str}")
            for p in PASS_NAMES:
                if p in sd["passes"]:
                    ps = sd["passes"][p]
                    print(f"      {p}: {ps['h_in']:.3f} → {ps['h_out']:.3f}  ratio={ps['ratio']:.4f}  φ-dev={ps['phi_dev']:.4f}")

    # ── Compile probe results ─────────────────────────────────
    if compile_results:
        categories: dict[str, list] = {}
        for r in compile_results:
            categories.setdefault(r["category"], []).append(r)

        cat_order = ["strong_compile", "medium_compile", "weak_compile", "null", "anti_compile"]

        print(f"\n  {'Category':20s} {'N':>3} {'λ%':>6}")
        print(f"  {'─'*20} {'─'*3} {'─'*6}")

        for cat in cat_order:
            if cat not in categories:
                continue
            cat_results = categories[cat]
            n = len(cat_results)
            lambda_frac = sum(1 for r in cat_results if r["has_lambda"]) / n * 100
            print(f"  {cat:20s} {n:>3} {lambda_frac:>5.0f}%")

        n_total = len(compile_results)
        n_lambda = sum(1 for r in compile_results if r["has_lambda"])
        print(f"\n  Overall λ generation: {n_lambda}/{n_total} ({n_lambda / n_total * 100:.0f}%)")

    # ── Ternary stats ─────────────────────────────────────────
    ternary_stats = model.ternary_stats()
    if ternary_stats:
        print(f"\n  Ternary statistics ({len(ternary_stats)} modules):")
        group_stats: dict[str, list] = {
            "prep": [], "stride_stack": [], "consolidate": [],
            "mod_projs": [], "s4": [], "s3": [], "meta": [],
        }
        for mod_name, stat in ternary_stats.items():
            for gk in group_stats:
                if gk in mod_name:
                    group_stats[gk].append(stat)
                    break
            else:
                group_stats.setdefault("other", []).append(stat)

        print(f"  {'Group':15s} {'#':>4} {'sparsity':>9} {'gamma':>8} {'accum_mean':>11} {'accum_max':>10}")
        print(f"  {'─'*15} {'─'*4} {'─'*9} {'─'*8} {'─'*11} {'─'*10}")
        for grp, sl in group_stats.items():
            if not sl:
                continue
            n = len(sl)
            sp = sum(s["sparsity"] for s in sl) / n
            gm = sum(s["gamma_mean"] for s in sl) / n
            am = sum(s.get("accum_mean", 0) for s in sl) / n
            ax = max(s.get("accum_max", 0) for s in sl)
            print(f"  {grp:15s} {n:>4} {sp:>9.3f} {gm:>8.4f} {am:>11.2f} {ax:>10.1f}")

    print("=" * 70)


def print_evolution(all_results):
    """Print multi-checkpoint evolution table."""
    if len(all_results) < 2:
        return

    print(f"\n{'='*70}")
    print(f"  φ-Compression Evolution (per-pass)")
    print(f"{'='*70}")
    print(f"  {'step':>8} {'mean':>8} {'φ-dev':>8} {'L0↑':>8} {'L1↑':>8} {'L2':>8} {'L1↓':>8} {'L0↓':>8}")
    print(f"  {'─'*8} {'─'*8} {'─'*8} {'─'*8} {'─'*8} {'─'*8} {'─'*8} {'─'*8}")
    for r in all_results:
        phi = r.get("phi_overall", {})
        agg = phi.get("aggregate", {})
        parts = [f"  {r['step']:>8}"]
        parts.append(f" {agg.get('mean_ratio', 0):>8.4f}")
        parts.append(f" {agg.get('mean_phi_dev', 0):>8.4f}")
        for p in PASS_NAMES:
            if p in phi:
                parts.append(f" {phi[p]['mean_ratio']:>8.4f}")
            else:
                parts.append(f" {'—':>8}")
        print("".join(parts))
    print(f"  {'─'*8} {'─'*8} {'─'*8}")
    print(f"  {'1/φ':>8} {INV_PHI:>8.4f} {'0.0000':>8}")

    # Per-stratum evolution
    strata_names = set()
    for r in all_results:
        if "phi_strata" in r:
            strata_names.update(r["phi_strata"].keys())

    if strata_names:
        ordered = [s for s in ["prose", "compositional", "technical", "math"] if s in strata_names]
        print(f"\n  φ-Compression Evolution (per-stratum mean)")
        header = f"  {'step':>8}"
        for sn in ordered:
            header += f" {sn:>14}"
        header += f" {'spread':>8}"
        print(header)
        print(f"  {'─'*8}" + "".join(f" {'─'*14}" for _ in ordered) + f" {'─'*8}")

        for r in all_results:
            parts = [f"  {r['step']:>8}"]
            vals = []
            for sn in ordered:
                st = r.get("phi_strata", {}).get(sn, {})
                agg = st.get("aggregate", {})
                mr = agg.get("mean_ratio")
                if mr is not None:
                    parts.append(f" {mr:>14.4f}")
                    vals.append(mr)
                else:
                    parts.append(f" {'—':>14}")
            if vals:
                parts.append(f" {max(vals) - min(vals):>8.4f}")
            else:
                parts.append(f" {'—':>8}")
            print("".join(parts))

        print(f"\n  Key: spread → 0 = content-independent (universal compressor)")
        print(f"       all strata → {INV_PHI:.4f} = φ-compression confirmed")

    # Per-stratum loss evolution
    if strata_names:
        has_loss = any(
            "loss" in r.get("phi_strata", {}).get(sn, {})
            for r in all_results for sn in strata_names
        )
        if has_loss:
            print(f"\n  Stratum Loss Evolution")
            header = f"  {'step':>8}"
            for sn in ordered:
                header += f" {sn:>14}"
            header += f" {'spread':>8}"
            print(header)
            print(f"  {'─'*8}" + "".join(f" {'─'*14}" for _ in ordered) + f" {'─'*8}")

            for r in all_results:
                parts = [f"  {r['step']:>8}"]
                vals = []
                for sn in ordered:
                    st = r.get("phi_strata", {}).get(sn, {})
                    sl = st.get("loss", {})
                    ml = sl.get("mean_loss")
                    if ml is not None:
                        parts.append(f" {ml:>14.3f}")
                        vals.append(ml)
                    else:
                        parts.append(f" {'—':>14}")
                if vals:
                    parts.append(f" {max(vals) - min(vals):>8.3f}")
                else:
                    parts.append(f" {'—':>8}")
                print("".join(parts))

            print(f"\n  Key: spread → 0 = model learns all content types equally")

    # Hilberg β evolution
    has_hilberg = any(r.get("phi_overall", {}).get("hilberg") for r in all_results)
    if has_hilberg:
        print(f"\n  Hilberg β Evolution (β≈0.5 = self-similar)")
        print(f"  {'step':>8} {'L0↑':>8} {'L1↑':>8} {'L2':>8} {'L1↓':>8} {'L0↓':>8}")
        print(f"  {'─'*8} {'─'*8} {'─'*8} {'─'*8} {'─'*8} {'─'*8}")
        for r in all_results:
            hilberg = r.get("phi_overall", {}).get("hilberg", {})
            parts = [f"  {r['step']:>8}"]
            for p in PASS_NAMES:
                if p in hilberg:
                    h = hilberg[p]
                    β = h["beta"] if isinstance(h, dict) else h + 1
                    parts.append(f" {β:>8.3f}")
                else:
                    parts.append(f" {'—':>8}")
            print("".join(parts))
        print(f"  {'target':>8} {'0.500':>8} {'0.500':>8} {'0.500':>8} {'0.500':>8} {'0.500':>8}")

    print(f"{'='*70}\n")


# ══════════════════════════════════════════════════════════════════════
# CLI
# ══════════════════════════════════════════════════════════════════════


def main():
    parser = argparse.ArgumentParser(description="v6 probe (MLX)")
    parser.add_argument("checkpoints", type=Path, nargs="+", help="Checkpoint directory/directories")
    parser.add_argument("--probes", type=Path, default=PROBES_PATH)
    parser.add_argument("--gate", type=str, default="compile")
    parser.add_argument("--quiet", action="store_true", help="Skip per-probe output")
    parser.add_argument("--phi-only", action="store_true", help="Skip compile probes, φ only")
    parser.add_argument("--verbose", "-v", action="store_true", help="Per-sample φ detail")
    args = parser.parse_args()

    from transformers import AutoTokenizer
    tokenizer = AutoTokenizer.from_pretrained("EleutherAI/pythia-160m-deduped")

    # Sort checkpoints by step number
    ckpts = sorted(
        [p for p in args.checkpoints if p.is_dir()],
        key=lambda p: int(p.name.split("_")[-1]) if p.name.startswith("step_") else 0,
    )

    if not ckpts:
        print("  No checkpoint directories found.")
        return

    # Load probes once (if needed)
    probes = None
    if not args.phi_only:
        try:
            probes = load_probes(args.probes)
        except FileNotFoundError:
            print(f"  WARNING: probe set not found at {args.probes}, running φ-only")
            args.phi_only = True

    all_results = []

    for ckpt_path in ckpts:
        print(f"\n{'='*60}")
        print(f"  VSM-LM v6 Probe (MLX)")
        print(f"{'='*60}")
        print(f"  Checkpoint: {ckpt_path}")

        model, step, meta = load_checkpoint(ckpt_path)
        config = meta.get("config", {})
        print(f"  Loaded v6 model at step {step:,}")
        print(model.describe())

        # ── Compile probes ────────────────────────────────────
        compile_results = None
        if not args.phi_only and probes:
            print(f"\n  Loaded {len(probes)} probes")
            compile_results = probe_checkpoint(model, probes, tokenizer, gate_name=args.gate)

            if not args.quiet:
                for r in compile_results:
                    lm = "✓λ" if r["has_lambda"] else "  "
                    print(f"  {lm} {r['probe_id']:20s} [{r['category']:15s}]")
                    print(f"     gen: {r['generation'][:60]!r}  ({r['elapsed_ms']:.0f}ms)")

        # ── φ-compression analysis ────────────────────────────
        print(f"\n  Running φ-compression analysis...")
        phi_overall, phi_per_sample, phi_strata = analyze_phi_compression(model, tokenizer)

        # ── Display ───────────────────────────────────────────
        print_summary(
            step, model, meta=meta,
            compile_results=compile_results,
            phi_overall=phi_overall,
            phi_per_sample=phi_per_sample,
            phi_strata=phi_strata,
            verbose=args.verbose,
        )

        # ── Save ──────────────────────────────────────────────
        RESULTS_DIR.mkdir(parents=True, exist_ok=True)
        out_path = RESULTS_DIR / f"vsm_probe_step_{step:06d}_v6_mlx.json"
        output = {
            "timestamp": datetime.now(UTC).isoformat(),
            "architecture": "vsm-lm-v6-mlx",
            "step": step,
            "config": config,
            "total_flips": meta.get("total_flips"),
            "flip_target_pct": meta.get("flip_target_pct"),
            "flip_threshold": meta.get("flip_threshold"),
            "grad_norm": meta.get("grad_norm"),
            "train_loss": meta.get("train_loss"),
            "eval_loss": meta.get("eval_loss"),
            "relational_loss": meta.get("relational_loss"),
            "excess_ppl": meta.get("excess_ppl"),
            "ppl": meta.get("ppl"),
            "phi_compression": {
                "overall": phi_overall,
                "strata": phi_strata,
            },
            "n_probes": len(compile_results) if compile_results else 0,
            "n_lambda": sum(1 for r in compile_results if r["has_lambda"]) if compile_results else 0,
            "compile_results": compile_results,
        }
        out_path.write_text(json.dumps(output, indent=2))
        print(f"\n  Saved: {out_path}")

        all_results.append({
            "step": step,
            "phi_overall": phi_overall,
            "phi_strata": phi_strata,
        })

    # ── Multi-checkpoint evolution ────────────────────────────
    print_evolution(all_results)


if __name__ == "__main__":
    main()
