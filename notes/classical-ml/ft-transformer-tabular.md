---
title: "FT-Transformer — Feature Tokenization for Tabular Data"
slug: "ft-transformer-tabular"
description: "FT-Transformer converts each tabular feature into an embedding token and processes them with a standard Transformer encoder, enabling explicit pairwise feature interactions via self-attention."
tags: ["tabular", "deep-learning", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"FT-Transformer (Gorishniy et al., Yandex Research, 2021) applies the Transformer architecture to tabular data by treating each feature as a token. A standard MLP operates on concatenated raw features and lacks explicit feature-interaction modeling; FT-Transformer\u0027s self-attention lets any feature attend to any other, capturing interaction effects directly."},{"type":"heading","level":2,"content":"Feature Tokenization"},{"type":"text","content":"Each feature is projected to a d-dimensional embedding before being processed by the Transformer encoder. Numerical and categorical features are tokenized differently, but the result is the same shape: one vector of dimension d per feature per sample."},{"type":"list","ordered":false,"items":["Numerical feature i: embed_i = W_i · x_i + b_i  (scalar × d-vector + bias = unique embedding per feature value)","Categorical feature j: standard embedding lookup table, one vector per category","Special [CLS] token prepended to the sequence — its output is used for the final prediction","Sequence length = number of features + 1 ([CLS])","Transformer encoder with multi-head self-attention processes the full feature token sequence"]},{"type":"heading","level":2,"content":"FT-Transformer Implementation"},{"type":"text","content":"Below is a minimal FT-Transformer for numerical features. The key module is NumericalTokenizer, which gives each feature its own linear projection."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torch import Tensor\n\nclass NumericalTokenizer(nn.Module):\n    \"\"\"Project each numerical feature to a d-dim embedding.\"\"\"\n    def __init__(self, n_features: int, d_token: int):\n        super().__init__()\n        # One weight vector per feature (not shared)\n        self.weight = nn.Parameter(torch.empty(n_features, d_token))\n        self.bias   = nn.Parameter(torch.zeros(n_features, d_token))\n        nn.init.kaiming_uniform_(self.weight)\n\n    def forward(self, x: Tensor) -\u003e Tensor:  # x: (B, F)\n        # Outer product: each scalar x_i multiplies its own weight vector\n        return x.unsqueeze(-1) * self.weight.unsqueeze(0) + self.bias.unsqueeze(0)\n        # Output shape: (B, F, d_token)\n\nclass FTTransformer(nn.Module):\n    def __init__(self, n_features: int, d_token: int, n_heads: int,\n                 n_layers: int, d_ffn: int, n_classes: int):\n        super().__init__()\n        self.tokenizer = NumericalTokenizer(n_features, d_token)\n        self.cls_token = nn.Parameter(torch.zeros(1, 1, d_token))\n        encoder_layer  = nn.TransformerEncoderLayer(\n            d_model=d_token, nhead=n_heads,\n            dim_feedforward=d_ffn, batch_first=True\n        )\n        self.encoder = nn.TransformerEncoder(encoder_layer, num_layers=n_layers)\n        self.head    = nn.Linear(d_token, n_classes)\n\n    def forward(self, x: Tensor) -\u003e Tensor:  # x: (B, F)\n        tokens = self.tokenizer(x)                       # (B, F, d)\n        cls    = self.cls_token.expand(x.size(0), -1, -1)  # (B, 1, d)\n        tokens = torch.cat([cls, tokens], dim=1)         # (B, F+1, d)\n        out    = self.encoder(tokens)                    # (B, F+1, d)\n        return self.head(out[:, 0])                      # (B, n_classes)"},{"type":"heading","level":2,"content":"Visualizing Attention Patterns"},{"type":"text","content":"Self-attention weights reveal which feature pairs the model treats as interacting. Extracting attention maps from a trained FT-Transformer provides interpretable feature-interaction heatmaps."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\nimport matplotlib.pyplot as plt\n\ndef extract_attention_weights(model, x_sample):\n    \"\"\"Extract attention weights from each Transformer layer.\"\"\"\n    model.eval()\n    attention_maps = []\n\n    def hook_fn(module, input, output):\n        # TransformerEncoderLayer stores attn_output_weights when need_weights=True\n        pass  # hook approach varies by PyTorch version\n\n    with torch.no_grad():\n        tokens = model.tokenizer(x_sample)\n        cls    = model.cls_token.expand(x_sample.size(0), -1, -1)\n        tokens = torch.cat([cls, tokens], dim=1)\n        # Access attention weights via forward with output_attentions\n        for layer in model.encoder.layers:\n            attn_out, attn_weights = layer.self_attn(\n                tokens, tokens, tokens, need_weights=True, average_attn_weights=True\n            )\n            attention_maps.append(attn_weights.detach().cpu().numpy())\n            tokens = layer(tokens)  # continue forward pass\n    return attention_maps\n\n# Plot average attention for first sample (feature vs feature)\nfeature_names = [f\u0027F{i}\u0027 for i in range(10)]\nattn = np.random.rand(11, 11)  # placeholder — replace with actual weights\nplt.figure(figsize=(8, 6))\nplt.imshow(attn, cmap=\u0027Blues\u0027, vmin=0, vmax=attn.max())\nplt.colorbar(label=\u0027Attention weight\u0027)\nplt.title(\u0027FT-Transformer Feature Attention (layer 1)\u0027)\nplt.tight_layout()\nplt.savefig(\u0027ft_attention.png\u0027, dpi=150)"},{"type":"heading","level":2,"content":"FT-Transformer vs MLP vs XGBoost"},{"type":"text","content":"On a controlled benchmark, FT-Transformer outperforms a plain MLP on datasets with rich feature interactions, and can match XGBoost on larger tabular datasets. The advantage over MLP comes from explicit pairwise attention; the gap versus XGBoost shrinks with increasing n."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\nfrom sklearn.datasets import make_classification\nfrom sklearn.model_selection import train_test_split\nfrom sklearn.metrics import accuracy_score\nfrom sklearn.neural_network import MLPClassifier\nfrom sklearn.preprocessing import StandardScaler\nfrom sklearn.pipeline import Pipeline\nimport xgboost as xgb\n\n# Dataset with interaction effects\nX, y = make_classification(\n    n_samples=5000, n_features=10, n_informative=8,\n    n_redundant=0, n_clusters_per_class=2, random_state=42\n)\nX_tr, X_te, y_tr, y_te = train_test_split(\n    X.astype(np.float32), y, test_size=0.2, random_state=42\n)\n\n# XGBoost baseline\nxgb_model = xgb.XGBClassifier(n_estimators=200, max_depth=6, random_state=42)\nxgb_model.fit(X_tr, y_tr)\nprint(f\u0027XGBoost:       {accuracy_score(y_te, xgb_model.predict(X_te)):.4f}\u0027)\n\n# MLP baseline\nmlp = Pipeline([(\u0027sc\u0027, StandardScaler()),\n                (\u0027net\u0027, MLPClassifier(hidden_layer_sizes=(128, 64), max_iter=300))])\nmlp.fit(X_tr, y_tr)\nprint(f\u0027MLP:           {accuracy_score(y_te, mlp.predict(X_te)):.4f}\u0027)\n\n# FT-Transformer (simplified training loop)\nmodel = FTTransformer(n_features=10, d_token=64, n_heads=4,\n                      n_layers=3, d_ffn=128, n_classes=2)\nprint(f\u0027FT-Transformer params: {sum(p.numel() for p in model.parameters()):,}\u0027)"},{"type":"heading","level":2,"content":"Numerical vs Categorical Tokenization"},{"type":"text","content":"The key design decision in FT-Transformer is how to tokenize heterogeneous feature types. Numerical features use a unique linear projection per feature; categoricals use learned embedding tables."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass CategoricalTokenizer(nn.Module):\n    def __init__(self, cardinalities: list, d_token: int):\n        super().__init__()\n        # One embedding table per categorical column\n        self.embeddings = nn.ModuleList([\n            nn.Embedding(n_cats, d_token) for n_cats in cardinalities\n        ])\n\n    def forward(self, x_cat: torch.Tensor) -\u003e torch.Tensor:\n        # x_cat: (B, n_cat_features) — integer indices\n        tokens = [emb(x_cat[:, i]) for i, emb in enumerate(self.embeddings)]\n        return torch.stack(tokens, dim=1)  # (B, n_cat_features, d_token)\n\nclass MixedTokenizer(nn.Module):\n    def __init__(self, n_num: int, cardinalities: list, d_token: int):\n        super().__init__()\n        self.num_tokenizer = NumericalTokenizer(n_num, d_token)\n        self.cat_tokenizer = CategoricalTokenizer(cardinalities, d_token)\n\n    def forward(self, x_num: torch.Tensor, x_cat: torch.Tensor) -\u003e torch.Tensor:\n        num_tokens = self.num_tokenizer(x_num)  # (B, n_num, d)\n        cat_tokens = self.cat_tokenizer(x_cat)  # (B, n_cat, d)\n        return torch.cat([num_tokens, cat_tokens], dim=1)  # (B, n_num+n_cat, d)\n\n# Test\ntokenizer = MixedTokenizer(n_num=5, cardinalities=[10, 50, 200], d_token=64)\nx_num = torch.randn(32, 5)\nx_cat = torch.randint(0, 10, (32, 3))\ntokens = tokenizer(x_num, x_cat)\nprint(f\u0027Token sequence shape: {tokens.shape}\u0027)  # (32, 8, 64)"},{"type":"divider"},{"type":"heading","level":2,"content":"Architecture Comparison"},{"type":"table","headers":["Architecture","Feature Interactions","Attention","Pretraining","Benchmark","Scalability"],"rows":[["Plain MLP","Implicit (all layers)","None","None","Weaker on interaction-heavy data","Fast training"],["FT-Transformer","Explicit pairwise (self-attention)","Feature-to-feature","MLM-style possible","Competitive with XGBoost at large n","O(F²) per layer"],["TabNet","Sequential sparse (attention mask)","Step-wise feature selection","Reconstruction pretraining","Competitive, often behind FT-Transformer","O(F) per step"],["XGBoost","Explicit (split hierarchy)","None — greedy splitting","None","State-of-the-art on most benchmarks","Scales to millions of rows"]]},{"type":"callout","variant":"info","title":"FT-Transformer Best Use Cases","content":"FT-Transformer is most effective when (1) your dataset is large enough (n \u003e 10k) to train deep attention layers, (2) features have meaningful pairwise interactions that axis-aligned splits miss, and (3) you want a single neural backbone for tabular + other modalities in an end-to-end system."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"list","ordered":false,"items":["FT-Transformer tokenizes each feature into a d-dim vector — numerical via unique linear projection, categorical via embedding lookup","A [CLS] token aggregates information from all feature tokens; its output drives the prediction head","Self-attention enables explicit, learnable pairwise feature interactions — unlike MLP which relies on implicit interactions","FT-Transformer competes with XGBoost on large tabular datasets but rarely outperforms it on small n","Mixed numerical-categorical inputs are handled cleanly with different tokenizer heads"]}]"
---
# FT-Transformer — Feature Tokenization for Tabular Data

FT-Transformer (Gorishniy et al., Yandex Research, 2021) applies the Transformer architecture to tabular data by treating each feature as a token. A standard MLP operates on concatenated raw features and lacks explicit feature-interaction modeling; FT-Transformer's self-attention lets any feature attend to any other, capturing interaction effects directly.

## Feature Tokenization

Each feature is projected to a d-dimensional embedding before being processed by the Transformer encoder. Numerical and categorical features are tokenized differently, but the result is the same shape: one vector of dimension d per feature per sample.

- Numerical feature i: embed_i = W_i · x_i + b_i  (scalar × d-vector + bias = unique embedding per feature value)
- Categorical feature j: standard embedding lookup table, one vector per category
- Special [CLS] token prepended to the sequence — its output is used for the final prediction
- Sequence length = number of features + 1 ([CLS])
- Transformer encoder with multi-head self-attention processes the full feature token sequence

## FT-Transformer Implementation

Below is a minimal FT-Transformer for numerical features. The key module is NumericalTokenizer, which gives each feature its own linear projection.

```python
import torch
import torch.nn as nn
from torch import Tensor

class NumericalTokenizer(nn.Module):
    """Project each numerical feature to a d-dim embedding."""
    def __init__(self, n_features: int, d_token: int):
        super().__init__()
        # One weight vector per feature (not shared)
        self.weight = nn.Parameter(torch.empty(n_features, d_token))
        self.bias   = nn.Parameter(torch.zeros(n_features, d_token))
        nn.init.kaiming_uniform_(self.weight)

    def forward(self, x: Tensor) -> Tensor:  # x: (B, F)
        # Outer product: each scalar x_i multiplies its own weight vector
        return x.unsqueeze(-1) * self.weight.unsqueeze(0) + self.bias.unsqueeze(0)
        # Output shape: (B, F, d_token)

class FTTransformer(nn.Module):
    def __init__(self, n_features: int, d_token: int, n_heads: int,
                 n_layers: int, d_ffn: int, n_classes: int):
        super().__init__()
        self.tokenizer = NumericalTokenizer(n_features, d_token)
        self.cls_token = nn.Parameter(torch.zeros(1, 1, d_token))
        encoder_layer  = nn.TransformerEncoderLayer(
            d_model=d_token, nhead=n_heads,
            dim_feedforward=d_ffn, batch_first=True
        )
        self.encoder = nn.TransformerEncoder(encoder_layer, num_layers=n_layers)
        self.head    = nn.Linear(d_token, n_classes)

    def forward(self, x: Tensor) -> Tensor:  # x: (B, F)
        tokens = self.tokenizer(x)                       # (B, F, d)
        cls    = self.cls_token.expand(x.size(0), -1, -1)  # (B, 1, d)
        tokens = torch.cat([cls, tokens], dim=1)         # (B, F+1, d)
        out    = self.encoder(tokens)                    # (B, F+1, d)
        return self.head(out[:, 0])                      # (B, n_classes)
```

## Visualizing Attention Patterns

Self-attention weights reveal which feature pairs the model treats as interacting. Extracting attention maps from a trained FT-Transformer provides interpretable feature-interaction heatmaps.

```python
import torch
import numpy as np
import matplotlib.pyplot as plt

def extract_attention_weights(model, x_sample):
    """Extract attention weights from each Transformer layer."""
    model.eval()
    attention_maps = []

    def hook_fn(module, input, output):
        # TransformerEncoderLayer stores attn_output_weights when need_weights=True
        pass  # hook approach varies by PyTorch version

    with torch.no_grad():
        tokens = model.tokenizer(x_sample)
        cls    = model.cls_token.expand(x_sample.size(0), -1, -1)
        tokens = torch.cat([cls, tokens], dim=1)
        # Access attention weights via forward with output_attentions
        for layer in model.encoder.layers:
            attn_out, attn_weights = layer.self_attn(
                tokens, tokens, tokens, need_weights=True, average_attn_weights=True
            )
            attention_maps.append(attn_weights.detach().cpu().numpy())
            tokens = layer(tokens)  # continue forward pass
    return attention_maps

# Plot average attention for first sample (feature vs feature)
feature_names = [f'F{i}' for i in range(10)]
attn = np.random.rand(11, 11)  # placeholder — replace with actual weights
plt.figure(figsize=(8, 6))
plt.imshow(attn, cmap='Blues', vmin=0, vmax=attn.max())
plt.colorbar(label='Attention weight')
plt.title('FT-Transformer Feature Attention (layer 1)')
plt.tight_layout()
plt.savefig('ft_attention.png', dpi=150)
```

## FT-Transformer vs MLP vs XGBoost

On a controlled benchmark, FT-Transformer outperforms a plain MLP on datasets with rich feature interactions, and can match XGBoost on larger tabular datasets. The advantage over MLP comes from explicit pairwise attention; the gap versus XGBoost shrinks with increasing n.

```python
import numpy as np
import torch
import torch.nn as nn
from sklearn.datasets import make_classification
from sklearn.model_selection import train_test_split
from sklearn.metrics import accuracy_score
from sklearn.neural_network import MLPClassifier
from sklearn.preprocessing import StandardScaler
from sklearn.pipeline import Pipeline
import xgboost as xgb

# Dataset with interaction effects
X, y = make_classification(
    n_samples=5000, n_features=10, n_informative=8,
    n_redundant=0, n_clusters_per_class=2, random_state=42
)
X_tr, X_te, y_tr, y_te = train_test_split(
    X.astype(np.float32), y, test_size=0.2, random_state=42
)

# XGBoost baseline
xgb_model = xgb.XGBClassifier(n_estimators=200, max_depth=6, random_state=42)
xgb_model.fit(X_tr, y_tr)
print(f'XGBoost:       {accuracy_score(y_te, xgb_model.predict(X_te)):.4f}')

# MLP baseline
mlp = Pipeline([('sc', StandardScaler()),
                ('net', MLPClassifier(hidden_layer_sizes=(128, 64), max_iter=300))])
mlp.fit(X_tr, y_tr)
print(f'MLP:           {accuracy_score(y_te, mlp.predict(X_te)):.4f}')

# FT-Transformer (simplified training loop)
model = FTTransformer(n_features=10, d_token=64, n_heads=4,
                      n_layers=3, d_ffn=128, n_classes=2)
print(f'FT-Transformer params: {sum(p.numel() for p in model.parameters()):,}')
```

## Numerical vs Categorical Tokenization

The key design decision in FT-Transformer is how to tokenize heterogeneous feature types. Numerical features use a unique linear projection per feature; categoricals use learned embedding tables.

```python
import torch
import torch.nn as nn

class CategoricalTokenizer(nn.Module):
    def __init__(self, cardinalities: list, d_token: int):
        super().__init__()
        # One embedding table per categorical column
        self.embeddings = nn.ModuleList([
            nn.Embedding(n_cats, d_token) for n_cats in cardinalities
        ])

    def forward(self, x_cat: torch.Tensor) -> torch.Tensor:
        # x_cat: (B, n_cat_features) — integer indices
        tokens = [emb(x_cat[:, i]) for i, emb in enumerate(self.embeddings)]
        return torch.stack(tokens, dim=1)  # (B, n_cat_features, d_token)

class MixedTokenizer(nn.Module):
    def __init__(self, n_num: int, cardinalities: list, d_token: int):
        super().__init__()
        self.num_tokenizer = NumericalTokenizer(n_num, d_token)
        self.cat_tokenizer = CategoricalTokenizer(cardinalities, d_token)

    def forward(self, x_num: torch.Tensor, x_cat: torch.Tensor) -> torch.Tensor:
        num_tokens = self.num_tokenizer(x_num)  # (B, n_num, d)
        cat_tokens = self.cat_tokenizer(x_cat)  # (B, n_cat, d)
        return torch.cat([num_tokens, cat_tokens], dim=1)  # (B, n_num+n_cat, d)

# Test
tokenizer = MixedTokenizer(n_num=5, cardinalities=[10, 50, 200], d_token=64)
x_num = torch.randn(32, 5)
x_cat = torch.randint(0, 10, (32, 3))
tokens = tokenizer(x_num, x_cat)
print(f'Token sequence shape: {tokens.shape}')  # (32, 8, 64)
```

---

## Architecture Comparison

| Architecture | Feature Interactions | Attention | Pretraining | Benchmark | Scalability |
| --- | --- | --- | --- | --- | --- |
| Plain MLP | Implicit (all layers) | None | None | Weaker on interaction-heavy data | Fast training |
| FT-Transformer | Explicit pairwise (self-attention) | Feature-to-feature | MLM-style possible | Competitive with XGBoost at large n | O(F²) per layer |
| TabNet | Sequential sparse (attention mask) | Step-wise feature selection | Reconstruction pretraining | Competitive, often behind FT-Transformer | O(F) per step |
| XGBoost | Explicit (split hierarchy) | None — greedy splitting | None | State-of-the-art on most benchmarks | Scales to millions of rows |

> **FT-Transformer Best Use Cases**: FT-Transformer is most effective when (1) your dataset is large enough (n > 10k) to train deep attention layers, (2) features have meaningful pairwise interactions that axis-aligned splits miss, and (3) you want a single neural backbone for tabular + other modalities in an end-to-end system.

## Key Takeaways

- FT-Transformer tokenizes each feature into a d-dim vector — numerical via unique linear projection, categorical via embedding lookup
- A [CLS] token aggregates information from all feature tokens; its output drives the prediction head
- Self-attention enables explicit, learnable pairwise feature interactions — unlike MLP which relies on implicit interactions
- FT-Transformer competes with XGBoost on large tabular datasets but rarely outperforms it on small n
- Mixed numerical-categorical inputs are handled cleanly with different tokenizer heads

