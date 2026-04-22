"""VSM-LM v6 — Ternary Stacked Compressors on Metal (MLX).

Faithful port of the PyTorch v6 design to MLX with custom Metal
ternary matmul kernels. All projection weights use TernaryLinear
(add/sub only, no fp32 multiplies). Training uses flip accumulation.

See docs/v6-design.md for full architecture description.

License: MIT
"""

from __future__ import annotations

from typing import Optional

import mlx.core as mx
import mlx.nn as nn

from verbum.v6.ternary import TernaryLinear, TernaryFFN
from verbum.v6.attention import StrideStack
from verbum.v6.components import (
    S4Ternary,
    S3Ternary,
    MetaS4Ternary,
    MetaS3Ternary,
    _interleave_banks,
)


class VSMLMV6(nn.Module):
    """Viable System Model Language Model — v6, MLX + Metal.

    5-pass bidirectional VSM with ternary stacked compressors.
    All S1 operations run through custom Metal ternary matmul kernel.

    Constants:
        REGISTER_NAMES: ("type", "scope", "role")
        PHASE_NAMES:    ("prep", "converge", "consolidate")
        N_PASSES:       5
        PASS_NAMES:     ("L0_asc", "L1_asc", "L2_apex", "L1_desc", "L0_desc")
    """

    REGISTER_NAMES = ("type", "scope", "role")
    PHASE_NAMES = ("prep", "converge", "consolidate")
    N_PASSES = 5
    PASS_NAMES = ("L0_asc", "L1_asc", "L2_apex", "L1_desc", "L0_desc")

    def __init__(
        self,
        vocab_size: int = 50277,
        d_model: int = 512,
        d_register: int = 128,
        max_len: int = 4096,
        n_heads: int = 8,
        d_ff: int = 1536,
        d_ff_consolidate: int = 2048,
        window: int = 8,
        strides: tuple[int, ...] = (1, 8, 16, 32, 64, 128, 256, 512, 1024),
        dropout: float = 0.1,
        alpha: float = 1.18,
    ):
        super().__init__()
        self.vocab_size = vocab_size
        self.d_model = d_model
        self.d_register = d_register
        self.max_len = max_len
        self.n_heads = n_heads
        self.d_ff = d_ff
        self.d_ff_consolidate = d_ff_consolidate
        self.window = window
        self.strides = strides
        self.alpha = alpha

        self.n_registers = len(self.REGISTER_NAMES)
        self.n_phases = len(self.PHASE_NAMES)
        self.n_banks = 6

        # ── S5: Identity (fp16) ────────────────────────────────
        self.token_embed = nn.Embedding(vocab_size, d_model)
        self.pos_embed = nn.Embedding(max_len, d_model)
        self.output_norm = nn.LayerNorm(d_model)

        # Register bank 0: learnable real init
        self.register_inits = {
            f"reg_{name}": mx.zeros((d_register,))
            for name in self.REGISTER_NAMES
        }

        # ── S1: Operations (ternary) ──────────────────────────
        self.prep = TernaryFFN(d_model, d_ff, dropout)
        self.stride_stack = StrideStack(
            d_model=d_model, strides=strides, window=window,
            n_heads=n_heads, dropout=dropout, alpha=alpha,
        )
        self.consolidate = TernaryFFN(d_model, d_ff_consolidate, dropout)

        # ── S4 (ternary projections) ──────────────────────────
        self.s4 = S4Ternary(d_model, d_register, n_registers=self.n_registers,
                            max_banks=self.n_banks, dropout=dropout)

        # ── S3 (5 instances, one per pass) ────────────────────
        self.s3_passes = [
            S3Ternary(d_model, d_register, n_phases=self.n_phases,
                      n_registers=self.n_registers, d_align=d_model)
            for _ in range(self.N_PASSES)
        ]

        # ── Modulation projections (ternary) ──────────────────
        self.mod_projs = [
            TernaryLinear(d_model, d_model, pre_norm=False)
            for _ in range(self.n_phases)
        ]
        # Zero-init gamma → modulation = 1 at start
        for proj in self.mod_projs:
            proj.gamma = mx.zeros_like(proj.gamma)

        # ── Meta-S4 (ternary) ────────────────────────────────
        self.meta_s4 = MetaS4Ternary(d_model, d_register,
                                      n_registers=self.n_registers,
                                      n_banks=4, dropout=dropout)

        # ── Meta-S3 (fp16, tiny) ─────────────────────────────
        self.meta_s3 = MetaS3Ternary(d_register, n_registers=self.n_registers,
                                      n_banks=self.n_banks, n_passes=self.N_PASSES)

    # ── Register helpers ──────────────────────────────────────────

    def _init_bank0(self) -> list[mx.array]:
        return [
            self.register_inits[f"reg_{name}"] + 0j
            for name in self.REGISTER_NAMES
        ]

    def _fresh_bank(self) -> list[mx.array]:
        return [mx.zeros((self.d_register,), dtype=mx.complex64)
                for _ in self.REGISTER_NAMES]

    # ── Modulation ────────────────────────────────────────────────

    def _modulate(self, x, delta, gate, phase_idx):
        modulation = 1.0 + gate * mx.tanh(self.mod_projs[phase_idx](delta))
        return x * modulation

    # ── Core level-pass ───────────────────────────────────────────

    def _run_level_pass(self, x, pass_idx, is_descending, readable_banks, target_bank):
        x_before = x

        # S4 scan
        s4_updates, _ = self.s4(readable_banks, x)
        target_bank = [target_bank[i] + s4_updates[i] for i in range(self.n_registers)]

        # Phase 0: prep
        prep_out = self.prep(x)
        delta = prep_out - x
        _, target_bank, gate, _ = self.s3_passes[pass_idx].gate_phase(target_bank, delta, 0)
        x = self._modulate(x, delta, gate, 0)

        # Phase 1: converge
        converge_out = self.stride_stack(x, reverse=is_descending)
        delta = converge_out - x
        _, target_bank, gate, _ = self.s3_passes[pass_idx].gate_phase(target_bank, delta, 1)
        x = self._modulate(x, delta, gate, 1)

        # Phase 2: consolidate
        consolidate_out = self.consolidate(x)
        delta = consolidate_out - x
        _, target_bank, gate, _ = self.s3_passes[pass_idx].gate_phase(target_bank, delta, 2)
        x = self._modulate(x, delta, gate, 2)

        return x, target_bank, x - x_before

    # ── Forward ───────────────────────────────────────────────────

    def __call__(
        self,
        input_ids: mx.array,
        targets: Optional[mx.array] = None,
    ) -> tuple[mx.array, Optional[mx.array]]:
        B, L = input_ids.shape

        positions = mx.arange(L)
        x = self.token_embed(input_ids) + self.pos_embed(positions)

        # Register banks
        bank_0 = self._init_bank0()
        bank_1_asc = self._fresh_bank()
        bank_2_asc = self._fresh_bank()
        bank_3 = self._fresh_bank()
        bank_2_desc = self._fresh_bank()
        bank_1_desc = self._fresh_bank()

        pass_deltas = []

        # Ascending: L0↑ → L1↑ → L2
        x, bank_1_asc, delta = self._run_level_pass(x, 0, False, [bank_0], bank_1_asc)
        pass_deltas.append(delta)

        x, bank_2_asc, delta = self._run_level_pass(x, 1, False, [bank_0, bank_1_asc], bank_2_asc)
        pass_deltas.append(delta)

        x, bank_3, delta = self._run_level_pass(x, 2, False, [bank_0, bank_1_asc, bank_2_asc], bank_3)
        pass_deltas.append(delta)

        # Descending: L1↓ → L0↓
        x, bank_2_desc, delta = self._run_level_pass(x, 3, True, [bank_0, bank_1_asc, bank_2_asc, bank_3], bank_2_desc)
        pass_deltas.append(delta)

        x, bank_1_desc, delta = self._run_level_pass(x, 4, True, [bank_0, bank_1_asc, bank_2_desc, bank_3], bank_1_desc)
        pass_deltas.append(delta)

        # Meta-S3: per-pass contribution gates
        all_banks = [bank_0, bank_1_asc, bank_2_asc, bank_3, bank_2_desc, bank_1_desc]
        meta_gates = self.meta_s3(all_banks)

        total_ungated = sum(pass_deltas)
        total_gated = sum(meta_gates[i] * pass_deltas[i] for i in range(self.N_PASSES))
        x = x - total_ungated + total_gated

        # Meta-S4: final structural summary
        meta_banks = [bank_0, bank_1_desc, bank_2_desc, bank_3]
        x = self.meta_s4(meta_banks, x)

        # Output
        x = self.output_norm(x)
        logits = x @ self.token_embed.weight.T  # tied weights

        loss = None
        if targets is not None:
            loss = nn.losses.cross_entropy(
                logits.reshape(-1, self.vocab_size),
                targets.reshape(-1),
            ).mean()

        return logits, loss

    # ── Ternary stats ─────────────────────────────────────────────

    def ternary_stats(self) -> dict[str, dict[str, float]]:
        stats = {}
        def _walk(prefix, mod):
            if isinstance(mod, TernaryLinear):
                stats[prefix] = mod.ternary_stats()
            if isinstance(mod, nn.Module):
                for name, child in mod.children().items():
                    child_path = f"{prefix}.{name}" if prefix else name
                    if isinstance(child, nn.Module):
                        _walk(child_path, child)
                    elif isinstance(child, dict):
                        for k, v in child.items():
                            if isinstance(v, nn.Module):
                                _walk(f"{child_path}.{k}", v)
                    elif isinstance(child, list):
                        for i, item in enumerate(child):
                            if isinstance(item, nn.Module):
                                _walk(f"{child_path}.{i}", item)
        _walk("", self)
        return stats

    # ── Parameter counting ────────────────────────────────────────

    def count_parameters(self) -> dict[str, int]:
        # MLX parameters() returns nested dict; flatten to count
        def _count_leaves(tree):
            if isinstance(tree, mx.array):
                return tree.size
            elif isinstance(tree, dict):
                return sum(_count_leaves(v) for v in tree.values())
            elif isinstance(tree, list):
                return sum(_count_leaves(v) for v in tree)
            return 0

        total = _count_leaves(self.parameters())
        total_ternary = 0
        total_gamma = 0
        for path, module in self.named_modules():
            if isinstance(module, TernaryLinear):
                total_ternary += module.ternary_weight.size
                total_gamma += module.gamma.size

        total_continuous = total - total_ternary
        total_bits = total_ternary * 2 + total_continuous * 16
        effective_bits = total_bits / max(total, 1)

        return {
            "total": total,
            "total_ternary": total_ternary,
            "total_continuous": total_continuous,
            "total_gamma": total_gamma,
            "effective_bits_x1000": int(effective_bits * 1000),
            "inference_MB": int((total_ternary * 2 / 8 + total_continuous * 2) / 1024 / 1024),
            "training_MB": int((total_ternary * 5 + total_continuous * 16) / 1024 / 1024),
        }

    # ── Describe ──────────────────────────────────────────────────

    def describe(self) -> str:
        strides_str = " → ".join(f"s{s}" for s in self.strides)
        params = self.count_parameters()
        eff = params["effective_bits_x1000"] / 1000
        return "\n".join([
            "VSM-LM v6 — Ternary on Metal (MLX)",
            f"  d_model={self.d_model}, d_register=ℂ^{self.d_register}, seq_len={self.max_len}",
            f"  Passes: {self.N_PASSES} (L0↑, L1↑, L2, L1↓, L0↓)",
            f"  Phases: prep(TernaryFFN) → converge(StrideStack) → consolidate(TernaryFFN)",
            f"  Strides: {strides_str} (W={self.window}, α={self.alpha})",
            f"  Parameters: {params['total']/1e6:.1f}M total",
            f"    Ternary: {params['total_ternary']/1e6:.1f}M (Metal add/sub kernel)",
            f"    Continuous: {params['total_continuous']/1e6:.1f}M (Adam optimizer)",
            f"    Effective bits: {eff:.2f}",
            f"    Inference: {params['inference_MB']} MB, Training: {params['training_MB']} MB",
        ])

    # ── Generate ──────────────────────────────────────────────────

    def generate(self, input_ids: mx.array, max_new_tokens: int = 50, temperature: float = 1.0) -> mx.array:
        for _ in range(max_new_tokens):
            ctx = input_ids[:, -self.max_len:]
            logits, _ = self(ctx)
            logits = logits[:, -1, :] / temperature
            next_token = mx.argmax(logits, axis=-1, keepdims=True)
            input_ids = mx.concatenate([input_ids, next_token], axis=1)
        return input_ids
