---
title: "When Deep Learning Beats Gradient Boosting on Tabular Data"
slug: "when-dl-beats-gbm-tabular"
description: "Conditions where neural networks outperform gradient-boosted trees on tabular data: large datasets, multi-modal inputs, smooth functions, online learning, and multi-task scenarios."
tags: ["tabular", "deep-learning", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Gradient-boosted trees win on most tabular benchmarks — but not all. Neural networks have structural advantages in specific scenarios: very large datasets, multi-modal inputs, streaming data, multi-task learning, and smooth target functions. Knowing these conditions helps you choose the right tool rather than defaulting to XGBoost everywhere."},{"type":"heading","level":2,"content":"Conditions Favoring Deep Learning"},{"type":"text","content":"Seven conditions where DL outperforms GBM on tabular data, each rooted in a structural advantage of neural networks over decision trees:"},{"type":"list","ordered":false,"items":["Very large n (\u003e1M): tree inference is linear in n_estimators × tree depth; NN inference is O(1) in n","Multi-modal inputs: NN handles tabular + images + text in one model; trees cannot process raw pixels or token sequences","Smooth target functions: physical simulations, financial pricing models — NN implicit regularization fits smooth functions better","Online/streaming learning: NN with SGD updates incrementally from new samples; trees need full rebuilds","Multi-task learning: shared NN representations generalize across related tasks; separate trees per task don\u0027t share capacity","Transfer learning: pre-trained tabular transformers (TabPFN, prior work) can be fine-tuned; no tree equivalent","End-to-end systems: recommendation, ranking — NN integrates user embedding + item features + context jointly"]},{"type":"heading","level":2,"content":"DL vs GBM Across Dataset Sizes"},{"type":"text","content":"The crossover between GBM and DL accuracy depends on dataset size. Trees dominate at small n; the gap narrows as n grows. This benchmark illustrates the trend across five orders of magnitude."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.datasets import make_classification\nfrom sklearn.model_selection import cross_val_score\nfrom sklearn.neural_network import MLPClassifier\nfrom sklearn.preprocessing import StandardScaler\nfrom sklearn.pipeline import Pipeline\nimport xgboost as xgb\nimport time\n\nsizes = [100, 500, 1000, 5000, 10000, 50000]\nresults = []\n\nfor n in sizes:\n    X, y = make_classification(\n        n_samples=n, n_features=20, n_informative=10, random_state=42\n    )\n    gbm = xgb.XGBClassifier(n_estimators=200, max_depth=6, learning_rate=0.05,\n                             random_state=42, eval_metric=\u0027logloss\u0027)\n    mlp = Pipeline([\n        (\u0027sc\u0027, StandardScaler()),\n        (\u0027net\u0027, MLPClassifier(\n            hidden_layer_sizes=(256, 128, 64), max_iter=400,\n            early_stopping=True, random_state=42\n        ))\n    ])\n    cv = max(3, min(5, n // 500))\n    t0 = time.time()\n    gbm_score = cross_val_score(gbm, X, y, cv=cv).mean()\n    gbm_time  = time.time() - t0\n    t0 = time.time()\n    mlp_score = cross_val_score(mlp, X, y, cv=cv).mean()\n    mlp_time  = time.time() - t0\n    print(f\u0027n={n:\u003e6}: GBM={gbm_score:.3f}({gbm_time:.1f}s)  MLP={mlp_score:.3f}({mlp_time:.1f}s)\u0027)"},{"type":"heading","level":2,"content":"Multi-Task Learning with Shared Representations"},{"type":"text","content":"Neural networks learn shared feature representations across related tasks. A single backbone trained on multiple tabular targets simultaneously often outperforms per-task trees, especially when tasks share underlying structure."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torch.utils.data import DataLoader, TensorDataset\nimport numpy as np\nfrom sklearn.datasets import make_classification\n\nclass MultiTaskTabular(nn.Module):\n    def __init__(self, n_features: int, hidden: int, n_tasks: int):\n        super().__init__()\n        # Shared encoder — learns representations useful across all tasks\n        self.backbone = nn.Sequential(\n            nn.Linear(n_features, hidden), nn.LayerNorm(hidden), nn.ReLU(),\n            nn.Linear(hidden, hidden // 2), nn.LayerNorm(hidden // 2), nn.ReLU()\n        )\n        # Task-specific heads\n        self.heads = nn.ModuleList([\n            nn.Linear(hidden // 2, 1) for _ in range(n_tasks)\n        ])\n\n    def forward(self, x: torch.Tensor) -\u003e list:\n        shared = self.backbone(x)\n        return [head(shared).squeeze(-1) for head in self.heads]\n\n# Multi-task dataset: 3 correlated binary targets\nnp.random.seed(42)\nX = np.random.randn(2000, 20).astype(np.float32)\ny1 = (X[:, 0] + X[:, 1] \u003e 0).astype(np.float32)\ny2 = (X[:, 0] - X[:, 2] \u003e 0).astype(np.float32)\ny3 = (X[:, 1] + X[:, 3] \u003e 0).astype(np.float32)\n\nmodel  = MultiTaskTabular(n_features=20, hidden=128, n_tasks=3)\ncriterion = nn.BCEWithLogitsLoss()\noptimizer = torch.optim.Adam(model.parameters(), lr=1e-3)\nprint(f\u0027Shared backbone params: {sum(p.numel() for p in model.backbone.parameters()):,}\u0027)"},{"type":"heading","level":2,"content":"Online Learning: Incremental NN vs Rebuilding Trees"},{"type":"text","content":"For streaming data, neural networks update naturally from each new batch via SGD. Tree models require full retraining when new data arrives, making them impractical for high-velocity streams."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\nfrom sklearn.linear_model import SGDClassifier\nfrom sklearn.ensemble import RandomForestClassifier\nfrom sklearn.metrics import accuracy_score\nfrom sklearn.preprocessing import StandardScaler\n\nrng  = np.random.default_rng(42)\nn_total, n_init, batch_size = 5000, 1000, 100\n\nX_all = rng.standard_normal((n_total, 10)).astype(np.float32)\ny_all = (X_all[:, 0] + X_all[:, 1] \u003e 0).astype(int)\n\nsc = StandardScaler().fit(X_all[:n_init])\nX_all_sc = sc.transform(X_all)\n\n# Online learner: SGDClassifier supports partial_fit\nsgd = SGDClassifier(loss=\u0027log_loss\u0027, random_state=42)\nsgd.partial_fit(X_all_sc[:n_init], y_all[:n_init], classes=[0, 1])\n\n# Batch learner: RandomForest requires full refit\nrf = RandomForestClassifier(n_estimators=50, random_state=42)\nrf.fit(X_all_sc[:n_init], y_all[:n_init])\n\n# Stream new batches\nfor start in range(n_init, n_total, batch_size):\n    end = start + batch_size\n    X_batch, y_batch = X_all_sc[start:end], y_all[start:end]\n    sgd.partial_fit(X_batch, y_batch)  # O(batch) update\n    # RF: would need rf.fit(X_all_sc[:end], y_all[:end]) — O(n) rebuild\n\nprint(f\u0027SGD online accuracy: {accuracy_score(y_all[n_init:], sgd.predict(X_all_sc[n_init:])):.4f}\u0027)"},{"type":"heading","level":2,"content":"Multi-Modal: Tabular + Text Feature Fusion"},{"type":"text","content":"When tabular rows include a free-text column (product description, customer review), neural networks can fuse the text encoding with tabular features in a single model. Trees require a hand-crafted text-to-numeric pipeline."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom transformers import AutoTokenizer, AutoModel\nimport numpy as np\n\nclass MultiModalTabularText(nn.Module):\n    \"\"\"Fuse tabular numeric features with BERT text embeddings.\"\"\"\n    def __init__(self, n_tabular: int, text_dim: int, hidden: int, n_classes: int):\n        super().__init__()\n        self.text_encoder = AutoModel.from_pretrained(\u0027distilbert-base-uncased\u0027)\n        self.text_proj    = nn.Linear(text_dim, hidden)\n        self.tab_proj     = nn.Linear(n_tabular, hidden)\n        self.fusion = nn.Sequential(\n            nn.LayerNorm(hidden * 2),\n            nn.Linear(hidden * 2, hidden),\n            nn.GELU(),\n            nn.Dropout(0.2),\n            nn.Linear(hidden, n_classes)\n        )\n\n    def forward(self, x_tab: torch.Tensor, input_ids: torch.Tensor,\n                attention_mask: torch.Tensor) -\u003e torch.Tensor:\n        # Encode text with DistilBERT\n        text_out   = self.text_encoder(input_ids, attention_mask).last_hidden_state\n        text_cls   = text_out[:, 0]           # CLS token: (B, 768)\n        text_feat  = self.text_proj(text_cls)  # (B, hidden)\n        # Encode tabular features\n        tab_feat   = self.tab_proj(x_tab)      # (B, hidden)\n        # Fuse and classify\n        fused = torch.cat([text_feat, tab_feat], dim=1)\n        return self.fusion(fused)\n\nmodel = MultiModalTabularText(n_tabular=10, text_dim=768, hidden=128, n_classes=2)\nprint(f\u0027Total parameters: {sum(p.numel() for p in model.parameters()):,}\u0027)"},{"type":"divider"},{"type":"heading","level":2,"content":"DL vs GBM Decision Framework"},{"type":"table","headers":["Condition","Dataset Size","Winner","Recommendation"],"rows":[["Small tabular, n\u003c1k","Small","GBM / TabPFN","Use TabPFN or XGBoost with HPO"],["Medium tabular, n=1k-100k","Medium","GBM","XGBoost/LightGBM with Optuna tuning"],["Large tabular, n\u003e1M","Large","Competitive","FT-Transformer or LightGBM; benchmark both"],["Multi-modal (tabular+text/image)","Any","DL","Neural fusion model required"],["Streaming / online updates","Any","DL","SGD-based NN; trees need full rebuild"],["Multi-task (shared representation)","Any","DL","Shared backbone NN with task-specific heads"],["Smooth target function","Any","DL","MLP or FT-Transformer; less regularization"],["Need native interpretability","Any","Depends","SHAP for GBM; attention maps for TabNet/SAINT"]]},{"type":"callout","variant":"tip","title":"HPO Budget Matters","content":"XGBoost with default hyperparameters sometimes loses to well-tuned deep learning. Always compare under equal HPO budgets: if you spend 100 Optuna trials on XGBoost and 100 on FT-Transformer, the DL gap often narrows significantly — especially on datasets with n \u003e 10k."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"list","ordered":false,"items":["DL wins on multi-modal inputs, online learning, multi-task learning, and very large datasets","The n-threshold for DL competitiveness is roughly 10k-100k depending on feature complexity","FT-Transformer and SAINT are the strongest tabular DL models at large n","Multi-task shared backbones are a natural fit for related prediction problems that GBM cannot handle jointly","Always benchmark under equal HPO effort — XGBoost default often loses to well-tuned DL on larger datasets"]}]"
---
# When Deep Learning Beats Gradient Boosting on Tabular Data

Gradient-boosted trees win on most tabular benchmarks — but not all. Neural networks have structural advantages in specific scenarios: very large datasets, multi-modal inputs, streaming data, multi-task learning, and smooth target functions. Knowing these conditions helps you choose the right tool rather than defaulting to XGBoost everywhere.

## Conditions Favoring Deep Learning

Seven conditions where DL outperforms GBM on tabular data, each rooted in a structural advantage of neural networks over decision trees:

- Very large n (>1M): tree inference is linear in n_estimators × tree depth; NN inference is O(1) in n
- Multi-modal inputs: NN handles tabular + images + text in one model; trees cannot process raw pixels or token sequences
- Smooth target functions: physical simulations, financial pricing models — NN implicit regularization fits smooth functions better
- Online/streaming learning: NN with SGD updates incrementally from new samples; trees need full rebuilds
- Multi-task learning: shared NN representations generalize across related tasks; separate trees per task don't share capacity
- Transfer learning: pre-trained tabular transformers (TabPFN, prior work) can be fine-tuned; no tree equivalent
- End-to-end systems: recommendation, ranking — NN integrates user embedding + item features + context jointly

## DL vs GBM Across Dataset Sizes

The crossover between GBM and DL accuracy depends on dataset size. Trees dominate at small n; the gap narrows as n grows. This benchmark illustrates the trend across five orders of magnitude.

```python
import numpy as np
from sklearn.datasets import make_classification
from sklearn.model_selection import cross_val_score
from sklearn.neural_network import MLPClassifier
from sklearn.preprocessing import StandardScaler
from sklearn.pipeline import Pipeline
import xgboost as xgb
import time

sizes = [100, 500, 1000, 5000, 10000, 50000]
results = []

for n in sizes:
    X, y = make_classification(
        n_samples=n, n_features=20, n_informative=10, random_state=42
    )
    gbm = xgb.XGBClassifier(n_estimators=200, max_depth=6, learning_rate=0.05,
                             random_state=42, eval_metric='logloss')
    mlp = Pipeline([
        ('sc', StandardScaler()),
        ('net', MLPClassifier(
            hidden_layer_sizes=(256, 128, 64), max_iter=400,
            early_stopping=True, random_state=42
        ))
    ])
    cv = max(3, min(5, n // 500))
    t0 = time.time()
    gbm_score = cross_val_score(gbm, X, y, cv=cv).mean()
    gbm_time  = time.time() - t0
    t0 = time.time()
    mlp_score = cross_val_score(mlp, X, y, cv=cv).mean()
    mlp_time  = time.time() - t0
    print(f'n={n:>6}: GBM={gbm_score:.3f}({gbm_time:.1f}s)  MLP={mlp_score:.3f}({mlp_time:.1f}s)')
```

## Multi-Task Learning with Shared Representations

Neural networks learn shared feature representations across related tasks. A single backbone trained on multiple tabular targets simultaneously often outperforms per-task trees, especially when tasks share underlying structure.

```python
import torch
import torch.nn as nn
from torch.utils.data import DataLoader, TensorDataset
import numpy as np
from sklearn.datasets import make_classification

class MultiTaskTabular(nn.Module):
    def __init__(self, n_features: int, hidden: int, n_tasks: int):
        super().__init__()
        # Shared encoder — learns representations useful across all tasks
        self.backbone = nn.Sequential(
            nn.Linear(n_features, hidden), nn.LayerNorm(hidden), nn.ReLU(),
            nn.Linear(hidden, hidden // 2), nn.LayerNorm(hidden // 2), nn.ReLU()
        )
        # Task-specific heads
        self.heads = nn.ModuleList([
            nn.Linear(hidden // 2, 1) for _ in range(n_tasks)
        ])

    def forward(self, x: torch.Tensor) -> list:
        shared = self.backbone(x)
        return [head(shared).squeeze(-1) for head in self.heads]

# Multi-task dataset: 3 correlated binary targets
np.random.seed(42)
X = np.random.randn(2000, 20).astype(np.float32)
y1 = (X[:, 0] + X[:, 1] > 0).astype(np.float32)
y2 = (X[:, 0] - X[:, 2] > 0).astype(np.float32)
y3 = (X[:, 1] + X[:, 3] > 0).astype(np.float32)

model  = MultiTaskTabular(n_features=20, hidden=128, n_tasks=3)
criterion = nn.BCEWithLogitsLoss()
optimizer = torch.optim.Adam(model.parameters(), lr=1e-3)
print(f'Shared backbone params: {sum(p.numel() for p in model.backbone.parameters()):,}')
```

## Online Learning: Incremental NN vs Rebuilding Trees

For streaming data, neural networks update naturally from each new batch via SGD. Tree models require full retraining when new data arrives, making them impractical for high-velocity streams.

```python
import numpy as np
import torch
import torch.nn as nn
from sklearn.linear_model import SGDClassifier
from sklearn.ensemble import RandomForestClassifier
from sklearn.metrics import accuracy_score
from sklearn.preprocessing import StandardScaler

rng  = np.random.default_rng(42)
n_total, n_init, batch_size = 5000, 1000, 100

X_all = rng.standard_normal((n_total, 10)).astype(np.float32)
y_all = (X_all[:, 0] + X_all[:, 1] > 0).astype(int)

sc = StandardScaler().fit(X_all[:n_init])
X_all_sc = sc.transform(X_all)

# Online learner: SGDClassifier supports partial_fit
sgd = SGDClassifier(loss='log_loss', random_state=42)
sgd.partial_fit(X_all_sc[:n_init], y_all[:n_init], classes=[0, 1])

# Batch learner: RandomForest requires full refit
rf = RandomForestClassifier(n_estimators=50, random_state=42)
rf.fit(X_all_sc[:n_init], y_all[:n_init])

# Stream new batches
for start in range(n_init, n_total, batch_size):
    end = start + batch_size
    X_batch, y_batch = X_all_sc[start:end], y_all[start:end]
    sgd.partial_fit(X_batch, y_batch)  # O(batch) update
    # RF: would need rf.fit(X_all_sc[:end], y_all[:end]) — O(n) rebuild

print(f'SGD online accuracy: {accuracy_score(y_all[n_init:], sgd.predict(X_all_sc[n_init:])):.4f}')
```

## Multi-Modal: Tabular + Text Feature Fusion

When tabular rows include a free-text column (product description, customer review), neural networks can fuse the text encoding with tabular features in a single model. Trees require a hand-crafted text-to-numeric pipeline.

```python
import torch
import torch.nn as nn
from transformers import AutoTokenizer, AutoModel
import numpy as np

class MultiModalTabularText(nn.Module):
    """Fuse tabular numeric features with BERT text embeddings."""
    def __init__(self, n_tabular: int, text_dim: int, hidden: int, n_classes: int):
        super().__init__()
        self.text_encoder = AutoModel.from_pretrained('distilbert-base-uncased')
        self.text_proj    = nn.Linear(text_dim, hidden)
        self.tab_proj     = nn.Linear(n_tabular, hidden)
        self.fusion = nn.Sequential(
            nn.LayerNorm(hidden * 2),
            nn.Linear(hidden * 2, hidden),
            nn.GELU(),
            nn.Dropout(0.2),
            nn.Linear(hidden, n_classes)
        )

    def forward(self, x_tab: torch.Tensor, input_ids: torch.Tensor,
                attention_mask: torch.Tensor) -> torch.Tensor:
        # Encode text with DistilBERT
        text_out   = self.text_encoder(input_ids, attention_mask).last_hidden_state
        text_cls   = text_out[:, 0]           # CLS token: (B, 768)
        text_feat  = self.text_proj(text_cls)  # (B, hidden)
        # Encode tabular features
        tab_feat   = self.tab_proj(x_tab)      # (B, hidden)
        # Fuse and classify
        fused = torch.cat([text_feat, tab_feat], dim=1)
        return self.fusion(fused)

model = MultiModalTabularText(n_tabular=10, text_dim=768, hidden=128, n_classes=2)
print(f'Total parameters: {sum(p.numel() for p in model.parameters()):,}')
```

---

## DL vs GBM Decision Framework

| Condition | Dataset Size | Winner | Recommendation |
| --- | --- | --- | --- |
| Small tabular, n<1k | Small | GBM / TabPFN | Use TabPFN or XGBoost with HPO |
| Medium tabular, n=1k-100k | Medium | GBM | XGBoost/LightGBM with Optuna tuning |
| Large tabular, n>1M | Large | Competitive | FT-Transformer or LightGBM; benchmark both |
| Multi-modal (tabular+text/image) | Any | DL | Neural fusion model required |
| Streaming / online updates | Any | DL | SGD-based NN; trees need full rebuild |
| Multi-task (shared representation) | Any | DL | Shared backbone NN with task-specific heads |
| Smooth target function | Any | DL | MLP or FT-Transformer; less regularization |
| Need native interpretability | Any | Depends | SHAP for GBM; attention maps for TabNet/SAINT |

> **HPO Budget Matters**: XGBoost with default hyperparameters sometimes loses to well-tuned deep learning. Always compare under equal HPO budgets: if you spend 100 Optuna trials on XGBoost and 100 on FT-Transformer, the DL gap often narrows significantly — especially on datasets with n > 10k.

## Key Takeaways

- DL wins on multi-modal inputs, online learning, multi-task learning, and very large datasets
- The n-threshold for DL competitiveness is roughly 10k-100k depending on feature complexity
- FT-Transformer and SAINT are the strongest tabular DL models at large n
- Multi-task shared backbones are a natural fit for related prediction problems that GBM cannot handle jointly
- Always benchmark under equal HPO effort — XGBoost default often loses to well-tuned DL on larger datasets

