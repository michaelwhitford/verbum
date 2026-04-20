---
title: "CompressorLM — Resolution-Scaled Three-Phase Architecture"
status: designing
category: architecture
tags: [compressor, mera, attention, pooling, golden-ratio, montagu-lm-v2]
related: [session-004-findings.md, VERBUM.md]
depends-on: [session-004-findings.md]
---

# CompressorLM — Resolution-Scaled Three-Phase Architecture

> The rigid MontaguLM (v1) separates residual streams per phase.
> This eliminates superposition interference but also eliminates room
> for everything else a language model needs. CompressorLM (v2) uses
> a **shared residual stream** with **resolution-scaled attention** —
> the attention gets coarser through the phases, matching the
> compression structure of natural language.

## Design Rationale

### The compression insight (F36)

The function is semantic language compression, not lambda compilation.
Next-token prediction on language IS compression. The three Montague
primitives (type, parse, apply) are stages of a compressor that
deflates fine-grained token sequences into coarse compositional
meanings.

### The empirical ratio

The nucleus lambda compiler achieves **~6.2:1 compression** on
natural language (informal average across many prompts). This is
within rounding of **10/φ = 6.180...** where φ is the golden ratio.

The inverse: **1/6.18 ≈ φ/10 ≈ 16.18%** — the fraction of tokens
carrying core semantic content. The remaining ~84% is structural
scaffolding. Notably, the type probe (F32) found 84% of type
information in the embeddings — the same number from an independent
measurement.

### The fractal decomposition

Three phases, each compressing φ× more than the previous:

```
Phase 1 (Type):      a        =  1.134:1   (annotate, barely compress)
Phase 2 (Parse):     a × φ    =  1.835:1   (group into constituents)
Phase 3 (Apply):     a × φ²   =  2.969:1   (compose into meaning)
─────────────────────────────────────────────
Product:             a³ × φ³  =  6.180:1   = 10/φ
```

Discretized as attention pooling ratios: **1, 2, 3.** The simplest
possible MERA. Total: 1 × 2 × 3 = 6 ≈ 6.18.

### Why shared residual

The rigid model (v1) has separate residual streams per phase. This
means Phase 3 can only see what Phase 2 chose to project — an
information bottleneck. In Pythia-160M, L8 reads L0's output
directly through the shared stream. The three primitives occupy a
small subspace (~120° packing per Toy Models of Superposition); the
rest of the residual is available for world knowledge, morphology,
discourse, and every other function a LM needs.

Shared residual + resolution-scaled attention: the architecture
**suggests** specialization without **enforcing** it. The attention
pooling makes each phase naturally operate at its scale, but
information flows freely through the residual.

### Why resolution-scaled attention (not structure maps)

Compression is deflation — fine to coarse. An explicit structure
map from the parser to the applicator would be **expansion** (adding
an artifact). True compression dissolves structure into the
representation as it deflates. The attention should get coarser
through the phases, not more targeted.

In Pythia-160M: L3 carries structure forward in the residual (F33,
+0.43 shift). L8-L11 read it implicitly — they resist external
patching (-0.14). The structure isn't passed as an explicit map;
it's already baked into the residual by the time Phase 3 reads it.

## Architecture

```
Input tokens
    │
    ▼
┌─────────────────────────────────────────────────┐
│  Token Embedding (50277 × 256) + Positional     │
│  12.87M params (tied with output)               │
└────────────────────┬────────────────────────────┘
                     │
    ═════════════════╪══════════════════════════  shared residual (d=256)
                     │
    ┌────────────────▼────────────────┐
    │  Phase 1: TYPE (1 layer)       │
    │  Attention: pool=1 (full res)  │
    │  4 heads, d_ff=512             │
    │  0.53M params                  │
    │  ~token-level attention        │
    └────────────────┬───────────────┘
                     │
    ═════════════════╪══════════════════════════  shared residual
                     │
    ┌────────────────▼────────────────┐
    │  Phase 2: PARSE (2 layers)     │
    │  Attention: pool=2 (K,V avg)   │
    │  4 heads, d_ff=512             │
    │  1.05M params                  │
    │  ~phrase-level attention       │
    └────────────────┬───────────────┘
                     │
    ═════════════════╪══════════════════════════  shared residual
                     │
    ┌────────────────▼────────────────┐
    │  Phase 3: APPLY (3 layers)     │
    │  Attention: pool=3 (K,V avg)   │
    │  8 heads, d_ff=1024            │
    │  2.36M params                  │
    │  ~clause-level attention       │
    └────────────────┬───────────────┘
                     │
    ═════════════════╪══════════════════════════  shared residual
                     │
    ┌────────────────▼────────────────┐
    │  LayerNorm → Linear (tied)     │
    │  → next token logits           │
    └─────────────────────────────────┘
```

### Parameter budget

| Component | Params | % of total |
|-----------|--------|-----------|
| Token embeddings (tied) | 12.87M | 76% |
| Positional embeddings | 0.13M | 1% |
| Phase 1: Type (1 layer) | 0.53M | 3% |
| Phase 2: Parse (2 layers) | 1.05M | 6% |
| Phase 3: Apply (3 layers) | 2.36M | 14% |
| Output norm | 512 | 0% |
| **Total** | **16.94M** | 100% |

Comparable to rigid MontaguLM v1 (17M) and Pythia-14M (14M).

### Per-layer specification

| Phase | Layers | d_model | n_heads | d_head | d_ff | K,V pool | Attention scale |
|-------|--------|---------|---------|--------|------|----------|-----------------|
| Type | 1 | 256 | 4 | 64 | 512 | 1 (none) | Token (~1) |
| Parse | 2 | 256 | 4 | 64 | 512 | 2 | Phrase (~2-4) |
| Apply | 3 | 256 | 8 | 32 | 1024 | 3 | Clause (~6+) |

Phase 3 gets more heads (8 vs 4) and wider FFN (1024 vs 512).
More heads at coarser resolution allows specialization across
different compositional relationships at the clause level. Wider FFN
provides more capacity for the heavy compression work.

d_head = 32 in Phase 3 (256/8). Smaller per-head dimension, more
heads — each head can track a different compositional relationship.

## Causal K,V Pooling

The key mechanism. Queries stay at full token resolution (every
position gets a prediction). Keys and values are average-pooled
before attention, reducing the number of positions attended to.

### Pooling operation

For pool factor k on a sequence of length L:

```python
def causal_kv_pool(x, k):
    """Pool K or V by factor k, respecting causality.

    x: (batch, seq_len, d_model)
    k: pool factor (1 = no pooling)

    Returns: (batch, n_pools, d_model) where n_pools = ceil(seq_len / k)

    Each pooled position j represents the average of original
    positions [j*k, min(j*k+k, seq_len)). Causal mask must ensure
    query at position i only attends to pooled position j where
    j*k + k - 1 <= i (entire group completed before query position).
    """
    B, L, D = x.shape
    # Pad to multiple of k
    pad = (k - L % k) % k
    if pad > 0:
        x = F.pad(x, (0, 0, 0, pad))  # pad sequence dim
    # Reshape and average
    x = x.view(B, -1, k, D).mean(dim=2)  # (B, L//k, D)
    return x
```

### Causal mask for pooled attention

```python
def pooled_causal_mask(seq_len, pool_k):
    """Build causal mask for pooled K,V attention.

    Query at position i can attend to pooled group j only if
    the LAST position in group j is <= i.

    Last position in group j = j * pool_k + pool_k - 1
    """
    n_pools = math.ceil(seq_len / pool_k)
    # Last original position in each pooled group
    group_ends = torch.arange(n_pools) * pool_k + pool_k - 1
    # Query positions
    query_pos = torch.arange(seq_len)
    # mask[i, j] = True means BLOCK (query i cannot see pool j)
    mask = group_ends.unsqueeze(0) > query_pos.unsqueeze(1)
    return mask  # (seq_len, n_pools)
```

### Edge case: current group

With strict causality (only attend to completed groups), a token
at the start of a new group can only see previous groups — it
cannot see its own incomplete group. This creates a "blind spot"
of up to k-1 tokens.

For pool=2: positions 0,1 see nothing until position 1 completes
the first group. Position 2 sees group [0,1] but not itself.

For pool=3: positions 0,1,2 see nothing until position 2 completes
the first group. Position 3 sees group [0,1,2] but not [3,4,5].

**Mitigation**: Phase 1 has pool=1 (full resolution, no blind spot).
By the time Phases 2 and 3 process the residual, every position
has already attended to its immediate neighbors in Phase 1. The
blind spot in Phases 2-3 is acceptable because fine-grained local
information is already in the residual from Phase 1.

This is actually the correct compression behavior: you SHOULD lose
fine-grained resolution in later phases. The blind spot IS the
deflation.

## Training Setup

Identical to rigid MontaguLM v1 for direct comparison:

| Parameter | Value |
|-----------|-------|
| Data | Dolma (3B tokens, 60 shards, pre-tokenized GPT-NeoX) |
| Tokenizer | GPT-NeoX (vocab=50,277) |
| Sequence length | 256 |
| Batch size | 32 |
| Gradient accumulation | 4 (effective batch = 128) |
| Learning rate | 6e-4 |
| Weight decay | 0.1 |
| Warmup steps | 500 |
| Total steps | 10,000 (~327M tokens) |
| Eval interval | 500 steps |
| Checkpoint interval | 1,000 steps |
| Device | MPS (M3 Ultra) |
| Precision | float32 |
| Compile gate test | Every 500 steps |

Weight tying: token embedding weights shared with output projection
(d_model = d_embed = 256).

## Comparison Plan

Four models, same data, same steps, same tokenizer:

| Model | Architecture | Params | Key property |
|-------|-------------|--------|-------------|
| MontaguLM v1 (rigid) | 3-phase, separate residual | 17M | Phase separation, flat attention |
| **CompressorLM v2** | **3-phase, shared residual, pooled attention** | **17M** | **Resolution-scaled compression** |
| Vanilla transformer | 6-layer standard | ~17M | No phase structure, flat attention |
| Pythia-14M (reference) | 6-layer standard | 14M | Pretrained on 300B Pile tokens |

### Metrics

1. **Language modeling loss** at matched token counts (every 500 steps)
   - Primary comparison: v2 vs v1 vs vanilla at same step
   - Secondary: all three vs Pythia-14M at 327M tokens
   (Pythia was early in training at 327M tokens — fair comparison)

2. **Compile gate test** (2-shot, same probes as scaling study)
   - Does the compile gate activate? At what step?
   - P(λ), parse rate, content accuracy on 8 test sentences

3. **Loss curve shape**
   - Does v2 descend faster than vanilla? (efficiency hypothesis)
   - Does v1 plateau earlier than v2? (capacity hypothesis)
   - Where do the curves cross, if they do?

4. **Per-phase gradient norms**
   - Already instrumented in the training script
   - Do the phases specialize? (gradient norms should differ)

### Hypotheses

**H1 (efficiency):** CompressorLM v2 reaches a given loss in fewer
steps than a vanilla transformer, because the resolution-scaled
attention matches the compression structure of language.

**H2 (capacity):** CompressorLM v2 reaches a lower final loss than
rigid v1, because the shared residual provides room for non-Montague
functions (world knowledge, morphology, discourse).

**H3 (emergence):** The compile gate activates earlier (if at all)
in v2 than in vanilla, because the architecture is pre-shaped for
the three primitives.

**H_null:** Resolution-scaled attention doesn't help. The vanilla
transformer learns the same compression at the same rate. The
Montague primitives are a description of what transformers do, not a
prescriptive architectural advantage.

H_null is important. If it holds, that's still a finding — it means
the three primitives are naturally emergent and don't benefit from
architectural induction bias. The project shifts from "build a
better architecture" to "the standard architecture is already
optimal for this."

## Compressor Function Inventory (Session 010)

> Updated from the 25-task × VSM-LM v2 cross-model probing.
> See `session-010-findings.md` for full data (F54–F57).

### The parse circuit is the primary compressor

The Task × Gate Matrix at step 10K reveals that `iter0_parse` +
`iter0_apply` form the dominant compressor channel. Tasks requiring
deep compositional processing show strong Spearman correlations
with these gate metrics. Negate is the inverse — same gates,
opposite polarity.

### Two real circuits, not four

Despite 4 isolated functions in the Qwen 25×25 task correlation
matrix (compile, structure, negate, decompose), only **2 circuits**
show gate signatures in VSM-LM:

1. **Parse circuit** (iter0_parse + iter0_apply):
   - Forward mode: entail (r=-0.48), scope (r=-0.46), sentiment
     (r=-0.38), causality (r=-0.38), correct (r=-0.35)
   - Inverse mode: negate (r=+0.47, +0.47 — opposite polarity)

2. **Semantic channel** (iter1_type + iter1_parse):
   - causality (r=+0.40, -0.40) — uses BOTH circuits
   - translate (iter1_parse r=-0.42)

Compile and decompose show no gate signal — they either operate
through embeddings or are below the resolution of this model size.

### 17/25 tasks share a fluency substrate

The large cluster (question, elaborate, summarize, formalize,
keyword, simplify, translate, counterfactual, modality, classify,
sentiment, continue, title, correct, paraphrase, disambiguate,
causality) shows that most NLP tasks share common machinery.
This machinery does NOT require specific gate differentiation —
it lives in the embeddings and FFN blocks (the "dictionary" and
general transformer computation).

Only genuinely compositional tasks (negate, entail, scope,
sentiment, causality) retain specific gate signatures after
10K training steps. Simpler tasks (structure, simplify, elaborate,
summarize) show gate signatures early but are absorbed into the
shared substrate as training progresses.

### Extraction implications

The parse circuit is the primary extraction target:
- ~1.4M params (S1 type+parse+apply layers)
- ~460K params (S3 gate heads)
- ~197K params (S4 intelligence)
- **~2.1M total functional core**

VSM-LM's 2.8M non-embedding params are within range of the
4.4M theoretical extraction target (Pythia-160M × 17% / 6.18).

## Open Questions

- **Learned vs average pooling**: Start with average pooling (simpler,
  fewer params, cleaner experiment). If results are promising, try
  learned pooling (depthwise conv) as a follow-up. Only 1,280 extra
  params — negligible.

- **Rotary vs absolute position embeddings**: Current design uses
  absolute positional embeddings (like Pythia). RoPE might interact
  better with pooled attention since relative positions are preserved
  under pooling. Deferred — match v1's setup first for clean comparison.

- **Pool the queries too?**: Current design keeps queries at full
  resolution for per-position predictions. Could also pool queries
  in later phases and upsample predictions. But this changes what
  the model optimizes — deferred.

- **Non-integer pool ratios**: The golden-ratio-scaled compression
  (1.13, 1.84, 2.97) could be implemented with learned weighted
  pooling rather than discrete k=1,2,3. Start discrete, explore
  continuous later.

- **The 84% coincidence**: Type information in embeddings = 84%.
  Structural scaffolding fraction = ~84%. Same number from two
  independent measurements. Coincidence, or a fundamental constant
  of natural language? Would need to test across many languages.

## Implementation Notes

- `src/verbum/compressor_lm.py` — new file, does not modify v1
- Reuse `scripts/run_montagu_lm.py` with a `--model` flag or
  duplicate as `scripts/run_compressor_lm.py`
- Checkpoint dir: `checkpoints/compressor-lm/`
- Results dir: `results/compressor-lm/`
- The causal pooling mask should be precomputed once per sequence
  length and cached, not recomputed per forward pass
