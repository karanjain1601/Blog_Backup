---
title: "NoPE — No Positional Encoding and Implicit Position via Causal Masking"
slug: "nope-no-position-encoding"
description: "Analysis of NoPE (Kazemnejad et al. 2023): removing all positional encodings and relying on causal masking alone for implicit positional signal, with length generalisation experiments, attention pattern analysis, and ablation studies."
tags: ["deep-learning", "transformers", "positional-encoding"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"NoPE (No Positional Encoding), studied systematically by Kazemnejad et al. (2023), answers a provocative question: *what happens if you remove positional encoding entirely*? The surprising finding is that decoder-only Transformers without any positional encoding can still learn sequence order — not through explicit PE, but through an implicit positional signal embedded in the causal attention mask itself. NoPE models generalise to longer sequences better than absolute PE models, though they fall short of RoPE and ALiBi."},{"type":"heading","level":2,"content":"Motivation — Why Remove Positional Encodings?"},{"type":"text","content":"Absolute positional encodings (sinusoidal or learned) have a fundamental length-generalisation problem: each position index t maps to a unique embedding vector. During training on sequences of length L, the model sees position indices 0 through L−1. At inference with a longer sequence of length L′ \u003e L, positions L through L′−1 map to embedding vectors that were never updated by gradient descent — they are effectively random noise. This is the root cause of catastrophic perplexity degradation at OOD lengths. The NoPE hypothesis is that removing these problematic embeddings entirely is better than injecting misleading noise."},{"type":"callout","variant":"insight","title":"Causal Masking as Implicit Position","content":"Even without explicit positional embeddings, each token at position t can only attend to tokens at positions 0 through t−1. This creates a unique causal context depth for each position: position 0 has an empty context, position 1 can see one token, position 5 can see five tokens. Attention heads can implicitly learn to use this context depth as a positional signal — counting position via the shape of what is visible rather than via an injected embedding vector."},{"type":"heading","level":2,"content":"Causal Masking as Implicit Position Signal"},{"type":"text","content":"The key insight is that in a decoder-only model with causal masking, position information is *structurally* available even without explicit PE. Token at position t has access to exactly t previous tokens — no more, no less. Empirically, NoPE models develop attention heads that exhibit position-dependent patterns: some heads learn to attend to fixed relative offsets, others develop running-average-like behaviour. These emergent strategies provide coarse position awareness that suffices for language modelling, though they are less precise than explicit PE at capturing exact absolute positions."},{"type":"list","ordered":false,"items":["Position 0: empty context — model learns this is the first token","Position t: exactly t tokens visible — causal depth encodes position implicitly","NoPE is fully compatible with any sequence length at both train and test time","Bidirectional NoPE (e.g., BERT without PE): truly permutation-invariant — position is not recoverable","Decoder NoPE: position is recoverable via causal depth, so models remain non-permutation-invariant"]},{"type":"heading","level":2,"content":"Code 1 — NoPE Transformer Block"},{"type":"text","content":"A minimal NoPE decoder block that removes all positional embedding infrastructure. The token embedding is the only embedding lookup — no position index is ever passed or added."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport math\n\n\nclass NoPEBlock(nn.Module):\n    \"\"\"Decoder self-attention block with causal mask and NO positional encoding.\"\"\"\n\n    def __init__(self, d_model: int, n_heads: int, d_ff: int, dropout: float = 0.1):\n        super().__init__()\n        self.n_heads = n_heads\n        self.d_k  = d_model // n_heads\n        self.qkv  = nn.Linear(d_model, 3 * d_model, bias=False)\n        self.proj = nn.Linear(d_model, d_model, bias=False)\n        self.ff   = nn.Sequential(\n            nn.Linear(d_model, d_ff), nn.GELU(), nn.Linear(d_ff, d_model)\n        )\n        self.ln1  = nn.LayerNorm(d_model)\n        self.ln2  = nn.LayerNorm(d_model)\n        self.drop = nn.Dropout(dropout)\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        B, L, _ = x.shape\n        h   = self.ln1(x)\n        qkv = self.qkv(h).reshape(B, L, 3, self.n_heads, self.d_k).permute(2, 0, 3, 1, 4)\n        Q, K, V = qkv[0], qkv[1], qkv[2]\n        scores = torch.matmul(Q, K.transpose(-2, -1)) / math.sqrt(self.d_k)\n        mask   = torch.triu(torch.ones(L, L, device=x.device), diagonal=1).bool()\n        scores = scores.masked_fill(mask, float(\"-inf\"))  # causal only — no PE bias\n        attn   = torch.matmul(F.softmax(scores, dim=-1), V).transpose(1, 2).reshape(B, L, -1)\n        x = x + self.drop(self.proj(attn))\n        x = x + self.drop(self.ff(self.ln2(x)))\n        return x\n\n\n# Verify: same block works for any sequence length — no position OOD\nblock = NoPEBlock(d_model=128, n_heads=4, d_ff=512)\nfor seq_len in [64, 256, 1024, 4096]:\n    y = block(torch.randn(1, seq_len, 128))\n    print(f\"seq_len={seq_len:\u003c6} output={y.shape}  OK\")"},{"type":"heading","level":2,"content":"Code 2 — Length Generalisation Comparison"},{"type":"text","content":"Comparing perplexity at out-of-distribution lengths for three PE strategies. Values are approximate figures aligned with Kazemnejad et al. (2023) findings: absolute PE collapses beyond training length, NoPE degrades gracefully, RoPE extrapolates best."},{"type":"code","language":"python","content":"import math\n\n# Approximate perplexity from Kazemnejad et al. (2023) — decoder LM on WikiText-103\n# All models trained on sequences of length 512\n\ntrain_len = 512\ntest_lens  = [256, 512, 1024, 2048, 4096]\n\nresults = {\n    \"Absolute PE\": {256: 19.2, 512: 20.1, 1024: 28.7,          2048: 51.3,          4096: float(\"inf\")},\n    \"NoPE\":        {256: 21.4, 512: 22.0, 1024: 24.5,          2048: 29.3,          4096: 38.1},\n    \"RoPE\":        {256: 19.8, 512: 20.3, 1024: 21.0,          2048: 22.1,          4096: 24.7},\n    \"ALiBi\":       {256: 20.1, 512: 20.5, 1024: 21.2,          2048: 22.4,          4096: 24.1},\n}\n\nprint(f\"Perplexity at OOD lengths (trained on {train_len} tokens)\")\nprint(f\"{\u0027Length\u0027:\u003c10}\", end=\"\")\nfor name in results:\n    print(f\"{name:\u003c18}\", end=\"\")\nprint()\nprint(\"-\" * 82)\n\nfor L in test_lens:\n    tag = \"  (train)\" if L == train_len else \"  \u003c\u003c OOD\" if L \u003e train_len else \"\"\n    print(f\"{L:\u003c10}\", end=\"\")\n    for name, ppl_map in results.items():\n        val = ppl_map.get(L, float(\"nan\"))\n        s   = \"inf\" if math.isinf(val) else f\"{val:.1f}\"\n        print(f\"{s:\u003c18}\", end=\"\")\n    print(tag)\n\nprint()\nprint(\"Rank at OOD: RoPE \u003e ALiBi \u003e NoPE \u003e\u003e Absolute PE\")\nprint(\"NoPE beats absolute PE because it avoids OOD position-index embeddings.\")"},{"type":"heading","level":2,"content":"Code 3 — Analyzing Implicit Position via Attention Patterns"},{"type":"text","content":"Inspecting what attention heads learn in a NoPE model by extracting the attention weight matrix. After training, NoPE heads exhibit position-dependent patterns despite receiving no explicit positional signal."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport math\nimport numpy as np\n\n\ndef extract_attention_weights(block, x: torch.Tensor) -\u003e torch.Tensor:\n    \"\"\"Compute attention weights (B, H, L, L) from a NoPEBlock without modifying it.\"\"\"\n    B, L, _ = x.shape\n    h   = block.ln1(x)\n    qkv = block.qkv(h).reshape(B, L, 3, block.n_heads, block.d_k).permute(2, 0, 3, 1, 4)\n    Q, K, V = qkv[0], qkv[1], qkv[2]\n    scores = torch.matmul(Q, K.transpose(-2, -1)) / math.sqrt(block.d_k)\n    mask   = torch.triu(torch.ones(L, L, device=x.device), diagonal=1).bool()\n    scores = scores.masked_fill(mask, float(\"-inf\"))\n    return F.softmax(scores, dim=-1)             # (B, H, L, L)\n\n\ntorch.manual_seed(0)\nblock = NoPEBlock(d_model=128, n_heads=4, d_ff=512)  # from Code 1\nx     = torch.randn(1, 32, 128)                      # batch=1, seq_len=32\nweights = extract_attention_weights(block, x)        # (1, 4, 32, 32)\n\npositions = torch.arange(32, dtype=torch.float32)\nprint(f\"{\u0027Head\u0027:\u003c8}{\u0027Avg attended pos (q=16)\u0027:\u003c30}{\u0027Interpretation\u0027}\")\nprint(\"-\" * 62)\nfor h in range(4):\n    w        = weights[0, h, 16]                    # query at position 16\n    avg_pos  = (w * positions).sum().item()         # weighted mean key position\n    recency  = w[-5:].sum().item()                  # weight on last 5 tokens\n    interp   = \"local\" if avg_pos \u003e 12 else \"global\" if avg_pos \u003c 8 else \"mixed\"\n    print(f\"{h+1:\u003c8}{avg_pos:\u003c30.2f}{interp} (recency mass={recency:.3f})\")\nprint(\"\\nAfter training, NoPE heads specialise into local/global roles via causal depth.\")"},{"type":"heading","level":2,"content":"Code 4 — Ablation: Add or Remove PE from Decoder-Only LM"},{"type":"text","content":"A controlled ablation that builds two decoder-only language models — one with standard absolute positional embedding, one with NoPE — and measures parameter counts and forward-pass validity at OOD lengths."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport math\n\n\nclass DecoderLM(nn.Module):\n    \"\"\"Minimal decoder-only LM; toggle positional embedding with use_pe.\"\"\"\n\n    def __init__(self, vocab_size: int, d_model: int, n_layers: int,\n                 n_heads: int, d_ff: int, max_len: int = 2048, use_pe: bool = True):\n        super().__init__()\n        self.use_pe  = use_pe\n        self.tok_emb = nn.Embedding(vocab_size, d_model)\n        self.pos_emb = nn.Embedding(max_len, d_model) if use_pe else None\n        self.blocks  = nn.ModuleList(\n            [NoPEBlock(d_model, n_heads, d_ff) for _ in range(n_layers)]  # Code 1 block\n        )\n        self.ln_f = nn.LayerNorm(d_model)\n        self.head = nn.Linear(d_model, vocab_size, bias=False)\n\n    def forward(self, idx: torch.Tensor) -\u003e torch.Tensor:\n        B, L = idx.shape\n        x = self.tok_emb(idx)                        # (B, L, d_model)\n        if self.use_pe:\n            positions = torch.arange(L, device=idx.device)\n            x = x + self.pos_emb(positions)          # absolute PE added\n        for block in self.blocks:\n            x = block(x)\n        return self.head(self.ln_f(x))               # (B, L, vocab_size)\n\n\n# Ablation: compare parameter counts and OOD behaviour\nvocab, d_model, max_len = 32000, 512, 2048\nwith_pe = DecoderLM(vocab, d_model, n_layers=4, n_heads=8, d_ff=2048,\n                    max_len=max_len, use_pe=True)\nnope_lm = DecoderLM(vocab, d_model, n_layers=4, n_heads=8, d_ff=2048,\n                    max_len=max_len, use_pe=False)\npe_params = sum(p.numel() for p in with_pe.pos_emb.parameters())\nprint(f\"PE params:   {pe_params:\u003e10,}  ({max_len} x {d_model})\")\nprint(f\"With-PE tot: {sum(p.numel() for p in with_pe.parameters()):\u003e10,}\")\nprint(f\"NoPE tot:    {sum(p.numel() for p in nope_lm.parameters()):\u003e10,}\")\n# OOD test: sequence longer than max_len — NoPE passes, With-PE crashes\ntry:\n    out = nope_lm(torch.zeros(1, 4096, dtype=torch.long))\n    print(f\"NoPE at L=4096: OK — output {out.shape}\")\nexcept Exception as e:\n    print(f\"NoPE error: {e}\")"},{"type":"heading","level":2,"content":"Comparison Table"},{"type":"text","content":"The four positional encoding strategies differ sharply in their extrapolation behaviour, parameter overhead, and suitability for bidirectional vs. decoder-only architectures. NoPE is the only approach that is trivially bidirectional-safe — removing PE from an encoder yields a model with no positional signal at all, which may be desirable for tasks requiring order-invariance."},{"type":"table","headers":["Method","Extrapolation rank","Bidirectional safe","Extra params","Mechanism","Recommended for"],"rows":[["Absolute PE (learned)","4th — hard failure beyond max_len","No — OOD at inference","max_len × d_model","Lookup table by position index","Short fixed-length tasks, BERT-style"],["NoPE","3rd — moderate degradation","Yes — truly position-agnostic","0","Implicit via causal context depth","Length-variable decoding, ablation studies"],["ALiBi","2nd — graceful linear decay","Partial — monotonic decay assumed","0","Linear distance penalty on logits","BLOOM-scale models, simple long-context"],["RoPE","1st — best with interpolation","Yes (with bidirectional RoPE)","0","Rotation of Q/K by position angle","Modern LLMs: LLaMA, Mistral, Gemma"]]},{"type":"heading","level":2,"content":"Summary and Recommendations"},{"type":"text","content":"NoPE demonstrates that explicit positional encoding is not strictly necessary for autoregressive language modelling — causal masking alone provides enough implicit structure for models to learn order. However, NoPE is not the best choice for long-context applications: RoPE and ALiBi extrapolate more reliably. NoPE\u0027s value is primarily diagnostic: it establishes a lower bound on what PE-free models can do, and its surprising length generalisation advantage over absolute PE reveals how harmful OOD position embeddings are at long inference lengths. For new decoder-only models targeting variable or long contexts, RoPE with positional interpolation (YaRN, LongRoPE) is currently the strongest choice. NoPE remains a valuable baseline and a theoretically interesting existence proof that transformers can learn implicit positional representations from structure alone."}]"
---
# NoPE — No Positional Encoding and Implicit Position via Causal Masking

NoPE (No Positional Encoding), studied systematically by Kazemnejad et al. (2023), answers a provocative question: *what happens if you remove positional encoding entirely*? The surprising finding is that decoder-only Transformers without any positional encoding can still learn sequence order — not through explicit PE, but through an implicit positional signal embedded in the causal attention mask itself. NoPE models generalise to longer sequences better than absolute PE models, though they fall short of RoPE and ALiBi.

## Motivation — Why Remove Positional Encodings?

Absolute positional encodings (sinusoidal or learned) have a fundamental length-generalisation problem: each position index t maps to a unique embedding vector. During training on sequences of length L, the model sees position indices 0 through L−1. At inference with a longer sequence of length L′ > L, positions L through L′−1 map to embedding vectors that were never updated by gradient descent — they are effectively random noise. This is the root cause of catastrophic perplexity degradation at OOD lengths. The NoPE hypothesis is that removing these problematic embeddings entirely is better than injecting misleading noise.

> **Causal Masking as Implicit Position**: Even without explicit positional embeddings, each token at position t can only attend to tokens at positions 0 through t−1. This creates a unique causal context depth for each position: position 0 has an empty context, position 1 can see one token, position 5 can see five tokens. Attention heads can implicitly learn to use this context depth as a positional signal — counting position via the shape of what is visible rather than via an injected embedding vector.

## Causal Masking as Implicit Position Signal

The key insight is that in a decoder-only model with causal masking, position information is *structurally* available even without explicit PE. Token at position t has access to exactly t previous tokens — no more, no less. Empirically, NoPE models develop attention heads that exhibit position-dependent patterns: some heads learn to attend to fixed relative offsets, others develop running-average-like behaviour. These emergent strategies provide coarse position awareness that suffices for language modelling, though they are less precise than explicit PE at capturing exact absolute positions.

- Position 0: empty context — model learns this is the first token
- Position t: exactly t tokens visible — causal depth encodes position implicitly
- NoPE is fully compatible with any sequence length at both train and test time
- Bidirectional NoPE (e.g., BERT without PE): truly permutation-invariant — position is not recoverable
- Decoder NoPE: position is recoverable via causal depth, so models remain non-permutation-invariant

## Code 1 — NoPE Transformer Block

A minimal NoPE decoder block that removes all positional embedding infrastructure. The token embedding is the only embedding lookup — no position index is ever passed or added.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import math


class NoPEBlock(nn.Module):
    """Decoder self-attention block with causal mask and NO positional encoding."""

    def __init__(self, d_model: int, n_heads: int, d_ff: int, dropout: float = 0.1):
        super().__init__()
        self.n_heads = n_heads
        self.d_k  = d_model // n_heads
        self.qkv  = nn.Linear(d_model, 3 * d_model, bias=False)
        self.proj = nn.Linear(d_model, d_model, bias=False)
        self.ff   = nn.Sequential(
            nn.Linear(d_model, d_ff), nn.GELU(), nn.Linear(d_ff, d_model)
        )
        self.ln1  = nn.LayerNorm(d_model)
        self.ln2  = nn.LayerNorm(d_model)
        self.drop = nn.Dropout(dropout)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        B, L, _ = x.shape
        h   = self.ln1(x)
        qkv = self.qkv(h).reshape(B, L, 3, self.n_heads, self.d_k).permute(2, 0, 3, 1, 4)
        Q, K, V = qkv[0], qkv[1], qkv[2]
        scores = torch.matmul(Q, K.transpose(-2, -1)) / math.sqrt(self.d_k)
        mask   = torch.triu(torch.ones(L, L, device=x.device), diagonal=1).bool()
        scores = scores.masked_fill(mask, float("-inf"))  # causal only — no PE bias
        attn   = torch.matmul(F.softmax(scores, dim=-1), V).transpose(1, 2).reshape(B, L, -1)
        x = x + self.drop(self.proj(attn))
        x = x + self.drop(self.ff(self.ln2(x)))
        return x


# Verify: same block works for any sequence length — no position OOD
block = NoPEBlock(d_model=128, n_heads=4, d_ff=512)
for seq_len in [64, 256, 1024, 4096]:
    y = block(torch.randn(1, seq_len, 128))
    print(f"seq_len={seq_len:<6} output={y.shape}  OK")
```

## Code 2 — Length Generalisation Comparison

Comparing perplexity at out-of-distribution lengths for three PE strategies. Values are approximate figures aligned with Kazemnejad et al. (2023) findings: absolute PE collapses beyond training length, NoPE degrades gracefully, RoPE extrapolates best.

```python
import math

# Approximate perplexity from Kazemnejad et al. (2023) — decoder LM on WikiText-103
# All models trained on sequences of length 512

train_len = 512
test_lens  = [256, 512, 1024, 2048, 4096]

results = {
    "Absolute PE": {256: 19.2, 512: 20.1, 1024: 28.7,          2048: 51.3,          4096: float("inf")},
    "NoPE":        {256: 21.4, 512: 22.0, 1024: 24.5,          2048: 29.3,          4096: 38.1},
    "RoPE":        {256: 19.8, 512: 20.3, 1024: 21.0,          2048: 22.1,          4096: 24.7},
    "ALiBi":       {256: 20.1, 512: 20.5, 1024: 21.2,          2048: 22.4,          4096: 24.1},
}

print(f"Perplexity at OOD lengths (trained on {train_len} tokens)")
print(f"{'Length':<10}", end="")
for name in results:
    print(f"{name:<18}", end="")
print()
print("-" * 82)

for L in test_lens:
    tag = "  (train)" if L == train_len else "  << OOD" if L > train_len else ""
    print(f"{L:<10}", end="")
    for name, ppl_map in results.items():
        val = ppl_map.get(L, float("nan"))
        s   = "inf" if math.isinf(val) else f"{val:.1f}"
        print(f"{s:<18}", end="")
    print(tag)

print()
print("Rank at OOD: RoPE > ALiBi > NoPE >> Absolute PE")
print("NoPE beats absolute PE because it avoids OOD position-index embeddings.")
```

## Code 3 — Analyzing Implicit Position via Attention Patterns

Inspecting what attention heads learn in a NoPE model by extracting the attention weight matrix. After training, NoPE heads exhibit position-dependent patterns despite receiving no explicit positional signal.

```python
import torch
import torch.nn.functional as F
import math
import numpy as np


def extract_attention_weights(block, x: torch.Tensor) -> torch.Tensor:
    """Compute attention weights (B, H, L, L) from a NoPEBlock without modifying it."""
    B, L, _ = x.shape
    h   = block.ln1(x)
    qkv = block.qkv(h).reshape(B, L, 3, block.n_heads, block.d_k).permute(2, 0, 3, 1, 4)
    Q, K, V = qkv[0], qkv[1], qkv[2]
    scores = torch.matmul(Q, K.transpose(-2, -1)) / math.sqrt(block.d_k)
    mask   = torch.triu(torch.ones(L, L, device=x.device), diagonal=1).bool()
    scores = scores.masked_fill(mask, float("-inf"))
    return F.softmax(scores, dim=-1)             # (B, H, L, L)


torch.manual_seed(0)
block = NoPEBlock(d_model=128, n_heads=4, d_ff=512)  # from Code 1
x     = torch.randn(1, 32, 128)                      # batch=1, seq_len=32
weights = extract_attention_weights(block, x)        # (1, 4, 32, 32)

positions = torch.arange(32, dtype=torch.float32)
print(f"{'Head':<8}{'Avg attended pos (q=16)':<30}{'Interpretation'}")
print("-" * 62)
for h in range(4):
    w        = weights[0, h, 16]                    # query at position 16
    avg_pos  = (w * positions).sum().item()         # weighted mean key position
    recency  = w[-5:].sum().item()                  # weight on last 5 tokens
    interp   = "local" if avg_pos > 12 else "global" if avg_pos < 8 else "mixed"
    print(f"{h+1:<8}{avg_pos:<30.2f}{interp} (recency mass={recency:.3f})")
print("\nAfter training, NoPE heads specialise into local/global roles via causal depth.")
```

## Code 4 — Ablation: Add or Remove PE from Decoder-Only LM

A controlled ablation that builds two decoder-only language models — one with standard absolute positional embedding, one with NoPE — and measures parameter counts and forward-pass validity at OOD lengths.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import math


class DecoderLM(nn.Module):
    """Minimal decoder-only LM; toggle positional embedding with use_pe."""

    def __init__(self, vocab_size: int, d_model: int, n_layers: int,
                 n_heads: int, d_ff: int, max_len: int = 2048, use_pe: bool = True):
        super().__init__()
        self.use_pe  = use_pe
        self.tok_emb = nn.Embedding(vocab_size, d_model)
        self.pos_emb = nn.Embedding(max_len, d_model) if use_pe else None
        self.blocks  = nn.ModuleList(
            [NoPEBlock(d_model, n_heads, d_ff) for _ in range(n_layers)]  # Code 1 block
        )
        self.ln_f = nn.LayerNorm(d_model)
        self.head = nn.Linear(d_model, vocab_size, bias=False)

    def forward(self, idx: torch.Tensor) -> torch.Tensor:
        B, L = idx.shape
        x = self.tok_emb(idx)                        # (B, L, d_model)
        if self.use_pe:
            positions = torch.arange(L, device=idx.device)
            x = x + self.pos_emb(positions)          # absolute PE added
        for block in self.blocks:
            x = block(x)
        return self.head(self.ln_f(x))               # (B, L, vocab_size)


# Ablation: compare parameter counts and OOD behaviour
vocab, d_model, max_len = 32000, 512, 2048
with_pe = DecoderLM(vocab, d_model, n_layers=4, n_heads=8, d_ff=2048,
                    max_len=max_len, use_pe=True)
nope_lm = DecoderLM(vocab, d_model, n_layers=4, n_heads=8, d_ff=2048,
                    max_len=max_len, use_pe=False)
pe_params = sum(p.numel() for p in with_pe.pos_emb.parameters())
print(f"PE params:   {pe_params:>10,}  ({max_len} x {d_model})")
print(f"With-PE tot: {sum(p.numel() for p in with_pe.parameters()):>10,}")
print(f"NoPE tot:    {sum(p.numel() for p in nope_lm.parameters()):>10,}")
# OOD test: sequence longer than max_len — NoPE passes, With-PE crashes
try:
    out = nope_lm(torch.zeros(1, 4096, dtype=torch.long))
    print(f"NoPE at L=4096: OK — output {out.shape}")
except Exception as e:
    print(f"NoPE error: {e}")
```

## Comparison Table

The four positional encoding strategies differ sharply in their extrapolation behaviour, parameter overhead, and suitability for bidirectional vs. decoder-only architectures. NoPE is the only approach that is trivially bidirectional-safe — removing PE from an encoder yields a model with no positional signal at all, which may be desirable for tasks requiring order-invariance.

| Method | Extrapolation rank | Bidirectional safe | Extra params | Mechanism | Recommended for |
| --- | --- | --- | --- | --- | --- |
| Absolute PE (learned) | 4th — hard failure beyond max_len | No — OOD at inference | max_len × d_model | Lookup table by position index | Short fixed-length tasks, BERT-style |
| NoPE | 3rd — moderate degradation | Yes — truly position-agnostic | 0 | Implicit via causal context depth | Length-variable decoding, ablation studies |
| ALiBi | 2nd — graceful linear decay | Partial — monotonic decay assumed | 0 | Linear distance penalty on logits | BLOOM-scale models, simple long-context |
| RoPE | 1st — best with interpolation | Yes (with bidirectional RoPE) | 0 | Rotation of Q/K by position angle | Modern LLMs: LLaMA, Mistral, Gemma |

## Summary and Recommendations

NoPE demonstrates that explicit positional encoding is not strictly necessary for autoregressive language modelling — causal masking alone provides enough implicit structure for models to learn order. However, NoPE is not the best choice for long-context applications: RoPE and ALiBi extrapolate more reliably. NoPE's value is primarily diagnostic: it establishes a lower bound on what PE-free models can do, and its surprising length generalisation advantage over absolute PE reveals how harmful OOD position embeddings are at long inference lengths. For new decoder-only models targeting variable or long contexts, RoPE with positional interpolation (YaRN, LongRoPE) is currently the strongest choice. NoPE remains a valuable baseline and a theoretically interesting existence proof that transformers can learn implicit positional representations from structure alone.

