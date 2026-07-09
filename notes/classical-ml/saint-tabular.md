---
title: "SAINT — Self-Attention and Intersample Attention for Tabular Data"
slug: "saint-tabular"
description: "SAINT alternates between row-wise self-attention (over features) and intersample attention (over other training rows) to combine feature interaction modeling with instance-based learning."
tags: ["tabular", "deep-learning", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"SAINT (Self-Attention and Intersample Attention Transformer, Somepalli et al. 2021) addresses a key limitation of FT-Transformer: attention is computed only across features of a single row, ignoring relationships between training samples. SAINT adds a second attention axis — across rows — effectively combining a feature-interaction Transformer with a learned k-NN in embedding space."},{"type":"heading","level":2,"content":"Two Types of Attention"},{"type":"text","content":"Each SAINT block contains two sequential sub-blocks. Row attention (identical to FT-Transformer) processes features within a single sample. Intersample attention processes the representation of the same feature across a batch of samples."},{"type":"list","ordered":false,"items":["Row attention: for one sample, attend over F feature tokens — captures feature interactions within a row","Intersample attention: for a mini-batch of B samples, attend over B sample representations of the same feature position","Alternating pattern: [Row Attn → Intersample Attn] × N_layers","Intersample attention lets the model ask: which other training samples are most informative for predicting the current sample?","Computational cost: O(B²) per intersample attention — quadratic in batch size, not dataset size","At inference time, the batch acts as the context — similar samples in the batch reinforce predictions"]},{"type":"heading","level":2,"content":"Row Attention Block"},{"type":"text","content":"The row attention block is a standard Transformer encoder layer applied to the F feature tokens of a single sample. It is identical in design to one FT-Transformer layer."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torch import Tensor\n\nclass RowAttentionBlock(nn.Module):\n    \"\"\"Self-attention over features within each row (identical to FT-Transformer layer).\"\"\"\n    def __init__(self, d_token: int, n_heads: int, d_ffn: int, dropout: float = 0.1):\n        super().__init__()\n        self.attn = nn.MultiheadAttention(\n            embed_dim=d_token, num_heads=n_heads,\n            dropout=dropout, batch_first=True\n        )\n        self.ff = nn.Sequential(\n            nn.LayerNorm(d_token),\n            nn.Linear(d_token, d_ffn),\n            nn.GELU(),\n            nn.Dropout(dropout),\n            nn.Linear(d_ffn, d_token),\n            nn.Dropout(dropout)\n        )\n        self.norm1 = nn.LayerNorm(d_token)\n        self.norm2 = nn.LayerNorm(d_token)\n\n    def forward(self, x: Tensor) -\u003e Tensor:  # x: (B, F, d)\n        # Self-attention over features (F tokens)\n        attn_out, _ = self.attn(x, x, x)\n        x = self.norm1(x + attn_out)\n        # Feed-forward\n        x = self.norm2(x + self.ff(x))\n        return x  # (B, F, d)"},{"type":"heading","level":2,"content":"Intersample Attention Block"},{"type":"text","content":"Intersample attention transposes the batch and feature dimensions: for each feature position, all B sample representations attend to each other. This produces a B×B attention matrix per feature — the model learns which samples are relevant for predicting each other."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torch import Tensor\n\nclass IntersampleAttentionBlock(nn.Module):\n    \"\"\"Self-attention over samples for each feature position.\"\"\"\n    def __init__(self, d_token: int, n_heads: int, d_ffn: int, dropout: float = 0.1):\n        super().__init__()\n        self.attn  = nn.MultiheadAttention(\n            embed_dim=d_token, num_heads=n_heads,\n            dropout=dropout, batch_first=True\n        )\n        self.norm1 = nn.LayerNorm(d_token)\n        self.norm2 = nn.LayerNorm(d_token)\n        self.ff    = nn.Sequential(\n            nn.Linear(d_token, d_ffn), nn.GELU(),\n            nn.Dropout(dropout),\n            nn.Linear(d_ffn, d_token), nn.Dropout(dropout)\n        )\n\n    def forward(self, x: Tensor) -\u003e Tensor:  # x: (B, F, d)\n        B, F, d = x.shape\n        # Transpose: treat each feature position as a sequence of B samples\n        x_t = x.permute(1, 0, 2)          # (F, B, d)\n        attn_out, _ = self.attn(x_t, x_t, x_t)  # attend over B samples\n        x_t = self.norm1(x_t + attn_out)\n        x_t = self.norm2(x_t + self.ff(x_t))\n        return x_t.permute(1, 0, 2)        # back to (B, F, d)"},{"type":"heading","level":2,"content":"SAINT Full Forward Pass"},{"type":"text","content":"SAINT stacks alternating row and intersample attention blocks. The [CLS] token (prepended to the feature sequence) aggregates global information and drives the prediction."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torch import Tensor\n\nclass SAINT(nn.Module):\n    def __init__(self, n_features: int, d_token: int, n_heads: int,\n                 d_ffn: int, n_layers: int, n_classes: int):\n        super().__init__()\n        # Feature tokenization (numerical, same as FT-Transformer)\n        self.tokenizer = nn.Linear(1, d_token)  # simplified: shared projection\n        self.cls_token  = nn.Parameter(torch.zeros(1, 1, d_token))\n\n        self.row_blocks = nn.ModuleList([\n            RowAttentionBlock(d_token, n_heads, d_ffn) for _ in range(n_layers)\n        ])\n        self.isample_blocks = nn.ModuleList([\n            IntersampleAttentionBlock(d_token, n_heads, d_ffn) for _ in range(n_layers)\n        ])\n        self.head = nn.Sequential(\n            nn.LayerNorm(d_token),\n            nn.Linear(d_token, n_classes)\n        )\n\n    def forward(self, x: Tensor) -\u003e Tensor:  # x: (B, F)\n        # Tokenize each feature independently\n        tokens = self.tokenizer(x.unsqueeze(-1))           # (B, F, d)\n        cls    = self.cls_token.expand(x.size(0), -1, -1)  # (B, 1, d)\n        tokens = torch.cat([cls, tokens], dim=1)            # (B, F+1, d)\n\n        # Alternate row and intersample attention\n        for row_blk, isample_blk in zip(self.row_blocks, self.isample_blocks):\n            tokens = row_blk(tokens)\n            tokens = isample_blk(tokens)\n\n        return self.head(tokens[:, 0])  # CLS token → prediction"},{"type":"heading","level":2,"content":"SCARF-Style Pretraining"},{"type":"text","content":"SAINT uses SCARF (Self-supervised Contrastive learning using random Feature Corruption) for pretraining: randomly replace each feature value with a value sampled from the empirical marginal distribution of that feature. The model learns to produce similar representations for clean and corrupted views of the same row (contrastive loss)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nfrom torch import Tensor\n\ndef scarf_corrupt(x: Tensor, corruption_rate: float = 0.6) -\u003e Tensor:\n    \"\"\"Replace each feature with a random value from its empirical marginal.\"\"\"\n    B, F = x.shape\n    mask = torch.bernoulli(torch.full((B, F), corruption_rate)).bool()\n    # Sample random row indices for each position to use as replacement\n    random_rows = torch.randint(0, B, (B, F))\n    x_corrupt   = x.clone()\n    for j in range(F):\n        x_corrupt[mask[:, j], j] = x[random_rows[mask[:, j], j], j]\n    return x_corrupt\n\nclass SCARFLoss(nn.Module):\n    def __init__(self, temperature: float = 0.07):\n        super().__init__()\n        self.temperature = temperature\n\n    def forward(self, z_clean: Tensor, z_corrupt: Tensor) -\u003e Tensor:\n        z1 = F.normalize(z_clean,   dim=-1)  # (B, d)\n        z2 = F.normalize(z_corrupt, dim=-1)  # (B, d)\n        logits = z1 @ z2.T / self.temperature  # (B, B)\n        labels = torch.arange(z1.size(0), device=z1.device)\n        return F.cross_entropy(logits, labels)  # InfoNCE loss"},{"type":"divider"},{"type":"heading","level":2,"content":"SAINT vs Other Tabular Models"},{"type":"table","headers":["Model","Attention Type","Pretraining","Complexity","Benchmark Performance"],"rows":[["FT-Transformer","Row only (feature × feature)","MLM-style optional","O(F²) per layer","Competitive with XGBoost on large datasets"],["SAINT","Row + Intersample","SCARF contrastive","O(F²) + O(B²) per layer","Generally outperforms FT-Transformer"],["TabNet","Sequential sparse feature selection","Reconstruction pretraining","O(N_steps × F)","Often behind FT-Transformer and SAINT"],["XGBoost","None (greedy splits)","None","O(n log n) per tree","State-of-the-art on most tabular benchmarks"]]},{"type":"callout","variant":"warning","title":"Intersample Attention Cost","content":"Intersample attention is quadratic in batch size O(B²). For B=512, this means 262,144 attention score computations per feature position per layer. Keep batch sizes moderate (128–512) and monitor GPU memory. At inference, predictions improve when the batch contains diverse, representative samples from the training distribution."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"list","ordered":false,"items":["SAINT combines row attention (feature interactions) with intersample attention (sample similarity) in alternating blocks","Intersample attention is analogous to a learned soft k-NN: similar training samples attend to each other","SCARF pretraining uses marginal-distribution feature corruption with contrastive InfoNCE loss","SAINT generally outperforms FT-Transformer and TabNet but at higher computational cost","O(B²) intersample attention cost requires careful batch size selection to avoid memory issues"]}]"
---
# SAINT — Self-Attention and Intersample Attention for Tabular Data

SAINT (Self-Attention and Intersample Attention Transformer, Somepalli et al. 2021) addresses a key limitation of FT-Transformer: attention is computed only across features of a single row, ignoring relationships between training samples. SAINT adds a second attention axis — across rows — effectively combining a feature-interaction Transformer with a learned k-NN in embedding space.

## Two Types of Attention

Each SAINT block contains two sequential sub-blocks. Row attention (identical to FT-Transformer) processes features within a single sample. Intersample attention processes the representation of the same feature across a batch of samples.

- Row attention: for one sample, attend over F feature tokens — captures feature interactions within a row
- Intersample attention: for a mini-batch of B samples, attend over B sample representations of the same feature position
- Alternating pattern: [Row Attn → Intersample Attn] × N_layers
- Intersample attention lets the model ask: which other training samples are most informative for predicting the current sample?
- Computational cost: O(B²) per intersample attention — quadratic in batch size, not dataset size
- At inference time, the batch acts as the context — similar samples in the batch reinforce predictions

## Row Attention Block

The row attention block is a standard Transformer encoder layer applied to the F feature tokens of a single sample. It is identical in design to one FT-Transformer layer.

```python
import torch
import torch.nn as nn
from torch import Tensor

class RowAttentionBlock(nn.Module):
    """Self-attention over features within each row (identical to FT-Transformer layer)."""
    def __init__(self, d_token: int, n_heads: int, d_ffn: int, dropout: float = 0.1):
        super().__init__()
        self.attn = nn.MultiheadAttention(
            embed_dim=d_token, num_heads=n_heads,
            dropout=dropout, batch_first=True
        )
        self.ff = nn.Sequential(
            nn.LayerNorm(d_token),
            nn.Linear(d_token, d_ffn),
            nn.GELU(),
            nn.Dropout(dropout),
            nn.Linear(d_ffn, d_token),
            nn.Dropout(dropout)
        )
        self.norm1 = nn.LayerNorm(d_token)
        self.norm2 = nn.LayerNorm(d_token)

    def forward(self, x: Tensor) -> Tensor:  # x: (B, F, d)
        # Self-attention over features (F tokens)
        attn_out, _ = self.attn(x, x, x)
        x = self.norm1(x + attn_out)
        # Feed-forward
        x = self.norm2(x + self.ff(x))
        return x  # (B, F, d)
```

## Intersample Attention Block

Intersample attention transposes the batch and feature dimensions: for each feature position, all B sample representations attend to each other. This produces a B×B attention matrix per feature — the model learns which samples are relevant for predicting each other.

```python
import torch
import torch.nn as nn
from torch import Tensor

class IntersampleAttentionBlock(nn.Module):
    """Self-attention over samples for each feature position."""
    def __init__(self, d_token: int, n_heads: int, d_ffn: int, dropout: float = 0.1):
        super().__init__()
        self.attn  = nn.MultiheadAttention(
            embed_dim=d_token, num_heads=n_heads,
            dropout=dropout, batch_first=True
        )
        self.norm1 = nn.LayerNorm(d_token)
        self.norm2 = nn.LayerNorm(d_token)
        self.ff    = nn.Sequential(
            nn.Linear(d_token, d_ffn), nn.GELU(),
            nn.Dropout(dropout),
            nn.Linear(d_ffn, d_token), nn.Dropout(dropout)
        )

    def forward(self, x: Tensor) -> Tensor:  # x: (B, F, d)
        B, F, d = x.shape
        # Transpose: treat each feature position as a sequence of B samples
        x_t = x.permute(1, 0, 2)          # (F, B, d)
        attn_out, _ = self.attn(x_t, x_t, x_t)  # attend over B samples
        x_t = self.norm1(x_t + attn_out)
        x_t = self.norm2(x_t + self.ff(x_t))
        return x_t.permute(1, 0, 2)        # back to (B, F, d)
```

## SAINT Full Forward Pass

SAINT stacks alternating row and intersample attention blocks. The [CLS] token (prepended to the feature sequence) aggregates global information and drives the prediction.

```python
import torch
import torch.nn as nn
from torch import Tensor

class SAINT(nn.Module):
    def __init__(self, n_features: int, d_token: int, n_heads: int,
                 d_ffn: int, n_layers: int, n_classes: int):
        super().__init__()
        # Feature tokenization (numerical, same as FT-Transformer)
        self.tokenizer = nn.Linear(1, d_token)  # simplified: shared projection
        self.cls_token  = nn.Parameter(torch.zeros(1, 1, d_token))

        self.row_blocks = nn.ModuleList([
            RowAttentionBlock(d_token, n_heads, d_ffn) for _ in range(n_layers)
        ])
        self.isample_blocks = nn.ModuleList([
            IntersampleAttentionBlock(d_token, n_heads, d_ffn) for _ in range(n_layers)
        ])
        self.head = nn.Sequential(
            nn.LayerNorm(d_token),
            nn.Linear(d_token, n_classes)
        )

    def forward(self, x: Tensor) -> Tensor:  # x: (B, F)
        # Tokenize each feature independently
        tokens = self.tokenizer(x.unsqueeze(-1))           # (B, F, d)
        cls    = self.cls_token.expand(x.size(0), -1, -1)  # (B, 1, d)
        tokens = torch.cat([cls, tokens], dim=1)            # (B, F+1, d)

        # Alternate row and intersample attention
        for row_blk, isample_blk in zip(self.row_blocks, self.isample_blocks):
            tokens = row_blk(tokens)
            tokens = isample_blk(tokens)

        return self.head(tokens[:, 0])  # CLS token → prediction
```

## SCARF-Style Pretraining

SAINT uses SCARF (Self-supervised Contrastive learning using random Feature Corruption) for pretraining: randomly replace each feature value with a value sampled from the empirical marginal distribution of that feature. The model learns to produce similar representations for clean and corrupted views of the same row (contrastive loss).

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
from torch import Tensor

def scarf_corrupt(x: Tensor, corruption_rate: float = 0.6) -> Tensor:
    """Replace each feature with a random value from its empirical marginal."""
    B, F = x.shape
    mask = torch.bernoulli(torch.full((B, F), corruption_rate)).bool()
    # Sample random row indices for each position to use as replacement
    random_rows = torch.randint(0, B, (B, F))
    x_corrupt   = x.clone()
    for j in range(F):
        x_corrupt[mask[:, j], j] = x[random_rows[mask[:, j], j], j]
    return x_corrupt

class SCARFLoss(nn.Module):
    def __init__(self, temperature: float = 0.07):
        super().__init__()
        self.temperature = temperature

    def forward(self, z_clean: Tensor, z_corrupt: Tensor) -> Tensor:
        z1 = F.normalize(z_clean,   dim=-1)  # (B, d)
        z2 = F.normalize(z_corrupt, dim=-1)  # (B, d)
        logits = z1 @ z2.T / self.temperature  # (B, B)
        labels = torch.arange(z1.size(0), device=z1.device)
        return F.cross_entropy(logits, labels)  # InfoNCE loss
```

---

## SAINT vs Other Tabular Models

| Model | Attention Type | Pretraining | Complexity | Benchmark Performance |
| --- | --- | --- | --- | --- |
| FT-Transformer | Row only (feature × feature) | MLM-style optional | O(F²) per layer | Competitive with XGBoost on large datasets |
| SAINT | Row + Intersample | SCARF contrastive | O(F²) + O(B²) per layer | Generally outperforms FT-Transformer |
| TabNet | Sequential sparse feature selection | Reconstruction pretraining | O(N_steps × F) | Often behind FT-Transformer and SAINT |
| XGBoost | None (greedy splits) | None | O(n log n) per tree | State-of-the-art on most tabular benchmarks |

> **Intersample Attention Cost**: Intersample attention is quadratic in batch size O(B²). For B=512, this means 262,144 attention score computations per feature position per layer. Keep batch sizes moderate (128–512) and monitor GPU memory. At inference, predictions improve when the batch contains diverse, representative samples from the training distribution.

## Key Takeaways

- SAINT combines row attention (feature interactions) with intersample attention (sample similarity) in alternating blocks
- Intersample attention is analogous to a learned soft k-NN: similar training samples attend to each other
- SCARF pretraining uses marginal-distribution feature corruption with contrastive InfoNCE loss
- SAINT generally outperforms FT-Transformer and TabNet but at higher computational cost
- O(B²) intersample attention cost requires careful batch size selection to avoid memory issues

