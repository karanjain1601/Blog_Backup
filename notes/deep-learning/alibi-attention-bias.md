---
title: "ALiBi — Attention with Linear Biases for Length Generalization"
slug: "alibi-attention-bias"
description: "How ALiBi (Press et al. 2022) replaces positional embeddings with per-head linear distance penalties on attention logits, enabling train-short-test-long generalisation used in BLOOM-176B and MPT."
tags: ["deep-learning", "transformers", "positional-encoding"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"ALiBi (Attention with Linear Biases), introduced by Press et al. (2022), takes a radically simple approach to positional encoding: *do not add any positional information to the token embeddings at all*. Instead, subtract a linear bias from the raw attention logits at every layer and every head. The bias penalises attention to distant tokens in proportion to their distance, giving each head a built-in recency preference — zero learned positional parameters, zero embedding lookup, and a formula that remains valid at any sequence length."},{"type":"heading","level":2,"content":"The ALiBi Mechanism"},{"type":"text","content":"In standard scaled dot-product attention the logit for query position i attending to key position j is QᵢKⱼᵀ / √d_k. ALiBi modifies this to: score_alibi(i, j) = QᵢKⱼᵀ / √d_k − m·|i − j|, where m is a head-specific slope. The bias term depends only on the *relative* distance |i − j|, not on absolute position values. Crucially, this means the bias is valid at any absolute position — including positions 1025, 2048, or 8192 that were never seen during training on 1024-token sequences. No new embedding rows are needed for unseen positions; the distance formula extrapolates automatically."},{"type":"math","display":true,"content":"\\text{score\\_alibi}(i,j) = \\frac{Q_i K_j^{\\top}}{\\sqrt{d_k}} - m \\cdot |i - j|"},{"type":"heading","level":2,"content":"Geometric Slopes per Head"},{"type":"text","content":"Each attention head uses a different slope m drawn from a geometric sequence. For h heads, the slopes are: m_k = 2^{−8k/h} for k = 1, …, h. This gives a sequence from 2^{−8/h} (shallowest, global head) down to 2^{−8} (steepest, local head) — the paper reverses the indexing so head 1 is steepest and the last head is shallowest. Head 1 sharply penalises distance; a token at distance 10 receives a bias of −10m₁ which is very negative. The last head\u0027s shallow slope means distant tokens still receive near-zero bias and can contribute meaningfully. This diversity lets the model capture both local syntactic cues and long-range semantic dependencies simultaneously across heads."},{"type":"list","ordered":false,"items":["Head 1 (steepest slope m = 2^{-8}): effectively a local attention window of a few tokens","Head h (shallowest slope m = 2^{-8/h}): can attend globally with small distance penalty","Slopes are fixed at initialisation — never updated by gradient descent","Bias is a lower-triangular matrix combined with the causal mask at each layer","The bias tensor is computed on-the-fly for each sequence length — no max-length cap"]},{"type":"heading","level":2,"content":"Code 1 — ALiBi Bias Computation"},{"type":"text","content":"Computing the geometric slope sequence and building the full (n_heads × seq_len × seq_len) bias tensor. The implementation handles non-power-of-2 head counts by interpolating extra intermediate slopes."},{"type":"code","language":"python","content":"import torch\nimport math\n\n\ndef get_alibi_slopes(n_heads: int) -\u003e torch.Tensor:\n    \"\"\"Geometric sequence: {2^{-8/h}, 2^{-8*2/h}, ..., 2^{-8}} for h heads.\"\"\"\n    # Use largest power of 2 \u003c= n_heads as the base count\n    n = 2 ** math.floor(math.log2(n_heads))\n    m0 = 2 ** (-8 / n)                           # base step ratio\n    slopes = torch.tensor([m0 ** i for i in range(1, n + 1)], dtype=torch.float32)\n    if n \u003c n_heads:                               # non-power-of-2: interpolate extras\n        extra = torch.tensor(\n            [m0 ** (i / 2) for i in range(1, 2 * (n_heads - n) + 1, 2)],\n            dtype=torch.float32,\n        )\n        slopes = torch.cat([slopes, extra], dim=0)\n    return slopes  # shape (n_heads,)\n\n\ndef compute_alibi_bias(n_heads: int, seq_len: int) -\u003e torch.Tensor:\n    \"\"\"Return ALiBi bias tensor of shape (n_heads, seq_len, seq_len).\"\"\"\n    slopes = get_alibi_slopes(n_heads)            # (H,)\n    pos    = torch.arange(seq_len, dtype=torch.float32)\n    dist   = (pos.unsqueeze(0) - pos.unsqueeze(1)).abs()   # |i-j| matrix (L, L)\n    # (H, 1, 1) * (1, L, L) =\u003e (H, L, L)\n    return -slopes.view(n_heads, 1, 1) * dist.unsqueeze(0)\n\n\n# Example: 8 heads, sequence length 16\nbias   = compute_alibi_bias(8, 16)\nslopes = get_alibi_slopes(8)\nprint(\"Bias shape:\", bias.shape)                  # (8, 16, 16)\nprint(\"Slopes:\", slopes.numpy().round(5))\nprint(\"Head 0 bias at dist=8 (steepest):\",  bias[0, 8, 0].item())\nprint(\"Head 7 bias at dist=8 (shallowest):\", bias[7, 8, 0].item())"},{"type":"heading","level":2,"content":"Code 2 — ALiBi Inside Multi-Head Attention"},{"type":"text","content":"Integrating the ALiBi bias tensor into a full multi-head attention module. The bias is added to raw attention logits *before* softmax. No modification to Q, K, or V projections is needed — the token embeddings remain position-free."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport math\n\n\nclass ALiBiMultiHeadAttention(nn.Module):\n    \"\"\"Multi-head attention that uses ALiBi logit biases instead of positional embeddings.\"\"\"\n\n    def __init__(self, d_model: int, n_heads: int):\n        super().__init__()\n        assert d_model % n_heads == 0\n        self.n_heads = n_heads\n        self.d_k  = d_model // n_heads\n        self.qkv  = nn.Linear(d_model, 3 * d_model, bias=False)\n        self.proj = nn.Linear(d_model, d_model, bias=False)\n        slopes = self._make_slopes(n_heads)\n        self.register_buffer(\"slopes\", slopes)   # fixed, never trained\n\n    @staticmethod\n    def _make_slopes(n: int) -\u003e torch.Tensor:\n        base = 2 ** (-8 / (2 ** math.floor(math.log2(n))))\n        return torch.tensor([base ** i for i in range(1, n + 1)], dtype=torch.float32)\n\n    def _alibi_bias(self, seq_len: int) -\u003e torch.Tensor:\n        pos  = torch.arange(seq_len, device=self.slopes.device, dtype=torch.float32)\n        dist = (pos.unsqueeze(0) - pos.unsqueeze(1)).abs()          # (L, L)\n        return -self.slopes.view(-1, 1, 1) * dist.unsqueeze(0)      # (H, L, L)\n\n    def forward(self, x: torch.Tensor, causal: bool = True) -\u003e torch.Tensor:\n        B, L, _ = x.shape\n        qkv = self.qkv(x).reshape(B, L, 3, self.n_heads, self.d_k).permute(2, 0, 3, 1, 4)\n        Q, K, V = qkv[0], qkv[1], qkv[2]\n        scores = torch.matmul(Q, K.transpose(-2, -1)) / math.sqrt(self.d_k)\n        scores = scores + self._alibi_bias(L)    # \u003c-- ALiBi bias injected here\n        if causal:\n            mask = torch.triu(torch.ones(L, L, device=x.device), diagonal=1).bool()\n            scores = scores.masked_fill(mask, float(\"-inf\"))\n        out = torch.matmul(F.softmax(scores, dim=-1), V)\n        return self.proj(out.transpose(1, 2).reshape(B, L, -1))"},{"type":"callout","variant":"info","title":"Recency Bias Is Built In","content":"ALiBi\u0027s linear penalty creates a fixed recency advantage: the immediately preceding token (distance 1) receives a bias of −m, while a token at distance 100 receives −100m. This is a hardcoded inductive bias — the model cannot learn to attend uniformly at all distances. For retrieval-style tasks where a relevant token may be far away and needs high attention weight regardless of position, this monotonic decay is a meaningful limitation."},{"type":"heading","level":2,"content":"Train Short, Test Long — Extrapolation"},{"type":"text","content":"The critical advantage of ALiBi over sinusoidal and learned positional embeddings is its behaviour at sequence lengths beyond the training window. Sinusoidal PE is theoretically unbounded but introduces a distribution shift at inference because the model rarely sees the longest-range sinusoidal patterns during training. Learned PE cannot generalise at all to positions beyond max_train_len. ALiBi\u0027s bias depends only on relative distance, so evaluating at length 2048 when trained on 1024 tokens is handled seamlessly: the maximum distance increases, but the formula is unchanged."},{"type":"code","language":"python","content":"import math\n\n# Approximate perplexity results from Press et al. (2022) Table 1\n# All models trained on sequences of length 1024 (WikiText-103)\n\ntrain_len = 1024\ntest_lens  = [512, 1024, 2048, 4096, 8192]\n\nresults = {\n    \"Sinusoidal PE\": {512: 17.5, 1024: 17.8, 2048: 23.9, 4096: 38.4, 8192: float(\"inf\")},\n    \"Learned PE\":    {512: 17.3, 1024: 17.6, 2048: float(\"inf\"), 4096: float(\"inf\"), 8192: float(\"inf\")},\n    \"ALiBi\":         {512: 17.6, 1024: 17.9, 2048: 18.3, 4096: 19.0, 8192: 20.5},\n}\n\nprint(f\"Perplexity at Various Lengths (trained on {train_len} tokens)\")\nprint(f\"{\u0027Length\u0027:\u003c10}\", end=\"\")\nfor name in results:\n    print(f\"{name:\u003c20}\", end=\"\")\nprint()\nprint(\"-\" * 70)\n\nfor L in test_lens:\n    tag = \"  (train)\" if L == train_len else \"  OOD\" if L \u003e train_len else \"\"\n    print(f\"{L:\u003c10}\", end=\"\")\n    for name, ppl_map in results.items():\n        val = ppl_map.get(L, float(\"nan\"))\n        s   = \"inf\" if math.isinf(val) else f\"{val:.1f}\"\n        print(f\"{s:\u003c20}\", end=\"\")\n    print(tag)\n\nprint()\nprint(\"ALiBi degrades gracefully. Learned PE fails completely at OOD lengths.\")\nprint(\"Sinusoidal PE degrades sharply beyond 2x training length.\")"},{"type":"heading","level":2,"content":"Code 4 — Per-Head Slope Visualization"},{"type":"text","content":"Visualising how each head\u0027s slope controls the effective attention window size. A steep slope makes the model tightly locally focused; a shallow slope allows globally distributed attention over hundreds of tokens."},{"type":"code","language":"python","content":"import math\nimport numpy as np\nimport matplotlib.pyplot as plt\n\n\ndef get_alibi_slopes(n_heads: int) -\u003e list:\n    n  = 2 ** math.floor(math.log2(n_heads))\n    m0 = 2 ** (-8 / n)\n    slopes = [m0 ** i for i in range(1, n + 1)]\n    if n \u003c n_heads:\n        slopes += [m0 ** (i / 2) for i in range(1, 2 * (n_heads - n) + 1, 2)]\n    return slopes\n\n\nn_heads   = 8\nmax_dist  = 64\nslopes    = get_alibi_slopes(n_heads)\ndistances = np.arange(max_dist)\n\nfig, axes = plt.subplots(2, 4, figsize=(14, 5), sharey=True)\naxes = axes.flatten()\nfor h, (ax, m) in enumerate(zip(axes, slopes)):\n    bias = -m * distances\n    ax.plot(distances, bias, color=f\"C{h}\", linewidth=2)\n    ax.set_title(f\"Head {h+1}  m={m:.5f}\", fontsize=9)\n    ax.set_xlabel(\"|i - j| distance\")\n    if h % 4 == 0:\n        ax.set_ylabel(\"logit bias\")\nplt.suptitle(\"ALiBi Per-Head Linear Decay (8 heads)\", fontsize=12, y=1.01)\nplt.tight_layout()\nplt.savefig(\"alibi_slopes.png\", dpi=120, bbox_inches=\"tight\")\n\nprint(f\"{\u0027Head\u0027:\u003c8}{\u0027Slope m\u0027:\u003c15}{\u0027bias at dist=10\u0027:\u003c20}{\u0027Attention character\u0027}\")\nprint(\"-\" * 58)\nchars = [\"Very local\", \"Local\", \"Local\", \"Moderate\",\n         \"Moderate\", \"Semi-global\", \"Semi-global\", \"Global\"]\nfor h, (m, c) in enumerate(zip(slopes, chars)):\n    print(f\"{h+1:\u003c8}{m:\u003c15.6f}{-m*10:\u003c20.4f}{c}\")"},{"type":"heading","level":2,"content":"Comparison of Positional Encoding Methods"},{"type":"text","content":"ALiBi occupies a unique niche: zero trainable parameters, no embedding lookup, and graceful extrapolation beyond the training length. The tradeoff is a hardcoded monotonic decay that cannot learn non-monotonic attention patterns. The table below compares five approaches across properties relevant to deployment."},{"type":"table","headers":["Method","Train-short test-long","Params","Implementation","Monotonic decay","Used in"],"rows":[["Sinusoidal","Poor — distribution shift","0","Low","No","Original Transformer, BART"],["Learned Absolute","None — hard OOD failure","max_len × d_model","Low","No","BERT, GPT-2, early GPT-3"],["RoPE","Good — rotary relative PE","0","Medium","No (rotary)","LLaMA 1/2/3, Mistral, Falcon"],["ALiBi","Very good — linear decay","0","Low","Yes (hardcoded)","BLOOM-176B, MPT-7B, OPT variants"],["NoPE","Moderate — implicit causal","0","Trivial (remove PE)","N/A","Research ablations, decoder studies"]]},{"type":"text","content":"ALiBi was adopted in BLOOM-176B (the first open multilingual 100B+ model), the Mosaic MPT family, and several OPT variants. Its zero-parameter overhead and minimal implementation changes made it attractive at scale. As of 2024, RoPE has largely displaced ALiBi in new large models due to RoPE\u0027s superior long-context performance when combined with positional interpolation techniques like YaRN or LongRoPE. ALiBi\u0027s primary limitation — hardcoded monotonic decay — becomes significant in retrieval-augmented tasks where the relevant passage is far from the current generation position and must receive high attention weight regardless of distance."}]"
---
# ALiBi — Attention with Linear Biases for Length Generalization

ALiBi (Attention with Linear Biases), introduced by Press et al. (2022), takes a radically simple approach to positional encoding: *do not add any positional information to the token embeddings at all*. Instead, subtract a linear bias from the raw attention logits at every layer and every head. The bias penalises attention to distant tokens in proportion to their distance, giving each head a built-in recency preference — zero learned positional parameters, zero embedding lookup, and a formula that remains valid at any sequence length.

## The ALiBi Mechanism

In standard scaled dot-product attention the logit for query position i attending to key position j is QᵢKⱼᵀ / √d_k. ALiBi modifies this to: score_alibi(i, j) = QᵢKⱼᵀ / √d_k − m·|i − j|, where m is a head-specific slope. The bias term depends only on the *relative* distance |i − j|, not on absolute position values. Crucially, this means the bias is valid at any absolute position — including positions 1025, 2048, or 8192 that were never seen during training on 1024-token sequences. No new embedding rows are needed for unseen positions; the distance formula extrapolates automatically.

$$\text{score\_alibi}(i,j) = \frac{Q_i K_j^{\top}}{\sqrt{d_k}} - m \cdot |i - j|$$

## Geometric Slopes per Head

Each attention head uses a different slope m drawn from a geometric sequence. For h heads, the slopes are: m_k = 2^{−8k/h} for k = 1, …, h. This gives a sequence from 2^{−8/h} (shallowest, global head) down to 2^{−8} (steepest, local head) — the paper reverses the indexing so head 1 is steepest and the last head is shallowest. Head 1 sharply penalises distance; a token at distance 10 receives a bias of −10m₁ which is very negative. The last head's shallow slope means distant tokens still receive near-zero bias and can contribute meaningfully. This diversity lets the model capture both local syntactic cues and long-range semantic dependencies simultaneously across heads.

- Head 1 (steepest slope m = 2^{-8}): effectively a local attention window of a few tokens
- Head h (shallowest slope m = 2^{-8/h}): can attend globally with small distance penalty
- Slopes are fixed at initialisation — never updated by gradient descent
- Bias is a lower-triangular matrix combined with the causal mask at each layer
- The bias tensor is computed on-the-fly for each sequence length — no max-length cap

## Code 1 — ALiBi Bias Computation

Computing the geometric slope sequence and building the full (n_heads × seq_len × seq_len) bias tensor. The implementation handles non-power-of-2 head counts by interpolating extra intermediate slopes.

```python
import torch
import math


def get_alibi_slopes(n_heads: int) -> torch.Tensor:
    """Geometric sequence: {2^{-8/h}, 2^{-8*2/h}, ..., 2^{-8}} for h heads."""
    # Use largest power of 2 <= n_heads as the base count
    n = 2 ** math.floor(math.log2(n_heads))
    m0 = 2 ** (-8 / n)                           # base step ratio
    slopes = torch.tensor([m0 ** i for i in range(1, n + 1)], dtype=torch.float32)
    if n < n_heads:                               # non-power-of-2: interpolate extras
        extra = torch.tensor(
            [m0 ** (i / 2) for i in range(1, 2 * (n_heads - n) + 1, 2)],
            dtype=torch.float32,
        )
        slopes = torch.cat([slopes, extra], dim=0)
    return slopes  # shape (n_heads,)


def compute_alibi_bias(n_heads: int, seq_len: int) -> torch.Tensor:
    """Return ALiBi bias tensor of shape (n_heads, seq_len, seq_len)."""
    slopes = get_alibi_slopes(n_heads)            # (H,)
    pos    = torch.arange(seq_len, dtype=torch.float32)
    dist   = (pos.unsqueeze(0) - pos.unsqueeze(1)).abs()   # |i-j| matrix (L, L)
    # (H, 1, 1) * (1, L, L) => (H, L, L)
    return -slopes.view(n_heads, 1, 1) * dist.unsqueeze(0)


# Example: 8 heads, sequence length 16
bias   = compute_alibi_bias(8, 16)
slopes = get_alibi_slopes(8)
print("Bias shape:", bias.shape)                  # (8, 16, 16)
print("Slopes:", slopes.numpy().round(5))
print("Head 0 bias at dist=8 (steepest):",  bias[0, 8, 0].item())
print("Head 7 bias at dist=8 (shallowest):", bias[7, 8, 0].item())
```

## Code 2 — ALiBi Inside Multi-Head Attention

Integrating the ALiBi bias tensor into a full multi-head attention module. The bias is added to raw attention logits *before* softmax. No modification to Q, K, or V projections is needed — the token embeddings remain position-free.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import math


class ALiBiMultiHeadAttention(nn.Module):
    """Multi-head attention that uses ALiBi logit biases instead of positional embeddings."""

    def __init__(self, d_model: int, n_heads: int):
        super().__init__()
        assert d_model % n_heads == 0
        self.n_heads = n_heads
        self.d_k  = d_model // n_heads
        self.qkv  = nn.Linear(d_model, 3 * d_model, bias=False)
        self.proj = nn.Linear(d_model, d_model, bias=False)
        slopes = self._make_slopes(n_heads)
        self.register_buffer("slopes", slopes)   # fixed, never trained

    @staticmethod
    def _make_slopes(n: int) -> torch.Tensor:
        base = 2 ** (-8 / (2 ** math.floor(math.log2(n))))
        return torch.tensor([base ** i for i in range(1, n + 1)], dtype=torch.float32)

    def _alibi_bias(self, seq_len: int) -> torch.Tensor:
        pos  = torch.arange(seq_len, device=self.slopes.device, dtype=torch.float32)
        dist = (pos.unsqueeze(0) - pos.unsqueeze(1)).abs()          # (L, L)
        return -self.slopes.view(-1, 1, 1) * dist.unsqueeze(0)      # (H, L, L)

    def forward(self, x: torch.Tensor, causal: bool = True) -> torch.Tensor:
        B, L, _ = x.shape
        qkv = self.qkv(x).reshape(B, L, 3, self.n_heads, self.d_k).permute(2, 0, 3, 1, 4)
        Q, K, V = qkv[0], qkv[1], qkv[2]
        scores = torch.matmul(Q, K.transpose(-2, -1)) / math.sqrt(self.d_k)
        scores = scores + self._alibi_bias(L)    # <-- ALiBi bias injected here
        if causal:
            mask = torch.triu(torch.ones(L, L, device=x.device), diagonal=1).bool()
            scores = scores.masked_fill(mask, float("-inf"))
        out = torch.matmul(F.softmax(scores, dim=-1), V)
        return self.proj(out.transpose(1, 2).reshape(B, L, -1))
```

> **Recency Bias Is Built In**: ALiBi's linear penalty creates a fixed recency advantage: the immediately preceding token (distance 1) receives a bias of −m, while a token at distance 100 receives −100m. This is a hardcoded inductive bias — the model cannot learn to attend uniformly at all distances. For retrieval-style tasks where a relevant token may be far away and needs high attention weight regardless of position, this monotonic decay is a meaningful limitation.

## Train Short, Test Long — Extrapolation

The critical advantage of ALiBi over sinusoidal and learned positional embeddings is its behaviour at sequence lengths beyond the training window. Sinusoidal PE is theoretically unbounded but introduces a distribution shift at inference because the model rarely sees the longest-range sinusoidal patterns during training. Learned PE cannot generalise at all to positions beyond max_train_len. ALiBi's bias depends only on relative distance, so evaluating at length 2048 when trained on 1024 tokens is handled seamlessly: the maximum distance increases, but the formula is unchanged.

```python
import math

# Approximate perplexity results from Press et al. (2022) Table 1
# All models trained on sequences of length 1024 (WikiText-103)

train_len = 1024
test_lens  = [512, 1024, 2048, 4096, 8192]

results = {
    "Sinusoidal PE": {512: 17.5, 1024: 17.8, 2048: 23.9, 4096: 38.4, 8192: float("inf")},
    "Learned PE":    {512: 17.3, 1024: 17.6, 2048: float("inf"), 4096: float("inf"), 8192: float("inf")},
    "ALiBi":         {512: 17.6, 1024: 17.9, 2048: 18.3, 4096: 19.0, 8192: 20.5},
}

print(f"Perplexity at Various Lengths (trained on {train_len} tokens)")
print(f"{'Length':<10}", end="")
for name in results:
    print(f"{name:<20}", end="")
print()
print("-" * 70)

for L in test_lens:
    tag = "  (train)" if L == train_len else "  OOD" if L > train_len else ""
    print(f"{L:<10}", end="")
    for name, ppl_map in results.items():
        val = ppl_map.get(L, float("nan"))
        s   = "inf" if math.isinf(val) else f"{val:.1f}"
        print(f"{s:<20}", end="")
    print(tag)

print()
print("ALiBi degrades gracefully. Learned PE fails completely at OOD lengths.")
print("Sinusoidal PE degrades sharply beyond 2x training length.")
```

## Code 4 — Per-Head Slope Visualization

Visualising how each head's slope controls the effective attention window size. A steep slope makes the model tightly locally focused; a shallow slope allows globally distributed attention over hundreds of tokens.

```python
import math
import numpy as np
import matplotlib.pyplot as plt


def get_alibi_slopes(n_heads: int) -> list:
    n  = 2 ** math.floor(math.log2(n_heads))
    m0 = 2 ** (-8 / n)
    slopes = [m0 ** i for i in range(1, n + 1)]
    if n < n_heads:
        slopes += [m0 ** (i / 2) for i in range(1, 2 * (n_heads - n) + 1, 2)]
    return slopes


n_heads   = 8
max_dist  = 64
slopes    = get_alibi_slopes(n_heads)
distances = np.arange(max_dist)

fig, axes = plt.subplots(2, 4, figsize=(14, 5), sharey=True)
axes = axes.flatten()
for h, (ax, m) in enumerate(zip(axes, slopes)):
    bias = -m * distances
    ax.plot(distances, bias, color=f"C{h}", linewidth=2)
    ax.set_title(f"Head {h+1}  m={m:.5f}", fontsize=9)
    ax.set_xlabel("|i - j| distance")
    if h % 4 == 0:
        ax.set_ylabel("logit bias")
plt.suptitle("ALiBi Per-Head Linear Decay (8 heads)", fontsize=12, y=1.01)
plt.tight_layout()
plt.savefig("alibi_slopes.png", dpi=120, bbox_inches="tight")

print(f"{'Head':<8}{'Slope m':<15}{'bias at dist=10':<20}{'Attention character'}")
print("-" * 58)
chars = ["Very local", "Local", "Local", "Moderate",
         "Moderate", "Semi-global", "Semi-global", "Global"]
for h, (m, c) in enumerate(zip(slopes, chars)):
    print(f"{h+1:<8}{m:<15.6f}{-m*10:<20.4f}{c}")
```

## Comparison of Positional Encoding Methods

ALiBi occupies a unique niche: zero trainable parameters, no embedding lookup, and graceful extrapolation beyond the training length. The tradeoff is a hardcoded monotonic decay that cannot learn non-monotonic attention patterns. The table below compares five approaches across properties relevant to deployment.

| Method | Train-short test-long | Params | Implementation | Monotonic decay | Used in |
| --- | --- | --- | --- | --- | --- |
| Sinusoidal | Poor — distribution shift | 0 | Low | No | Original Transformer, BART |
| Learned Absolute | None — hard OOD failure | max_len × d_model | Low | No | BERT, GPT-2, early GPT-3 |
| RoPE | Good — rotary relative PE | 0 | Medium | No (rotary) | LLaMA 1/2/3, Mistral, Falcon |
| ALiBi | Very good — linear decay | 0 | Low | Yes (hardcoded) | BLOOM-176B, MPT-7B, OPT variants |
| NoPE | Moderate — implicit causal | 0 | Trivial (remove PE) | N/A | Research ablations, decoder studies |

ALiBi was adopted in BLOOM-176B (the first open multilingual 100B+ model), the Mosaic MPT family, and several OPT variants. Its zero-parameter overhead and minimal implementation changes made it attractive at scale. As of 2024, RoPE has largely displaced ALiBi in new large models due to RoPE's superior long-context performance when combined with positional interpolation techniques like YaRN or LongRoPE. ALiBi's primary limitation — hardcoded monotonic decay — becomes significant in retrieval-augmented tasks where the relevant passage is far from the current generation position and must receive high attention weight regardless of distance.

