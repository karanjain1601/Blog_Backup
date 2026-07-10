---
title: "Feed-Forward Sublayer — Position-Wise MLP in Transformers"
slug: "feed-forward-sublayer"
description: "The position-wise FFN sub-layer: dimensions, parameter budget, the FFN-as-associative-memory interpretation, and the activation function evolution from ReLU to SwiGLU."
tags: ["deep-learning", "transformers"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Every Transformer block contains two sub-layers: multi-head attention and a position-wise feed-forward network (FFN). While attention mixes information across token positions, the FFN processes each position independently with the same two-layer MLP applied identically to all positions. Despite its simplicity, the FFN typically accounts for two-thirds of a large Transformer\u0027s parameters and a substantial fraction of its inference compute."},{"type":"heading","level":2,"content":"Position-Wise FFN — Same MLP at Every Position"},{"type":"text","content":"The standard FFN is defined as FFN(x) = Activation(x W₁ + b₁) W₂ + b₂. Here x has shape (B, L, d_model), and the FFN is applied identically at every token position — the MLP weights are shared across positions, not across layers. The inner dimension d_ff is typically set to 4 × d_model, giving a bottleneck structure: the hidden state expands from d_model to d_ff, passes through the non-linearity, then contracts back to d_model. This 4× ratio is an empirical choice from Vaswani 2017 that has remained surprisingly durable."},{"type":"list","ordered":false,"items":["d_model = 512 → d_ff = 2048 (4×) — standard Transformer original","d_model = 768 → d_ff = 3072 (4×) — BERT-base","d_model = 1024 → d_ff = 4096 (4×) — BERT-large, GPT-2 medium","Parameter count: W₁ is d_model × d_ff, W₂ is d_ff × d_model → 2 · d_model · d_ff total","For d_model=512, d_ff=2048: FFN has 2,097,152 params vs ~786,432 for attention"]},{"type":"callout","variant":"info","title":"FFN Parameters Dominate in Large Models","content":"In a standard Transformer with d_model=512 and d_ff=2048, each FFN block has ~2M parameters while each attention block has ~786K parameters — about 2.7× more in the FFN. Across all layers, the FFN accounts for roughly two-thirds of total non-embedding parameters. This ratio worsens as models grow: GPT-3\u0027s 175B parameters are predominantly in FFN layers."},{"type":"heading","level":2,"content":"FFN as Associative Memory (Geva et al. 2021)"},{"type":"text","content":"Geva et al. (2021) proposed a compelling interpretation: the rows of W₁ act as \u0027keys\u0027 and the rows of W₂ᵀ act as \u0027values\u0027. The input x is compared against all keys via the linear projection xW₁; positions with high dot-product activate after the ReLU (or GELU) non-linearity. The activated hidden units then select corresponding value vectors from W₂, blending them into the output. This is a continuous, soft key-value lookup — the FFN retrieves factual associations (e.g., capital cities, common collocations) stored in its weights during pretraining."},{"type":"heading","level":2,"content":"Activation Functions — From ReLU to SwiGLU"},{"type":"text","content":"The original Transformer used ReLU. GPT-2 switched to GELU, which is smoother and avoids the dead-neuron problem of ReLU. More recently, gated variants (SwiGLU, GEGLU, ReGLU) have become standard in frontier LLMs. These use three matrices instead of two, where one branch acts as a multiplicative gate controlling information flow. Shazeer (2020) showed that gated variants consistently outperform ReLU and GELU at the same parameter and compute budget."},{"type":"heading","level":2,"content":"Code 1 — FFN Block from Scratch"},{"type":"text","content":"A clean position-wise FFN implementation with configurable activation, showing how FFN parameter count compares to attention parameter count."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass FeedForwardBlock(nn.Module):\n    \"\"\"Position-wise FFN: FFN(x) = Dropout(Act(x W1 + b1) W2 + b2).\n    Same MLP applied independently to every token position.\n    d_ff defaults to 4 * d_model (the standard ratio from Vaswani 2017).\n    \"\"\"\n    def __init__(self, d_model: int, d_ff: int = None,\n                 dropout: float = 0.1, activation: str = \u0027gelu\u0027):\n        super().__init__()\n        d_ff       = d_ff or 4 * d_model\n        self.fc1   = nn.Linear(d_model, d_ff)\n        self.fc2   = nn.Linear(d_ff, d_model)\n        self.drop  = nn.Dropout(dropout)\n        self.act   = {\u0027relu\u0027: F.relu, \u0027gelu\u0027: F.gelu}[activation]\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        return self.fc2(self.drop(self.act(self.fc1(x))))\n\n# Compare parameter counts: FFN vs attention\nd_model, d_ff = 512, 2048\nffn   = FeedForwardBlock(d_model, d_ff)\nattn  = nn.MultiheadAttention(d_model, num_heads=8, batch_first=True)\np_ffn  = sum(p.numel() for p in ffn.parameters())\np_attn = sum(p.numel() for p in attn.parameters())\nprint(f\u0027d_model={d_model}, d_ff={d_ff}\u0027)\nprint(f\u0027FFN params:  {p_ffn:,}  ({p_ffn/(p_ffn+p_attn)*100:.1f}% of FFN+Attn)\u0027)\nprint(f\u0027Attn params: {p_attn:,} ({p_attn/(p_ffn+p_attn)*100:.1f}% of FFN+Attn)\u0027)\nx   = torch.randn(2, 10, d_model)\nout = ffn(x)\nprint(f\u0027Output shape: {out.shape}  (position-wise: same as input)\u0027)"},{"type":"heading","level":2,"content":"Code 2 — Gated FFN (SwiGLU Variant)"},{"type":"text","content":"SwiGLU uses three weight matrices: a gate branch (W₁, through SiLU), a value branch (W₂, linear), and a down-projection (W₃). The hidden dimension is reduced to 2/3 of the standard d_ff to keep parameter counts equivalent."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass SwiGLUFFN(nn.Module):\n    \"\"\"SwiGLU (Shazeer 2020): FFN(x) = (SiLU(x W1) * x W2) W3.\n    Three matrices; d_ff adjusted to 2/3 of standard to match param count.\n    SiLU(x) = x * sigmoid(x)  (also called Swish).\n    Used in: LLaMA 1/2/3, Mistral, PaLM, Gemma.\n    \"\"\"\n    def __init__(self, d_model: int, d_ff: int = None, dropout: float = 0.0):\n        super().__init__()\n        d_ff       = d_ff or int(4 * d_model * 2 / 3)\n        self.W1    = nn.Linear(d_model, d_ff, bias=False)   # gate\n        self.W2    = nn.Linear(d_model, d_ff, bias=False)   # value\n        self.W3    = nn.Linear(d_ff,   d_model, bias=False) # down\n        self.drop  = nn.Dropout(dropout)\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        gate  = F.silu(self.W1(x))       # SiLU gate branch\n        value = self.W2(x)               # linear value branch\n        return self.W3(self.drop(gate * value))\n\n# Verify shapes and parameter count vs standard FFN\nd_model = 512\nswi     = SwiGLUFFN(d_model)\nstd_p   = 2 * d_model * (4 * d_model)   # standard 2-matrix FFN\nswi_p   = sum(p.numel() for p in swi.parameters())\nprint(f\u0027Standard FFN params (2 mats, d_ff={4*d_model}):  {std_p:,}\u0027)\nprint(f\u0027SwiGLU FFN  params (3 mats, d_ff={int(4*d_model*2/3)}): {swi_p:,}\u0027)\nprint(f\u0027Ratio: {swi_p / std_p:.3f}  (target close to 1.000)\u0027)\nx   = torch.randn(2, 10, d_model)\nout = swi(x)\nprint(f\u0027Output shape: {out.shape}\u0027)"},{"type":"heading","level":2,"content":"Code 3 — FFN as Associative Memory"},{"type":"text","content":"Demonstrating the Geva et al. (2021) key-value memory interpretation: a known key pattern stored in W₁ row 3 causes high activation there, and the corresponding W₂ column is retrieved as the output value."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\n# Geva et al. (2021): FFN rows of W1 = keys, columns of W2 = values\ntorch.manual_seed(42)\nd_in, d_ff, d_out = 8, 16, 8\n\nW1 = nn.Linear(d_in, d_ff, bias=False)    # key matrix  (d_ff x d_in rows)\nW2 = nn.Linear(d_ff, d_out, bias=False)   # value matrix\n\n# Plant a memory: key 3 -\u003e value vector\ntarget_key   = torch.randn(d_in)\ntarget_value = torch.randn(d_out)\nwith torch.no_grad():\n    W1.weight[3]    = target_key          # row 3 of W1 = the key\n    W2.weight[:, 3] = target_value       # column 3 of W2 = the value\n\n# Query with the planted key pattern\nx_query     = target_key.unsqueeze(0)    # (1, d_in)\nactivations = F.relu(W1(x_query))        # key pattern activates key 3 strongly\nprint(\u0027Activations (should be highest at index 3):\u0027)\nprint(activations.detach().numpy().round(3))\nprint(\u0027Max activation at index:\u0027, activations.argmax().item())\n\nretrieved = W2(activations)\nprint(\u0027\\nRetrieved:\u0027, retrieved.detach().numpy().round(3))\nprint(\u0027Target:   \u0027, target_value.numpy().round(3))\ncos = F.cosine_similarity(retrieved, target_value.unsqueeze(0))\nprint(f\u0027Cosine similarity: {cos.item():.4f}  (high = successful retrieval)\u0027)"},{"type":"heading","level":2,"content":"Code 4 — Profiling FFN vs Attention Compute Budget"},{"type":"text","content":"Empirically timing FFN and self-attention on the same batch to quantify their relative compute costs, showing the FFN dominates at large d_ff."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport time\n\ndef time_module(module: nn.Module, x: torch.Tensor,\n                n_runs: int = 100, label: str = \u0027\u0027) -\u003e float:\n    module.eval()\n    with torch.no_grad():\n        for _ in range(10):      # warm-up\n            _ = module(x)\n        t0 = time.perf_counter()\n        for _ in range(n_runs):\n            _ = module(x)\n        ms = (time.perf_counter() - t0) / n_runs * 1000\n    print(f\u0027{label:\u003c28}: {ms:.3f} ms/pass\u0027)\n    return ms\n\nd_model, n_heads, d_ff = 512, 8, 2048\nB, L = 4, 128\n\nffn = nn.Sequential(\n    nn.Linear(d_model, d_ff), nn.GELU(), nn.Linear(d_ff, d_model)\n)\n\nclass AttnWrapper(nn.Module):\n    def __init__(self, d, h): super().__init__(); self.a = nn.MultiheadAttention(d, h, batch_first=True)\n    def forward(self, x): return self.a(x, x, x)[0]\n\nx_ffn  = torch.randn(B, L, d_model)\nx_attn = torch.randn(B, L, d_model)\n\nt_ffn  = time_module(ffn, x_ffn, label=f\u0027FFN (d_ff={d_ff})\u0027)\nt_attn = time_module(AttnWrapper(d_model, n_heads), x_attn, label=\u0027Self-Attention\u0027)\nprint(f\u0027FFN / Attn time ratio: {t_ffn/t_attn:.2f}x  (d_model={d_model}, L={L})\u0027)"},{"type":"heading","level":2,"content":"FFN Variants Compared"},{"type":"table","headers":["Variant","Activation","Matrices","d_ff Ratio","Used In"],"rows":[["Standard ReLU","ReLU","2","4× d_model","Original Transformer, early BERT"],["Standard GELU","GELU","2","4× d_model","GPT-2, BERT, RoBERTa"],["SwiGLU","SiLU (Swish) gate","3","~8/3× d_model","LLaMA 1/2/3, Mistral, PaLM, Gemma"],["ReGLU","ReLU gate","3","≤4× d_model","Research models (Shazeer 2020)"],["GEGLU","GELU gate","3","≤4× d_model","T5 variants, some BERT successors"],["Sparse MoE","Any (per expert)","2 per expert","k active of n experts","Mixtral, Switch Transformer"]]},{"type":"text","content":"The FFN sub-layer is deceptively simple but plays a central role: it provides per-token non-linear transformation after each attention operation, storing factual knowledge in its weights and acting as the model\u0027s memory. The evolution from ReLU to GELU to gated variants (SwiGLU) represents consistent empirical wins at the same compute budget — a rare case where a drop-in change reliably improves quality without increasing FLOPs."}]"
---
# Feed-Forward Sublayer — Position-Wise MLP in Transformers

Every Transformer block contains two sub-layers: multi-head attention and a position-wise feed-forward network (FFN). While attention mixes information across token positions, the FFN processes each position independently with the same two-layer MLP applied identically to all positions. Despite its simplicity, the FFN typically accounts for two-thirds of a large Transformer's parameters and a substantial fraction of its inference compute.

## Position-Wise FFN — Same MLP at Every Position

The standard FFN is defined as FFN(x) = Activation(x W₁ + b₁) W₂ + b₂. Here x has shape (B, L, d_model), and the FFN is applied identically at every token position — the MLP weights are shared across positions, not across layers. The inner dimension d_ff is typically set to 4 × d_model, giving a bottleneck structure: the hidden state expands from d_model to d_ff, passes through the non-linearity, then contracts back to d_model. This 4× ratio is an empirical choice from Vaswani 2017 that has remained surprisingly durable.

- d_model = 512 → d_ff = 2048 (4×) — standard Transformer original
- d_model = 768 → d_ff = 3072 (4×) — BERT-base
- d_model = 1024 → d_ff = 4096 (4×) — BERT-large, GPT-2 medium
- Parameter count: W₁ is d_model × d_ff, W₂ is d_ff × d_model → 2 · d_model · d_ff total
- For d_model=512, d_ff=2048: FFN has 2,097,152 params vs ~786,432 for attention

> **FFN Parameters Dominate in Large Models**: In a standard Transformer with d_model=512 and d_ff=2048, each FFN block has ~2M parameters while each attention block has ~786K parameters — about 2.7× more in the FFN. Across all layers, the FFN accounts for roughly two-thirds of total non-embedding parameters. This ratio worsens as models grow: GPT-3's 175B parameters are predominantly in FFN layers.

## FFN as Associative Memory (Geva et al. 2021)

Geva et al. (2021) proposed a compelling interpretation: the rows of W₁ act as 'keys' and the rows of W₂ᵀ act as 'values'. The input x is compared against all keys via the linear projection xW₁; positions with high dot-product activate after the ReLU (or GELU) non-linearity. The activated hidden units then select corresponding value vectors from W₂, blending them into the output. This is a continuous, soft key-value lookup — the FFN retrieves factual associations (e.g., capital cities, common collocations) stored in its weights during pretraining.

## Activation Functions — From ReLU to SwiGLU

The original Transformer used ReLU. GPT-2 switched to GELU, which is smoother and avoids the dead-neuron problem of ReLU. More recently, gated variants (SwiGLU, GEGLU, ReGLU) have become standard in frontier LLMs. These use three matrices instead of two, where one branch acts as a multiplicative gate controlling information flow. Shazeer (2020) showed that gated variants consistently outperform ReLU and GELU at the same parameter and compute budget.

## Code 1 — FFN Block from Scratch

A clean position-wise FFN implementation with configurable activation, showing how FFN parameter count compares to attention parameter count.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class FeedForwardBlock(nn.Module):
    """Position-wise FFN: FFN(x) = Dropout(Act(x W1 + b1) W2 + b2).
    Same MLP applied independently to every token position.
    d_ff defaults to 4 * d_model (the standard ratio from Vaswani 2017).
    """
    def __init__(self, d_model: int, d_ff: int = None,
                 dropout: float = 0.1, activation: str = 'gelu'):
        super().__init__()
        d_ff       = d_ff or 4 * d_model
        self.fc1   = nn.Linear(d_model, d_ff)
        self.fc2   = nn.Linear(d_ff, d_model)
        self.drop  = nn.Dropout(dropout)
        self.act   = {'relu': F.relu, 'gelu': F.gelu}[activation]

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        return self.fc2(self.drop(self.act(self.fc1(x))))

# Compare parameter counts: FFN vs attention
d_model, d_ff = 512, 2048
ffn   = FeedForwardBlock(d_model, d_ff)
attn  = nn.MultiheadAttention(d_model, num_heads=8, batch_first=True)
p_ffn  = sum(p.numel() for p in ffn.parameters())
p_attn = sum(p.numel() for p in attn.parameters())
print(f'd_model={d_model}, d_ff={d_ff}')
print(f'FFN params:  {p_ffn:,}  ({p_ffn/(p_ffn+p_attn)*100:.1f}% of FFN+Attn)')
print(f'Attn params: {p_attn:,} ({p_attn/(p_ffn+p_attn)*100:.1f}% of FFN+Attn)')
x   = torch.randn(2, 10, d_model)
out = ffn(x)
print(f'Output shape: {out.shape}  (position-wise: same as input)')
```

## Code 2 — Gated FFN (SwiGLU Variant)

SwiGLU uses three weight matrices: a gate branch (W₁, through SiLU), a value branch (W₂, linear), and a down-projection (W₃). The hidden dimension is reduced to 2/3 of the standard d_ff to keep parameter counts equivalent.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class SwiGLUFFN(nn.Module):
    """SwiGLU (Shazeer 2020): FFN(x) = (SiLU(x W1) * x W2) W3.
    Three matrices; d_ff adjusted to 2/3 of standard to match param count.
    SiLU(x) = x * sigmoid(x)  (also called Swish).
    Used in: LLaMA 1/2/3, Mistral, PaLM, Gemma.
    """
    def __init__(self, d_model: int, d_ff: int = None, dropout: float = 0.0):
        super().__init__()
        d_ff       = d_ff or int(4 * d_model * 2 / 3)
        self.W1    = nn.Linear(d_model, d_ff, bias=False)   # gate
        self.W2    = nn.Linear(d_model, d_ff, bias=False)   # value
        self.W3    = nn.Linear(d_ff,   d_model, bias=False) # down
        self.drop  = nn.Dropout(dropout)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        gate  = F.silu(self.W1(x))       # SiLU gate branch
        value = self.W2(x)               # linear value branch
        return self.W3(self.drop(gate * value))

# Verify shapes and parameter count vs standard FFN
d_model = 512
swi     = SwiGLUFFN(d_model)
std_p   = 2 * d_model * (4 * d_model)   # standard 2-matrix FFN
swi_p   = sum(p.numel() for p in swi.parameters())
print(f'Standard FFN params (2 mats, d_ff={4*d_model}):  {std_p:,}')
print(f'SwiGLU FFN  params (3 mats, d_ff={int(4*d_model*2/3)}): {swi_p:,}')
print(f'Ratio: {swi_p / std_p:.3f}  (target close to 1.000)')
x   = torch.randn(2, 10, d_model)
out = swi(x)
print(f'Output shape: {out.shape}')
```

## Code 3 — FFN as Associative Memory

Demonstrating the Geva et al. (2021) key-value memory interpretation: a known key pattern stored in W₁ row 3 causes high activation there, and the corresponding W₂ column is retrieved as the output value.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

# Geva et al. (2021): FFN rows of W1 = keys, columns of W2 = values
torch.manual_seed(42)
d_in, d_ff, d_out = 8, 16, 8

W1 = nn.Linear(d_in, d_ff, bias=False)    # key matrix  (d_ff x d_in rows)
W2 = nn.Linear(d_ff, d_out, bias=False)   # value matrix

# Plant a memory: key 3 -> value vector
target_key   = torch.randn(d_in)
target_value = torch.randn(d_out)
with torch.no_grad():
    W1.weight[3]    = target_key          # row 3 of W1 = the key
    W2.weight[:, 3] = target_value       # column 3 of W2 = the value

# Query with the planted key pattern
x_query     = target_key.unsqueeze(0)    # (1, d_in)
activations = F.relu(W1(x_query))        # key pattern activates key 3 strongly
print('Activations (should be highest at index 3):')
print(activations.detach().numpy().round(3))
print('Max activation at index:', activations.argmax().item())

retrieved = W2(activations)
print('\nRetrieved:', retrieved.detach().numpy().round(3))
print('Target:   ', target_value.numpy().round(3))
cos = F.cosine_similarity(retrieved, target_value.unsqueeze(0))
print(f'Cosine similarity: {cos.item():.4f}  (high = successful retrieval)')
```

## Code 4 — Profiling FFN vs Attention Compute Budget

Empirically timing FFN and self-attention on the same batch to quantify their relative compute costs, showing the FFN dominates at large d_ff.

```python
import torch
import torch.nn as nn
import time

def time_module(module: nn.Module, x: torch.Tensor,
                n_runs: int = 100, label: str = '') -> float:
    module.eval()
    with torch.no_grad():
        for _ in range(10):      # warm-up
            _ = module(x)
        t0 = time.perf_counter()
        for _ in range(n_runs):
            _ = module(x)
        ms = (time.perf_counter() - t0) / n_runs * 1000
    print(f'{label:<28}: {ms:.3f} ms/pass')
    return ms

d_model, n_heads, d_ff = 512, 8, 2048
B, L = 4, 128

ffn = nn.Sequential(
    nn.Linear(d_model, d_ff), nn.GELU(), nn.Linear(d_ff, d_model)
)

class AttnWrapper(nn.Module):
    def __init__(self, d, h): super().__init__(); self.a = nn.MultiheadAttention(d, h, batch_first=True)
    def forward(self, x): return self.a(x, x, x)[0]

x_ffn  = torch.randn(B, L, d_model)
x_attn = torch.randn(B, L, d_model)

t_ffn  = time_module(ffn, x_ffn, label=f'FFN (d_ff={d_ff})')
t_attn = time_module(AttnWrapper(d_model, n_heads), x_attn, label='Self-Attention')
print(f'FFN / Attn time ratio: {t_ffn/t_attn:.2f}x  (d_model={d_model}, L={L})')
```

## FFN Variants Compared

| Variant | Activation | Matrices | d_ff Ratio | Used In |
| --- | --- | --- | --- | --- |
| Standard ReLU | ReLU | 2 | 4× d_model | Original Transformer, early BERT |
| Standard GELU | GELU | 2 | 4× d_model | GPT-2, BERT, RoBERTa |
| SwiGLU | SiLU (Swish) gate | 3 | ~8/3× d_model | LLaMA 1/2/3, Mistral, PaLM, Gemma |
| ReGLU | ReLU gate | 3 | ≤4× d_model | Research models (Shazeer 2020) |
| GEGLU | GELU gate | 3 | ≤4× d_model | T5 variants, some BERT successors |
| Sparse MoE | Any (per expert) | 2 per expert | k active of n experts | Mixtral, Switch Transformer |

The FFN sub-layer is deceptively simple but plays a central role: it provides per-token non-linear transformation after each attention operation, storing factual knowledge in its weights and acting as the model's memory. The evolution from ReLU to GELU to gated variants (SwiGLU) represents consistent empirical wins at the same compute budget — a rare case where a drop-in change reliably improves quality without increasing FLOPs.

