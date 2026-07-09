---
title: "Entity Embeddings — Learning Representations for Categorical Variables"
slug: "entity-embeddings"
description: "Entity embeddings learn dense vector representations for high-cardinality categorical features — capturing similarity structure and dramatically outperforming one-hot encoding."
tags: ["tabular", "deep-learning", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"One-hot encoding for high-cardinality categorical columns (cities, products, users) produces extremely high-dimensional, sparse representations with no similarity structure. Entity embeddings (Guo \u0026 Berkhahn 2016, popularized by the Rossman Kaggle competition winner) learn dense vector representations that encode semantic similarity — Paris and London end up nearby in embedding space."},{"type":"heading","level":2,"content":"The Problem with One-Hot Encoding"},{"type":"text","content":"For a categorical column with 10,000 unique values (e.g., ZIP codes), one-hot encoding creates 10,000 binary features. The representation is (1) sparse, wasting memory and compute; (2) equally distant — ZIP code 90210 is exactly as distant from 90211 as from 10001, despite being geographically adjacent; (3) not learnable — there is no mechanism to push similar categories closer together."},{"type":"list","ordered":false,"items":["Dimensionality: |vocab| features per column — grows linearly with cardinality","No similarity structure: all category pairs are equidistant in Hamming distance","Sparse gradients: each training sample updates only one position of each one-hot column","Heuristic embedding dim: k = ceil(|vocab|^0.25) or k = min(50, |vocab| // 2) are common choices","End-to-end training: embeddings are learned jointly with the model, capturing task-relevant similarity"]},{"type":"heading","level":2,"content":"Entity Embedding Layer in PyTorch"},{"type":"text","content":"An entity embedding is simply an nn.Embedding lookup table. Given an integer category index, it returns the corresponding dense vector. All embedding vectors are trained jointly with the rest of the neural network via backpropagation."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\nclass TabularModel(nn.Module):\n    \"\"\"Mixed model: entity embeddings for categoricals + MLP for numerics.\"\"\"\n    def __init__(self, cat_dims: list, emb_dims: list, n_cont: int,\n                 hidden_sizes: list, n_out: int, dropout: float = 0.3):\n        super().__init__()\n        # Entity embedding tables: one per categorical column\n        self.embeddings = nn.ModuleList([\n            nn.Embedding(n_cats, emb_dim)\n            for n_cats, emb_dim in zip(cat_dims, emb_dims)\n        ])\n        emb_total = sum(emb_dims)\n        in_dim = emb_total + n_cont  # concat embeddings + numeric features\n\n        # MLP on top of concatenated representation\n        layers = []\n        for h in hidden_sizes:\n            layers += [nn.Linear(in_dim, h), nn.BatchNorm1d(h),\n                       nn.ReLU(), nn.Dropout(dropout)]\n            in_dim = h\n        layers.append(nn.Linear(in_dim, n_out))\n        self.mlp = nn.Sequential(*layers)\n\n    def forward(self, x_cat: torch.Tensor, x_cont: torch.Tensor) -\u003e torch.Tensor:\n        cat_embs = [emb(x_cat[:, i]) for i, emb in enumerate(self.embeddings)]\n        x = torch.cat(cat_embs + [x_cont], dim=1)\n        return self.mlp(x)\n\n# Heuristic: embedding dim = min(50, ceil(vocab_size^0.25 * 6))\ndef get_emb_dim(vocab_size: int) -\u003e int:\n    return min(50, int(np.ceil(vocab_size ** 0.25 * 6)))"},{"type":"heading","level":2,"content":"Visualizing Learned Embeddings"},{"type":"text","content":"After training, t-SNE or UMAP projection of entity embeddings reveals the learned similarity structure. Similar categories cluster together in 2D — a visual sanity check that the embeddings are capturing meaningful relationships."},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\nfrom sklearn.manifold import TSNE\nimport torch\n\ndef visualize_embeddings(embedding_layer, category_labels, title=\u0027Entity Embeddings\u0027):\n    \"\"\"Project entity embeddings to 2D via t-SNE and plot.\"\"\"\n    weights = embedding_layer.weight.detach().cpu().numpy()  # (vocab_size, emb_dim)\n\n    if weights.shape[1] \u003e 2:\n        tsne = TSNE(n_components=2, random_state=42, perplexity=min(30, len(weights)//3))\n        coords = tsne.fit_transform(weights)\n    else:\n        coords = weights  # already 2D\n\n    fig, ax = plt.subplots(figsize=(10, 8))\n    ax.scatter(coords[:, 0], coords[:, 1], alpha=0.6, s=30)\n\n    for i, label in enumerate(category_labels[:30]):  # label top 30\n        ax.annotate(label, (coords[i, 0], coords[i, 1]),\n                    fontsize=8, alpha=0.8)\n\n    ax.set_title(title)\n    ax.set_xlabel(\u0027t-SNE dim 1\u0027)\n    ax.set_ylabel(\u0027t-SNE dim 2\u0027)\n    plt.tight_layout()\n    plt.savefig(\u0027embeddings_tsne.png\u0027, dpi=150)\n    return coords"},{"type":"heading","level":2,"content":"Hybrid: Embeddings as Features for XGBoost"},{"type":"text","content":"A powerful pattern (used by the Rossman Kaggle winner): train an entity embedding network first, extract embeddings, then feed them as dense features to XGBoost. This gives tree models the benefit of learned categorical representations without end-to-end neural training."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\nfrom torch.utils.data import DataLoader, TensorDataset\nfrom sklearn.preprocessing import LabelEncoder\nimport xgboost as xgb\n\n# Step 1: Encode categoricals as integers\ncity_le = LabelEncoder()\ncity_ids = city_le.fit_transform([\u0027Paris\u0027, \u0027London\u0027, \u0027Paris\u0027, \u0027Berlin\u0027, \u0027London\u0027])\n\n# Step 2: Train embedding network\nembedding = nn.Embedding(num_embeddings=len(city_le.classes_), embedding_dim=8)\noptimizer = torch.optim.Adam(embedding.parameters(), lr=1e-3)\n\n# (Normally: train within a larger model with backprop from task loss)\n# Here we simulate by using random targets as a stand-in\ncity_tensor = torch.LongTensor(city_ids)\nfor _ in range(100):\n    emb_out = embedding(city_tensor).mean(dim=0)  # aggregate\n    loss = -emb_out.sum()  # dummy loss for illustration\n    optimizer.zero_grad()\n    loss.backward()\n    optimizer.step()\n\n# Step 3: Extract learned embeddings\nwith torch.no_grad():\n    city_embs = embedding.weight.numpy()  # (n_cities, 8)\n\nprint(f\u0027Embedding matrix shape: {city_embs.shape}\u0027)\nprint(\u0027Now use city_embs[city_id] as dense features for XGBoost\u0027)"},{"type":"heading","level":2,"content":"Comparing Encoding Methods on High-Cardinality Features"},{"type":"text","content":"On a high-cardinality column (1000 unique categories), one-hot encoding creates a 1000-column sparse matrix that overwhelms any model with noise. Target encoding leaks if not done within cross-validation folds. Entity embeddings outperform both when trained end-to-end."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.preprocessing import OneHotEncoder\nfrom sklearn.linear_model import LogisticRegression\nfrom sklearn.pipeline import Pipeline\nfrom sklearn.model_selection import cross_val_score\nimport torch\nimport torch.nn as nn\n\nrng = np.random.default_rng(42)\nn, n_cats = 2000, 200  # high-cardinality: 200 unique categories\n\n# Simulate: category correlates with target\ncat_ids = rng.integers(0, n_cats, n)             # integer category column\ncat_effect = rng.normal(0, 1, n_cats)            # per-category effect\ny = (cat_effect[cat_ids] + rng.normal(0, 0.5, n) \u003e 0).astype(int)\n\nX_cat = cat_ids.reshape(-1, 1)  # (n, 1) integer column\n\n# Method 1: One-hot encoding\none_hot = OneHotEncoder(sparse_output=False, handle_unknown=\u0027ignore\u0027)\npipe_ohe = Pipeline([(\u0027enc\u0027, one_hot),\n                      (\u0027clf\u0027, LogisticRegression(max_iter=500, C=0.1))])\nscores_ohe = cross_val_score(pipe_ohe, X_cat, y, cv=5).mean()\nprint(f\u0027One-hot (200 cats): {scores_ohe:.4f}\u0027)\n\n# Method 2: Ordinal encoding (treats categories as numbers — wrong!)\nX_ord = cat_ids.reshape(-1, 1).astype(float)\npipe_ord = Pipeline([(\u0027clf\u0027, LogisticRegression(max_iter=300))])\nscores_ord = cross_val_score(pipe_ord, X_ord, y, cv=5).mean()\nprint(f\u0027Ordinal (wrong):    {scores_ord:.4f}\u0027)\nprint(\u0027Entity embeddings trained end-to-end typically outperform both\u0027)"},{"type":"divider"},{"type":"heading","level":2,"content":"Categorical Encoding Methods Comparison"},{"type":"table","headers":["Encoding","Max Cardinality","Similarity","Leakage Risk","Best Use Case"],"rows":[["One-hot","Low-medium (\u003c50)","None","None","Low-cardinality nominals, tree models"],["Ordinal","Any","None (arbitrary)","None","Ordered categories only"],["Target encoding","Any","Via target correlation","High (needs CV)","High-cardinality with strong target signal"],["Entity embedding","High (1k–1M)","Learned, task-relevant","None","High-cardinality in neural models"],["CatBoost native","Very high","Ordered target stats","Low (ordered encoding)","CatBoost-based pipelines"]]},{"type":"callout","variant":"tip","title":"Embedding Dimension Heuristic","content":"A reliable rule of thumb: emb_dim = min(50, ceil(vocab_size^0.25 * 6)). This gives 6 for vocab=10, 15 for vocab=100, 37 for vocab=1000, 50 for vocab \u003e= 5000. Never use a dimension larger than the vocabulary size — that is wasteful and adds no expressive power."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"list","ordered":false,"items":["Entity embeddings replace sparse one-hot vectors with dense learned representations for categorical features","Similar categories cluster together in embedding space — capturing geographic, semantic, or behavioral similarity","Recommended dim: min(50, ceil(vocab^0.25 × 6)) balances expressivity and parameter efficiency","Embeddings trained end-to-end are task-specific; they can also be pre-transferred to tree models as dense features","CatBoost\u0027s native categorical handling is competitive with entity embeddings for tree-based models"]}]"
---
# Entity Embeddings — Learning Representations for Categorical Variables

One-hot encoding for high-cardinality categorical columns (cities, products, users) produces extremely high-dimensional, sparse representations with no similarity structure. Entity embeddings (Guo & Berkhahn 2016, popularized by the Rossman Kaggle competition winner) learn dense vector representations that encode semantic similarity — Paris and London end up nearby in embedding space.

## The Problem with One-Hot Encoding

For a categorical column with 10,000 unique values (e.g., ZIP codes), one-hot encoding creates 10,000 binary features. The representation is (1) sparse, wasting memory and compute; (2) equally distant — ZIP code 90210 is exactly as distant from 90211 as from 10001, despite being geographically adjacent; (3) not learnable — there is no mechanism to push similar categories closer together.

- Dimensionality: |vocab| features per column — grows linearly with cardinality
- No similarity structure: all category pairs are equidistant in Hamming distance
- Sparse gradients: each training sample updates only one position of each one-hot column
- Heuristic embedding dim: k = ceil(|vocab|^0.25) or k = min(50, |vocab| // 2) are common choices
- End-to-end training: embeddings are learned jointly with the model, capturing task-relevant similarity

## Entity Embedding Layer in PyTorch

An entity embedding is simply an nn.Embedding lookup table. Given an integer category index, it returns the corresponding dense vector. All embedding vectors are trained jointly with the rest of the neural network via backpropagation.

```python
import torch
import torch.nn as nn
import numpy as np

class TabularModel(nn.Module):
    """Mixed model: entity embeddings for categoricals + MLP for numerics."""
    def __init__(self, cat_dims: list, emb_dims: list, n_cont: int,
                 hidden_sizes: list, n_out: int, dropout: float = 0.3):
        super().__init__()
        # Entity embedding tables: one per categorical column
        self.embeddings = nn.ModuleList([
            nn.Embedding(n_cats, emb_dim)
            for n_cats, emb_dim in zip(cat_dims, emb_dims)
        ])
        emb_total = sum(emb_dims)
        in_dim = emb_total + n_cont  # concat embeddings + numeric features

        # MLP on top of concatenated representation
        layers = []
        for h in hidden_sizes:
            layers += [nn.Linear(in_dim, h), nn.BatchNorm1d(h),
                       nn.ReLU(), nn.Dropout(dropout)]
            in_dim = h
        layers.append(nn.Linear(in_dim, n_out))
        self.mlp = nn.Sequential(*layers)

    def forward(self, x_cat: torch.Tensor, x_cont: torch.Tensor) -> torch.Tensor:
        cat_embs = [emb(x_cat[:, i]) for i, emb in enumerate(self.embeddings)]
        x = torch.cat(cat_embs + [x_cont], dim=1)
        return self.mlp(x)

# Heuristic: embedding dim = min(50, ceil(vocab_size^0.25 * 6))
def get_emb_dim(vocab_size: int) -> int:
    return min(50, int(np.ceil(vocab_size ** 0.25 * 6)))
```

## Visualizing Learned Embeddings

After training, t-SNE or UMAP projection of entity embeddings reveals the learned similarity structure. Similar categories cluster together in 2D — a visual sanity check that the embeddings are capturing meaningful relationships.

```python
import numpy as np
import matplotlib.pyplot as plt
from sklearn.manifold import TSNE
import torch

def visualize_embeddings(embedding_layer, category_labels, title='Entity Embeddings'):
    """Project entity embeddings to 2D via t-SNE and plot."""
    weights = embedding_layer.weight.detach().cpu().numpy()  # (vocab_size, emb_dim)

    if weights.shape[1] > 2:
        tsne = TSNE(n_components=2, random_state=42, perplexity=min(30, len(weights)//3))
        coords = tsne.fit_transform(weights)
    else:
        coords = weights  # already 2D

    fig, ax = plt.subplots(figsize=(10, 8))
    ax.scatter(coords[:, 0], coords[:, 1], alpha=0.6, s=30)

    for i, label in enumerate(category_labels[:30]):  # label top 30
        ax.annotate(label, (coords[i, 0], coords[i, 1]),
                    fontsize=8, alpha=0.8)

    ax.set_title(title)
    ax.set_xlabel('t-SNE dim 1')
    ax.set_ylabel('t-SNE dim 2')
    plt.tight_layout()
    plt.savefig('embeddings_tsne.png', dpi=150)
    return coords
```

## Hybrid: Embeddings as Features for XGBoost

A powerful pattern (used by the Rossman Kaggle winner): train an entity embedding network first, extract embeddings, then feed them as dense features to XGBoost. This gives tree models the benefit of learned categorical representations without end-to-end neural training.

```python
import numpy as np
import torch
import torch.nn as nn
from torch.utils.data import DataLoader, TensorDataset
from sklearn.preprocessing import LabelEncoder
import xgboost as xgb

# Step 1: Encode categoricals as integers
city_le = LabelEncoder()
city_ids = city_le.fit_transform(['Paris', 'London', 'Paris', 'Berlin', 'London'])

# Step 2: Train embedding network
embedding = nn.Embedding(num_embeddings=len(city_le.classes_), embedding_dim=8)
optimizer = torch.optim.Adam(embedding.parameters(), lr=1e-3)

# (Normally: train within a larger model with backprop from task loss)
# Here we simulate by using random targets as a stand-in
city_tensor = torch.LongTensor(city_ids)
for _ in range(100):
    emb_out = embedding(city_tensor).mean(dim=0)  # aggregate
    loss = -emb_out.sum()  # dummy loss for illustration
    optimizer.zero_grad()
    loss.backward()
    optimizer.step()

# Step 3: Extract learned embeddings
with torch.no_grad():
    city_embs = embedding.weight.numpy()  # (n_cities, 8)

print(f'Embedding matrix shape: {city_embs.shape}')
print('Now use city_embs[city_id] as dense features for XGBoost')
```

## Comparing Encoding Methods on High-Cardinality Features

On a high-cardinality column (1000 unique categories), one-hot encoding creates a 1000-column sparse matrix that overwhelms any model with noise. Target encoding leaks if not done within cross-validation folds. Entity embeddings outperform both when trained end-to-end.

```python
import numpy as np
from sklearn.preprocessing import OneHotEncoder
from sklearn.linear_model import LogisticRegression
from sklearn.pipeline import Pipeline
from sklearn.model_selection import cross_val_score
import torch
import torch.nn as nn

rng = np.random.default_rng(42)
n, n_cats = 2000, 200  # high-cardinality: 200 unique categories

# Simulate: category correlates with target
cat_ids = rng.integers(0, n_cats, n)             # integer category column
cat_effect = rng.normal(0, 1, n_cats)            # per-category effect
y = (cat_effect[cat_ids] + rng.normal(0, 0.5, n) > 0).astype(int)

X_cat = cat_ids.reshape(-1, 1)  # (n, 1) integer column

# Method 1: One-hot encoding
one_hot = OneHotEncoder(sparse_output=False, handle_unknown='ignore')
pipe_ohe = Pipeline([('enc', one_hot),
                      ('clf', LogisticRegression(max_iter=500, C=0.1))])
scores_ohe = cross_val_score(pipe_ohe, X_cat, y, cv=5).mean()
print(f'One-hot (200 cats): {scores_ohe:.4f}')

# Method 2: Ordinal encoding (treats categories as numbers — wrong!)
X_ord = cat_ids.reshape(-1, 1).astype(float)
pipe_ord = Pipeline([('clf', LogisticRegression(max_iter=300))])
scores_ord = cross_val_score(pipe_ord, X_ord, y, cv=5).mean()
print(f'Ordinal (wrong):    {scores_ord:.4f}')
print('Entity embeddings trained end-to-end typically outperform both')
```

---

## Categorical Encoding Methods Comparison

| Encoding | Max Cardinality | Similarity | Leakage Risk | Best Use Case |
| --- | --- | --- | --- | --- |
| One-hot | Low-medium (<50) | None | None | Low-cardinality nominals, tree models |
| Ordinal | Any | None (arbitrary) | None | Ordered categories only |
| Target encoding | Any | Via target correlation | High (needs CV) | High-cardinality with strong target signal |
| Entity embedding | High (1k–1M) | Learned, task-relevant | None | High-cardinality in neural models |
| CatBoost native | Very high | Ordered target stats | Low (ordered encoding) | CatBoost-based pipelines |

> **Embedding Dimension Heuristic**: A reliable rule of thumb: emb_dim = min(50, ceil(vocab_size^0.25 * 6)). This gives 6 for vocab=10, 15 for vocab=100, 37 for vocab=1000, 50 for vocab >= 5000. Never use a dimension larger than the vocabulary size — that is wasteful and adds no expressive power.

## Key Takeaways

- Entity embeddings replace sparse one-hot vectors with dense learned representations for categorical features
- Similar categories cluster together in embedding space — capturing geographic, semantic, or behavioral similarity
- Recommended dim: min(50, ceil(vocab^0.25 × 6)) balances expressivity and parameter efficiency
- Embeddings trained end-to-end are task-specific; they can also be pre-transferred to tree models as dense features
- CatBoost's native categorical handling is competitive with entity embeddings for tree-based models

