---
title: "SwiGLU — Gated Linear Units and LLaMA FFN"
slug: "swiglu-ffn"
description: "SwiGLU and the GLU family of gated FFN activations — how SiLU gates improve Transformer FFN quality, parameter equivalence with the 3-matrix design, and full LLaMA block integration."
tags: ["deep-learning", "transformers"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"The feed-forward sub-layer has been a quiet source of consistent improvement in Transformer design. Noam Shazeer\u0027s 2020 paper \u0027GLU Variants Improve Transformers\u0027 introduced a family of gated feed-forward layers where one linear projection acts as a multiplicative gate on another. SwiGLU — the variant using the SiLU (Swish) activation as the gate — has become the standard FFN in most frontier LLMs, including LLaMA 1/2/3, Mistral, PaLM, and Gemma."},{"type":"heading","level":2,"content":"Gated Linear Units — The GLU Family"},{"type":"text","content":"A Gated Linear Unit (GLU), introduced by Dauphin et al. (2017), splits a linear projection into two halves and multiplies them element-wise: GLU(x, W, V, b, c) = σ(xW + b) ⊙ (xV + c). The sigmoid-gated branch acts as an information gate — it controls how much of the value branch passes through to the next layer. Shazeer (2020) explored replacing the sigmoid gate with other non-linearities, finding that smooth activations (GELU, SiLU) consistently outperformed both GLU and ReLU."},{"type":"list","ordered":false,"items":["GLU (Dauphin 2017): σ(xW) ⊙ xV — sigmoid gate, splits projection in two","ReGLU (Shazeer 2020): ReLU(xW) ⊙ xV — ReLU gate, competitive with GELU","GEGLU (Shazeer 2020): GELU(xW) ⊙ xV — strong across benchmarks","SwiGLU (Shazeer 2020): SiLU(xW) ⊙ xV — best reported; SiLU = x·σ(x)","All gated variants use a third down-projection matrix W3 to return to d_model"]},{"type":"callout","variant":"info","title":"Why Gating Improves Quality","content":"The gate provides dynamic feature selection: it allows the network to suppress irrelevant dimensions token-by-token, similar to LSTM forget gates. SiLU is smooth, non-saturating for positive values, and has a small negative region — these properties combine to give richer gradients than ReLU and lower variance than sigmoid gates. Empirically GEGLU and SwiGLU improve perplexity by 1-3% at the same FLOPs budget."},{"type":"heading","level":2,"content":"SwiGLU — SiLU Gate with Parameter Adjustment"},{"type":"text","content":"SwiGLU is defined as FFN_SwiGLU(x) = (SiLU(xW₁) ⊙ xW₂) W₃ where SiLU(x) = x · σ(x). Three weight matrices replace the standard two, so the hidden dimension must be reduced to preserve the parameter budget: instead of d_ff = 4·d_model with two matrices (2·d·d_ff = 8d²), SwiGLU uses d_ff = 8d/3 with three matrices (3·d·(8d/3) = 8d²). LLaMA rounds 8/3 to the nearest multiple of 256 for hardware efficiency, typically d_ff ≈ 11,008 for d_model = 4,096."},{"type":"heading","level":2,"content":"Why Gates Improve FFN Quality"},{"type":"text","content":"Standard FFN activations (ReLU, GELU) apply a fixed non-linearity to every neuron independently of the input value. Gated variants make the effective activation *input-dependent*: SiLU(xW₁) ⊙ xW₂ means different tokens activate different subsets of features. This dynamic selection allows the FFN to specialise different neurons for different input patterns, increasing expressivity without increasing FLOPs. The gate also provides a natural mechanism for the model to route information — features with low gate activation are effectively zeroed out."},{"type":"heading","level":2,"content":"Code 1 — SwiGLU FFN from Scratch"},{"type":"text","content":"A clean SwiGLU implementation with the 8/3 hidden dimension scaling. Confirms output shape and parameter count relative to a standard 2-matrix FFN."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass SwiGLU(nn.Module):\n    \"\"\"SwiGLU from \u0027GLU Variants Improve Transformers\u0027 (Shazeer, 2020).\n    FFN(x) = (SiLU(x @ W_gate) * (x @ W_up)) @ W_down\n    Hidden dim = 8/3 * d_model to keep param count equal to 2-matrix FFN.\n    \"\"\"\n    def __init__(self, d_model: int, factor: float = 8/3):\n        super().__init__()\n        d_hidden       = int(d_model * factor)\n        self.gate_proj = nn.Linear(d_model, d_hidden, bias=False)\n        self.up_proj   = nn.Linear(d_model, d_hidden, bias=False)\n        self.down_proj = nn.Linear(d_hidden, d_model, bias=False)\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        gate = F.silu(self.gate_proj(x))   # SiLU(xW_gate)\n        up   = self.up_proj(x)             # xW_up (no activation)\n        return self.down_proj(gate * up)   # (gate ⊙ up) @ W_down\n\ntorch.manual_seed(0)\nd_model = 512\nffn     = SwiGLU(d_model)\nx       = torch.randn(2, 10, d_model)\nout     = ffn(x)\np_swi   = sum(p.numel() for p in ffn.parameters())\np_std   = 2 * d_model * (4 * d_model)    # standard 2-matrix param count\nprint(f\u0027SwiGLU output: {out.shape}\u0027)\nprint(f\u0027SwiGLU params: {p_swi:,}\u0027)\nprint(f\u0027Standard params (d_ff=4d): {p_std:,}\u0027)\nprint(f\u0027Ratio: {p_swi/p_std:.4f}  (should be ~1.0 — param-equivalent)\u0027)"},{"type":"heading","level":2,"content":"Code 2 — GLU Variants Side by Side"},{"type":"text","content":"A unified implementation of the GLU family using a split-projection approach, making it easy to swap gate activations and compare outputs on the same input."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass GatedFFN(nn.Module):\n    \"\"\"Unified GLU-family FFN: gate activation is configurable.\"\"\"\n    GATES = {\n        \u0027glu\u0027:    torch.sigmoid,\n        \u0027reglu\u0027:  F.relu,\n        \u0027geglu\u0027:  F.gelu,\n        \u0027swiglu\u0027: F.silu,\n    }\n\n    def __init__(self, d_model: int, d_ff: int, variant: str = \u0027swiglu\u0027):\n        super().__init__()\n        if variant not in self.GATES:\n            raise ValueError(f\u0027Unknown variant: {variant}. Choose: {list(self.GATES)}\u0027)\n        self.variant = variant\n        self.gate_fn  = self.GATES[variant]\n        self.up   = nn.Linear(d_model, d_ff * 2, bias=False)  # gate + value\n        self.down = nn.Linear(d_ff,   d_model,   bias=False)\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        gate, value = self.up(x).chunk(2, dim=-1)\n        return self.down(self.gate_fn(gate) * value)\n\n# Compare all variants on identical weights and input\nd_model, d_ff = 256, 512\nx = torch.randn(2, 8, d_model)\nfor variant in (\u0027glu\u0027, \u0027reglu\u0027, \u0027geglu\u0027, \u0027swiglu\u0027):\n    torch.manual_seed(0)\n    ffn    = GatedFFN(d_model, d_ff, variant)\n    out    = ffn(x)\n    params = sum(p.numel() for p in ffn.parameters())\n    print(f\u0027{variant.upper():8}: out={tuple(out.shape)}, params={params:,}\u0027)"},{"type":"heading","level":2,"content":"Code 3 — Parameter Equivalence Verification"},{"type":"text","content":"Proving that a SwiGLU FFN with d_ff = 2d/3 × original has the same parameter count as a standard 2-matrix FFN with d_ff = 4 × d_model."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass StandardFFN(nn.Module):\n    \"\"\"Two-matrix FFN: 2 * d_model * d_ff parameters.\"\"\"\n    def __init__(self, d, d_ff):\n        super().__init__()\n        self.fc1 = nn.Linear(d, d_ff,  bias=False)\n        self.fc2 = nn.Linear(d_ff, d,  bias=False)\n    def forward(self, x): return self.fc2(F.gelu(self.fc1(x)))\n\nclass SwiGLUFFN(nn.Module):\n    \"\"\"Three-matrix SwiGLU: 3 * d_model * d_hidden parameters.\"\"\"\n    def __init__(self, d, d_hidden):\n        super().__init__()\n        self.W1 = nn.Linear(d, d_hidden,   bias=False)\n        self.W2 = nn.Linear(d, d_hidden,   bias=False)\n        self.W3 = nn.Linear(d_hidden, d,   bias=False)\n    def forward(self, x): return self.W3(F.silu(self.W1(x)) * self.W2(x))\n\nd_model   = 512\nd_std_ff  = 4 * d_model          # standard d_ff = 2048\nd_swi_ff  = int(d_std_ff * 2/3)  # SwiGLU d_ff = 1365\n\nstd = StandardFFN(d_model, d_std_ff)\nswi = SwiGLUFFN(d_model, d_swi_ff)\np_std = sum(p.numel() for p in std.parameters())\np_swi = sum(p.numel() for p in swi.parameters())\n\nprint(f\u0027Standard FFN  (2 mats, d_ff={d_std_ff}): {p_std:,} params\u0027)\nprint(f\u0027SwiGLU FFN    (3 mats, d_ff={d_swi_ff}): {p_swi:,} params\u0027)\nprint(f\u0027Ratio: {p_swi/p_std:.4f}  (close to 1.000 — parameter-equivalent)\u0027)\nprint(f\u0027Formula check — 3 mats: 3*{d_model}*{d_swi_ff} = {3*d_model*d_swi_ff:,}\u0027)\nprint(f\u0027Formula check — 2 mats: 2*{d_model}*{d_std_ff} = {2*d_model*d_std_ff:,}\u0027)"},{"type":"heading","level":2,"content":"Code 4 — SwiGLU in a Full LLaMA-Style Block"},{"type":"text","content":"A complete LLaMA-style decoder block using RMSNorm (instead of LayerNorm), SwiGLU FFN, and pre-norm layout — the building block used in LLaMA 1/2/3 and Mistral."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass RMSNorm(nn.Module):\n    \"\"\"Root Mean Square Layer Normalisation (LLaMA, Mistral).\"\"\"\n    def __init__(self, d: int, eps: float = 1e-6):\n        super().__init__()\n        self.weight = nn.Parameter(torch.ones(d))\n        self.eps    = eps\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        rms = x.pow(2).mean(-1, keepdim=True).add(self.eps).sqrt()\n        return self.weight * x / rms\n\nclass SwiGLUFFN(nn.Module):\n    def __init__(self, d: int, d_ff: int):\n        super().__init__()\n        self.gate = nn.Linear(d, d_ff, bias=False)\n        self.up   = nn.Linear(d, d_ff, bias=False)\n        self.down = nn.Linear(d_ff, d, bias=False)\n    def forward(self, x): return self.down(F.silu(self.gate(x)) * self.up(x))\n\nclass LLaMABlock(nn.Module):\n    \"\"\"LLaMA-style block: RMSNorm + MHA + SwiGLU, pre-norm layout.\"\"\"\n    def __init__(self, d_model: int = 256, n_heads: int = 8, d_ff: int = None):\n        super().__init__()\n        d_ff           = d_ff or int(d_model * 8 / 3)\n        self.attn_norm = RMSNorm(d_model)\n        self.ffn_norm  = RMSNorm(d_model)\n        self.attn = nn.MultiheadAttention(d_model, n_heads, batch_first=True, bias=False)\n        self.ffn  = SwiGLUFFN(d_model, d_ff)\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        n = self.attn_norm(x)\n        x = x + self.attn(n, n, n)[0]      # pre-norm attention\n        x = x + self.ffn(self.ffn_norm(x)) # pre-norm SwiGLU FFN\n        return x\n\nblock  = LLaMABlock(d_model=256, n_heads=8)\nx      = torch.randn(2, 16, 256)\nout    = block(x)\nparams = sum(p.numel() for p in block.parameters())\nprint(f\u0027LLaMA block output: {out.shape}\u0027)\nprint(f\u0027Parameters: {params:,}\u0027)"},{"type":"heading","level":2,"content":"FFN Activation Variants Compared"},{"type":"table","headers":["Variant","Gate Activation","Formula (simplified)","Used In","Quality Rank"],"rows":[["Standard ReLU","None","ReLU(xW1) @ W2","Original Transformer, BERT","Baseline"],["Standard GELU","None","GELU(xW1) @ W2","GPT-2, RoBERTa, DistilBERT","Better than ReLU"],["GLU (sigmoid)","Sigmoid σ","(σ(xW) ⊙ xV) @ W2","Dauphin et al. (2017), LM tasks","Moderate gain"],["ReGLU","ReLU","(ReLU(xW) ⊙ xV) @ W2","Shazeer 2020 ablations","Competitive"],["GEGLU","GELU","(GELU(xW) ⊙ xV) @ W2","T5 variants, some BERT models","Strong"],["SwiGLU","SiLU (Swish)","(SiLU(xW) ⊙ xV) @ W2","LLaMA 1/2/3, Mistral, PaLM, Gemma","Best reported"]]},{"type":"text","content":"SwiGLU represents one of the clearest wins in modern LLM design: a one-line change to the FFN activation that consistently improves perplexity at identical compute. The 3-matrix design with the 2/3 hidden-dimension adjustment keeps FLOP and parameter counts equivalent to a standard FFN, so there is no cost to switching. For any new Transformer project using LLaMA-family architecture as a reference, SwiGLU with RMSNorm should be the starting point for the FFN sub-layer."}]"
---
# SwiGLU — Gated Linear Units and LLaMA FFN

The feed-forward sub-layer has been a quiet source of consistent improvement in Transformer design. Noam Shazeer's 2020 paper 'GLU Variants Improve Transformers' introduced a family of gated feed-forward layers where one linear projection acts as a multiplicative gate on another. SwiGLU — the variant using the SiLU (Swish) activation as the gate — has become the standard FFN in most frontier LLMs, including LLaMA 1/2/3, Mistral, PaLM, and Gemma.

## Gated Linear Units — The GLU Family

A Gated Linear Unit (GLU), introduced by Dauphin et al. (2017), splits a linear projection into two halves and multiplies them element-wise: GLU(x, W, V, b, c) = σ(xW + b) ⊙ (xV + c). The sigmoid-gated branch acts as an information gate — it controls how much of the value branch passes through to the next layer. Shazeer (2020) explored replacing the sigmoid gate with other non-linearities, finding that smooth activations (GELU, SiLU) consistently outperformed both GLU and ReLU.

- GLU (Dauphin 2017): σ(xW) ⊙ xV — sigmoid gate, splits projection in two
- ReGLU (Shazeer 2020): ReLU(xW) ⊙ xV — ReLU gate, competitive with GELU
- GEGLU (Shazeer 2020): GELU(xW) ⊙ xV — strong across benchmarks
- SwiGLU (Shazeer 2020): SiLU(xW) ⊙ xV — best reported; SiLU = x·σ(x)
- All gated variants use a third down-projection matrix W3 to return to d_model

> **Why Gating Improves Quality**: The gate provides dynamic feature selection: it allows the network to suppress irrelevant dimensions token-by-token, similar to LSTM forget gates. SiLU is smooth, non-saturating for positive values, and has a small negative region — these properties combine to give richer gradients than ReLU and lower variance than sigmoid gates. Empirically GEGLU and SwiGLU improve perplexity by 1-3% at the same FLOPs budget.

## SwiGLU — SiLU Gate with Parameter Adjustment

SwiGLU is defined as FFN_SwiGLU(x) = (SiLU(xW₁) ⊙ xW₂) W₃ where SiLU(x) = x · σ(x). Three weight matrices replace the standard two, so the hidden dimension must be reduced to preserve the parameter budget: instead of d_ff = 4·d_model with two matrices (2·d·d_ff = 8d²), SwiGLU uses d_ff = 8d/3 with three matrices (3·d·(8d/3) = 8d²). LLaMA rounds 8/3 to the nearest multiple of 256 for hardware efficiency, typically d_ff ≈ 11,008 for d_model = 4,096.

## Why Gates Improve FFN Quality

Standard FFN activations (ReLU, GELU) apply a fixed non-linearity to every neuron independently of the input value. Gated variants make the effective activation *input-dependent*: SiLU(xW₁) ⊙ xW₂ means different tokens activate different subsets of features. This dynamic selection allows the FFN to specialise different neurons for different input patterns, increasing expressivity without increasing FLOPs. The gate also provides a natural mechanism for the model to route information — features with low gate activation are effectively zeroed out.

## Code 1 — SwiGLU FFN from Scratch

A clean SwiGLU implementation with the 8/3 hidden dimension scaling. Confirms output shape and parameter count relative to a standard 2-matrix FFN.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class SwiGLU(nn.Module):
    """SwiGLU from 'GLU Variants Improve Transformers' (Shazeer, 2020).
    FFN(x) = (SiLU(x @ W_gate) * (x @ W_up)) @ W_down
    Hidden dim = 8/3 * d_model to keep param count equal to 2-matrix FFN.
    """
    def __init__(self, d_model: int, factor: float = 8/3):
        super().__init__()
        d_hidden       = int(d_model * factor)
        self.gate_proj = nn.Linear(d_model, d_hidden, bias=False)
        self.up_proj   = nn.Linear(d_model, d_hidden, bias=False)
        self.down_proj = nn.Linear(d_hidden, d_model, bias=False)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        gate = F.silu(self.gate_proj(x))   # SiLU(xW_gate)
        up   = self.up_proj(x)             # xW_up (no activation)
        return self.down_proj(gate * up)   # (gate ⊙ up) @ W_down

torch.manual_seed(0)
d_model = 512
ffn     = SwiGLU(d_model)
x       = torch.randn(2, 10, d_model)
out     = ffn(x)
p_swi   = sum(p.numel() for p in ffn.parameters())
p_std   = 2 * d_model * (4 * d_model)    # standard 2-matrix param count
print(f'SwiGLU output: {out.shape}')
print(f'SwiGLU params: {p_swi:,}')
print(f'Standard params (d_ff=4d): {p_std:,}')
print(f'Ratio: {p_swi/p_std:.4f}  (should be ~1.0 — param-equivalent)')
```

## Code 2 — GLU Variants Side by Side

A unified implementation of the GLU family using a split-projection approach, making it easy to swap gate activations and compare outputs on the same input.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class GatedFFN(nn.Module):
    """Unified GLU-family FFN: gate activation is configurable."""
    GATES = {
        'glu':    torch.sigmoid,
        'reglu':  F.relu,
        'geglu':  F.gelu,
        'swiglu': F.silu,
    }

    def __init__(self, d_model: int, d_ff: int, variant: str = 'swiglu'):
        super().__init__()
        if variant not in self.GATES:
            raise ValueError(f'Unknown variant: {variant}. Choose: {list(self.GATES)}')
        self.variant = variant
        self.gate_fn  = self.GATES[variant]
        self.up   = nn.Linear(d_model, d_ff * 2, bias=False)  # gate + value
        self.down = nn.Linear(d_ff,   d_model,   bias=False)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        gate, value = self.up(x).chunk(2, dim=-1)
        return self.down(self.gate_fn(gate) * value)

# Compare all variants on identical weights and input
d_model, d_ff = 256, 512
x = torch.randn(2, 8, d_model)
for variant in ('glu', 'reglu', 'geglu', 'swiglu'):
    torch.manual_seed(0)
    ffn    = GatedFFN(d_model, d_ff, variant)
    out    = ffn(x)
    params = sum(p.numel() for p in ffn.parameters())
    print(f'{variant.upper():8}: out={tuple(out.shape)}, params={params:,}')
```

## Code 3 — Parameter Equivalence Verification

Proving that a SwiGLU FFN with d_ff = 2d/3 × original has the same parameter count as a standard 2-matrix FFN with d_ff = 4 × d_model.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class StandardFFN(nn.Module):
    """Two-matrix FFN: 2 * d_model * d_ff parameters."""
    def __init__(self, d, d_ff):
        super().__init__()
        self.fc1 = nn.Linear(d, d_ff,  bias=False)
        self.fc2 = nn.Linear(d_ff, d,  bias=False)
    def forward(self, x): return self.fc2(F.gelu(self.fc1(x)))

class SwiGLUFFN(nn.Module):
    """Three-matrix SwiGLU: 3 * d_model * d_hidden parameters."""
    def __init__(self, d, d_hidden):
        super().__init__()
        self.W1 = nn.Linear(d, d_hidden,   bias=False)
        self.W2 = nn.Linear(d, d_hidden,   bias=False)
        self.W3 = nn.Linear(d_hidden, d,   bias=False)
    def forward(self, x): return self.W3(F.silu(self.W1(x)) * self.W2(x))

d_model   = 512
d_std_ff  = 4 * d_model          # standard d_ff = 2048
d_swi_ff  = int(d_std_ff * 2/3)  # SwiGLU d_ff = 1365

std = StandardFFN(d_model, d_std_ff)
swi = SwiGLUFFN(d_model, d_swi_ff)
p_std = sum(p.numel() for p in std.parameters())
p_swi = sum(p.numel() for p in swi.parameters())

print(f'Standard FFN  (2 mats, d_ff={d_std_ff}): {p_std:,} params')
print(f'SwiGLU FFN    (3 mats, d_ff={d_swi_ff}): {p_swi:,} params')
print(f'Ratio: {p_swi/p_std:.4f}  (close to 1.000 — parameter-equivalent)')
print(f'Formula check — 3 mats: 3*{d_model}*{d_swi_ff} = {3*d_model*d_swi_ff:,}')
print(f'Formula check — 2 mats: 2*{d_model}*{d_std_ff} = {2*d_model*d_std_ff:,}')
```

## Code 4 — SwiGLU in a Full LLaMA-Style Block

A complete LLaMA-style decoder block using RMSNorm (instead of LayerNorm), SwiGLU FFN, and pre-norm layout — the building block used in LLaMA 1/2/3 and Mistral.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class RMSNorm(nn.Module):
    """Root Mean Square Layer Normalisation (LLaMA, Mistral)."""
    def __init__(self, d: int, eps: float = 1e-6):
        super().__init__()
        self.weight = nn.Parameter(torch.ones(d))
        self.eps    = eps
    def forward(self, x: torch.Tensor) -> torch.Tensor:
        rms = x.pow(2).mean(-1, keepdim=True).add(self.eps).sqrt()
        return self.weight * x / rms

class SwiGLUFFN(nn.Module):
    def __init__(self, d: int, d_ff: int):
        super().__init__()
        self.gate = nn.Linear(d, d_ff, bias=False)
        self.up   = nn.Linear(d, d_ff, bias=False)
        self.down = nn.Linear(d_ff, d, bias=False)
    def forward(self, x): return self.down(F.silu(self.gate(x)) * self.up(x))

class LLaMABlock(nn.Module):
    """LLaMA-style block: RMSNorm + MHA + SwiGLU, pre-norm layout."""
    def __init__(self, d_model: int = 256, n_heads: int = 8, d_ff: int = None):
        super().__init__()
        d_ff           = d_ff or int(d_model * 8 / 3)
        self.attn_norm = RMSNorm(d_model)
        self.ffn_norm  = RMSNorm(d_model)
        self.attn = nn.MultiheadAttention(d_model, n_heads, batch_first=True, bias=False)
        self.ffn  = SwiGLUFFN(d_model, d_ff)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        n = self.attn_norm(x)
        x = x + self.attn(n, n, n)[0]      # pre-norm attention
        x = x + self.ffn(self.ffn_norm(x)) # pre-norm SwiGLU FFN
        return x

block  = LLaMABlock(d_model=256, n_heads=8)
x      = torch.randn(2, 16, 256)
out    = block(x)
params = sum(p.numel() for p in block.parameters())
print(f'LLaMA block output: {out.shape}')
print(f'Parameters: {params:,}')
```

## FFN Activation Variants Compared

| Variant | Gate Activation | Formula (simplified) | Used In | Quality Rank |
| --- | --- | --- | --- | --- |
| Standard ReLU | None | ReLU(xW1) @ W2 | Original Transformer, BERT | Baseline |
| Standard GELU | None | GELU(xW1) @ W2 | GPT-2, RoBERTa, DistilBERT | Better than ReLU |
| GLU (sigmoid) | Sigmoid σ | (σ(xW) ⊙ xV) @ W2 | Dauphin et al. (2017), LM tasks | Moderate gain |
| ReGLU | ReLU | (ReLU(xW) ⊙ xV) @ W2 | Shazeer 2020 ablations | Competitive |
| GEGLU | GELU | (GELU(xW) ⊙ xV) @ W2 | T5 variants, some BERT models | Strong |
| SwiGLU | SiLU (Swish) | (SiLU(xW) ⊙ xV) @ W2 | LLaMA 1/2/3, Mistral, PaLM, Gemma | Best reported |

SwiGLU represents one of the clearest wins in modern LLM design: a one-line change to the FFN activation that consistently improves perplexity at identical compute. The 3-matrix design with the 2/3 hidden-dimension adjustment keeps FLOP and parameter counts equivalent to a standard FFN, so there is no cost to switching. For any new Transformer project using LLaMA-family architecture as a reference, SwiGLU with RMSNorm should be the starting point for the FFN sub-layer.

