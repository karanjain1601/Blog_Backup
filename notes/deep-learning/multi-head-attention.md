---
title: "Multi-Head Attention — Parallel Heads and Projection"
slug: "multi-head-attention"
description: "Unpack the MHA formula head by head: projection matrices, parallel scaled dot-product attention, concatenation, output projection, parameter count, and the efficient reshape trick."
tags: ["deep-learning", "transformers", "attention"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Multi-Head Attention (MHA) runs h independent scaled dot-product attention operations in parallel, each on a lower-dimensional projection of the input. The outputs are concatenated and projected back to the model dimension. This allows the model to jointly attend to information from h different representation subspaces — a richer and more expressive operation than a single large attention head operating on the full dimension."},{"type":"heading","level":2,"content":"MHA Formula and Structure"},{"type":"text","content":"For head i, the query, key, and value projections are Qᵢ = QWᵢQ, Kᵢ = KWᵢK, Vᵢ = VWᵢV where WᵢQ, WᵢK ∈ ℝ^{d_model×dₖ} and WᵢV ∈ ℝ^{d_model×dv}. Each head computes headᵢ = Attention(Qᵢ, Kᵢ, Vᵢ) ∈ ℝ^{nq×dv}. The h head outputs are concatenated along the last axis to get ℝ^{nq×(h·dv)}, then projected by Wᴼ ∈ ℝ^{(h·dv)×d_model}. With the standard choice h=8, dₖ=dv=d_model/h=64, the total parameter count in the four projection matrices is 4·d_model²."},{"type":"math","content":"\\text{MultiHead}(Q,K,V) = \\text{Concat}(\\text{head}_1,\\ldots,\\text{head}_h)W^O, \\quad \\text{head}_i = \\text{Attention}(QW_i^Q,\\, KW_i^K,\\, VW_i^V)","display":true},{"type":"heading","level":2,"content":"Projection Matrices — Why They Matter"},{"type":"text","content":"Without projection matrices, MHA would simply split Q, K, V along the feature axis and run attention on each chunk. The projections allow each head to learn its own transformation of the input before computing similarities — head i can learn to extract syntactic features, head j semantic features, without interference. The output projection Wᴼ mixes the h head outputs and maps back to d_model so the residual addition x + MHA(x) remains shape-preserving. Initialising projections with small random values (scale ~ 1/√d_model) is crucial for stable training."},{"type":"code","language":"python","content":"import numpy as np\n\ndef sdp(Q, K, V):\n    dk = Q.shape[-1]\n    S = Q @ K.T / np.sqrt(dk)\n    S -= S.max(axis=-1, keepdims=True)\n    A = np.exp(S); A /= A.sum(axis=-1, keepdims=True)\n    return A @ V\n\nclass MultiHeadAttention:\n    def __init__(self, d_model, h, seed=0):\n        self.h = h\n        self.dk = self.dv = d_model // h\n        rng = np.random.RandomState(seed)\n        scale = np.sqrt(2.0 / d_model)\n        self.WQ = rng.randn(h, d_model, self.dk) * scale\n        self.WK = rng.randn(h, d_model, self.dk) * scale\n        self.WV = rng.randn(h, d_model, self.dv) * scale\n        self.WO = rng.randn(h * self.dv, d_model) * scale\n\n    def forward(self, Q, K, V):\n        heads = []\n        for i in range(self.h):\n            Qi = Q @ self.WQ[i]   # (nq, dk)\n            Ki = K @ self.WK[i]   # (nk, dk)\n            Vi = V @ self.WV[i]   # (nk, dv)\n            heads.append(sdp(Qi, Ki, Vi))    # (nq, dv)\n        concat = np.concatenate(heads, axis=-1)  # (nq, h*dv)\n        return concat @ self.WO                  # (nq, d_model)\n\nnp.random.seed(42)\nd_model, h, n = 512, 8, 10\nmha = MultiHeadAttention(d_model, h)\nx = np.random.randn(n, d_model)\nout = mha.forward(x, x, x)\nprint(\u0027Input: \u0027, x.shape, \u0027-\u003e Output:\u0027, out.shape)\nparams = h * (d_model * (d_model//h) * 3) + (h * (d_model//h)) * d_model\nprint(\u0027Total params: {:,} == 4*d_model^2: {:,}\u0027.format(params, 4 * d_model**2))"},{"type":"heading","level":2,"content":"PyTorch nn.MultiheadAttention"},{"type":"text","content":"PyTorch fuses the three input projection matrices WQ, WK, WV into a single in_proj_weight of shape (3·d_model, d_model) for efficiency — a single GEMM replaces three. The batch_first=True flag selects the (batch, seq, d_model) convention; the default is (seq, batch, d_model). For cross-attention, pass the decoder states as query and the encoder output as key and value. The returned attn_weights tensor averages attention weights across heads by default; pass average_attn_weights=False to get per-head weights (PyTorch ≥ 1.13)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ntorch.manual_seed(42)\nd_model, h, seq_len, batch = 512, 8, 10, 2\n\nmha = nn.MultiheadAttention(\n    embed_dim=d_model,\n    num_heads=h,\n    batch_first=True,\n    dropout=0.0\n)\n\n# Self-attention: Q = K = V = x\nx = torch.randn(batch, seq_len, d_model)\nout, attn_w = mha(x, x, x)\nprint(\u0027Input:\u0027, tuple(x.shape))\nprint(\u0027Output:\u0027, tuple(out.shape))\nprint(\u0027Attn weights (avg across heads):\u0027, tuple(attn_w.shape))\nprint(\u0027Row sums:\u0027, attn_w[0].sum(dim=-1).round(decimals=4))\n\n# Cross-attention: decoder queries attend to encoder key-value\ndec_len, enc_len = 6, 15\nq   = torch.randn(batch, dec_len, d_model)\nkv  = torch.randn(batch, enc_len, d_model)\nout_cross, cross_w = mha(q, kv, kv)\nprint(\u0027Cross-attn output:\u0027, tuple(out_cross.shape))\nprint(\u0027Cross-attn weights:\u0027, tuple(cross_w.shape), \u0027(dec_len x enc_len)\u0027)\n\ntotal_params = sum(p.numel() for p in mha.parameters())\nprint(\u0027Total MHA params: {:,}  =?= 4*d^2: {:,}\u0027.format(total_params, 4*d_model**2))"},{"type":"heading","level":2,"content":"Efficient Batched Head Computation"},{"type":"text","content":"The Python loop over h heads (one attention call per head) is correct but slow. The standard trick is to reshape the projected Q, K, V tensors from (batch, seq, d_model) to (batch, h, seq, dₖ) and execute a single batched matrix multiply across all heads simultaneously. This keeps GPU utilisation high and avoids h separate kernel launches. The reshape is O(1) — it reinterprets the memory layout without copying. After the batched attention, the head outputs are transposed back and reshaped to (batch, seq, h·dv) before the output projection."},{"type":"code","language":"python","content":"import numpy as np\n\ndef mha_batched(Q, K, V, WQ, WK, WV, WO, h):\n    # Q, K, V: (n, d_model); returns (n, d_model)\n    n, d = Q.shape\n    dk = d // h\n    # Project and split into heads: (n, d) -\u003e (n, h, dk) -\u003e (h, n, dk)\n    Qh = (Q @ WQ).reshape(n, h, dk).transpose(1, 0, 2)  # (h, n, dk)\n    Kh = (K @ WK).reshape(n, h, dk).transpose(1, 0, 2)\n    Vh = (V @ WV).reshape(n, h, dk).transpose(1, 0, 2)\n    # Batched scaled dot-product: (h, n, dk) x (h, dk, n) -\u003e (h, n, n)\n    S = Qh @ Kh.transpose(0, 2, 1) / np.sqrt(dk)\n    S -= S.max(axis=-1, keepdims=True)\n    A = np.exp(S); A /= A.sum(axis=-1, keepdims=True)  # (h, n, n)\n    # Value aggregation: (h, n, n) x (h, n, dk) -\u003e (h, n, dk)\n    O = A @ Vh                        # (h, n, dk)\n    O = O.transpose(1, 0, 2)          # (n, h, dk)\n    O = O.reshape(n, h * dk)          # (n, h*dk = d_model)\n    return O @ WO                     # (n, d_model)\n\nnp.random.seed(5)\nd_model, h, n = 256, 8, 12\nWQ = np.random.randn(d_model, d_model) * 0.02\nWK = np.random.randn(d_model, d_model) * 0.02\nWV = np.random.randn(d_model, d_model) * 0.02\nWO = np.random.randn(d_model, d_model) * 0.02\nx = np.random.randn(n, d_model)\nout = mha_batched(x, x, x, WQ, WK, WV, WO, h)\nprint(\u0027Input:\u0027, x.shape, \u0027-\u003e Output:\u0027, out.shape)\nprint(\u0027No Python head loop — single batched matmul across all\u0027, h, \u0027heads.\u0027)"},{"type":"callout","variant":"info","title":"Why the Reshape Trick Works","content":"After projecting Q to shape (n, d_model), reshaping to (n, h, dₖ) and transposing to (h, n, dₖ) rearranges memory such that each slice [i, :, :] along the first axis corresponds exactly to head i\u0027s projected queries. NumPy and PyTorch\u0027s batched matmul then processes all h slices in one GPU kernel call, replacing h separate attention kernels with a single one — the same FLOP count but far better hardware utilisation."},{"type":"heading","level":2,"content":"Head Specialisation Visualisation"},{"type":"text","content":"Different attention heads tend to learn qualitatively different patterns. A head with high diagonal mean attends strongly to the query token itself (self-focus). A head with low entropy attends to a small fixed set of positions (selective retrieval). A head with near-uniform weights aggregates contextual information broadly. Quantifying these per-head statistics — diagonal concentration, entropy, and off-diagonal distribution — is a lightweight diagnostic for understanding what a trained Transformer has learned."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ntorch.manual_seed(0)\nd_model, h, seq_len = 256, 8, 12\nmha = nn.MultiheadAttention(d_model, h, batch_first=True)\nWQ, WK, WV = mha.in_proj_weight.chunk(3, dim=0)\ndk = d_model // h\n\ndef head_attention_weights(x_flat, head_idx):\n    # x_flat: (seq, d_model) — single sample\n    with torch.no_grad():\n        Q = (x_flat @ WQ.T)[:, head_idx*dk:(head_idx+1)*dk]\n        K = (x_flat @ WK.T)[:, head_idx*dk:(head_idx+1)*dk]\n        S = (Q @ K.T / dk**0.5).numpy()\n    S -= S.max(1, keepdims=True)\n    A = np.exp(S); A /= A.sum(1, keepdims=True)\n    return A\n\nx = torch.randn(1, seq_len, d_model)\nx_flat = x.squeeze(0)\nprint(\u0027{:\u003e6} {:\u003e10} {:\u003e13} {:\u003e10}\u0027.format(\u0027Head\u0027, \u0027DiagMean\u0027, \u0027OffDiagMean\u0027, \u0027Entropy\u0027))\nfor i in range(h):\n    A = head_attention_weights(x_flat, i)\n    diag = np.diag(A).mean()\n    off  = (A.sum() - np.trace(A)) / (seq_len * (seq_len - 1))\n    ent  = -(A * np.log(A + 1e-9)).sum(1).mean()\n    print(\u0027{:\u003e6} {:\u003e10.4f} {:\u003e13.4f} {:\u003e10.4f}\u0027.format(i, diag, off, ent))\nprint(\u0027High DiagMean = self-focused head. Low entropy = selective head.\u0027)"},{"type":"heading","level":2,"content":"Parameter Count and Hyperparameter Design"},{"type":"text","content":"With d_model and h heads, each head has WᵢQ, WᵢK ∈ ℝ^{d_model×dₖ} and WᵢV ∈ ℝ^{d_model×dv}. Summing over h heads and adding Wᴼ: total = h·d_model·dₖ + h·d_model·dₖ + h·d_model·dv + (h·dv)·d_model = 4·d_model² when dₖ=dv=d_model/h. This means the parameter count is independent of the number of heads — an 8-head and 16-head MHA with the same d_model have the same parameter budget. Increasing h redistributes parameters into more, narrower projection matrices rather than adding parameters."},{"type":"table","headers":["Hyperparameter","GPT-2 Small","BERT-Base (original)","GPT-3 175B (per layer)","Role"],"rows":[["d_model","768","512","12288","Residual stream dimension"],["h (heads)","12","8","96","Number of attention heads"],["dₖ = dv = d_model/h","64","64","128","Per-head key/value dimension"],["Total MHA params","≈2.4M","≈1.0M","≈603M","Always 4 × d_model²"],["Max sequence length","1024","512","2048","Determines O(n²d) cost"]]},{"type":"list","ordered":false,"items":["h must evenly divide d_model so each head gets dimension d_model/h","Larger h with same d_model: more heads with narrower projections — more diverse patterns but less capacity per head","Empirical sweet spot: dₖ ≥ 32 per head; below this heads are too narrow to be expressive","Weight tying: some architectures (T5) share WQ and WK across heads or layers to save parameters","Grouped Query Attention (GQA, Ainslie et al. 2023): h query heads share g \u003c h key-value head pairs to reduce KV cache size at inference time"]},{"type":"divider"}]"
---
# Multi-Head Attention — Parallel Heads and Projection

Multi-Head Attention (MHA) runs h independent scaled dot-product attention operations in parallel, each on a lower-dimensional projection of the input. The outputs are concatenated and projected back to the model dimension. This allows the model to jointly attend to information from h different representation subspaces — a richer and more expressive operation than a single large attention head operating on the full dimension.

## MHA Formula and Structure

For head i, the query, key, and value projections are Qᵢ = QWᵢQ, Kᵢ = KWᵢK, Vᵢ = VWᵢV where WᵢQ, WᵢK ∈ ℝ^{d_model×dₖ} and WᵢV ∈ ℝ^{d_model×dv}. Each head computes headᵢ = Attention(Qᵢ, Kᵢ, Vᵢ) ∈ ℝ^{nq×dv}. The h head outputs are concatenated along the last axis to get ℝ^{nq×(h·dv)}, then projected by Wᴼ ∈ ℝ^{(h·dv)×d_model}. With the standard choice h=8, dₖ=dv=d_model/h=64, the total parameter count in the four projection matrices is 4·d_model².

$$\text{MultiHead}(Q,K,V) = \text{Concat}(\text{head}_1,\ldots,\text{head}_h)W^O, \quad \text{head}_i = \text{Attention}(QW_i^Q,\, KW_i^K,\, VW_i^V)$$

## Projection Matrices — Why They Matter

Without projection matrices, MHA would simply split Q, K, V along the feature axis and run attention on each chunk. The projections allow each head to learn its own transformation of the input before computing similarities — head i can learn to extract syntactic features, head j semantic features, without interference. The output projection Wᴼ mixes the h head outputs and maps back to d_model so the residual addition x + MHA(x) remains shape-preserving. Initialising projections with small random values (scale ~ 1/√d_model) is crucial for stable training.

```python
import numpy as np

def sdp(Q, K, V):
    dk = Q.shape[-1]
    S = Q @ K.T / np.sqrt(dk)
    S -= S.max(axis=-1, keepdims=True)
    A = np.exp(S); A /= A.sum(axis=-1, keepdims=True)
    return A @ V

class MultiHeadAttention:
    def __init__(self, d_model, h, seed=0):
        self.h = h
        self.dk = self.dv = d_model // h
        rng = np.random.RandomState(seed)
        scale = np.sqrt(2.0 / d_model)
        self.WQ = rng.randn(h, d_model, self.dk) * scale
        self.WK = rng.randn(h, d_model, self.dk) * scale
        self.WV = rng.randn(h, d_model, self.dv) * scale
        self.WO = rng.randn(h * self.dv, d_model) * scale

    def forward(self, Q, K, V):
        heads = []
        for i in range(self.h):
            Qi = Q @ self.WQ[i]   # (nq, dk)
            Ki = K @ self.WK[i]   # (nk, dk)
            Vi = V @ self.WV[i]   # (nk, dv)
            heads.append(sdp(Qi, Ki, Vi))    # (nq, dv)
        concat = np.concatenate(heads, axis=-1)  # (nq, h*dv)
        return concat @ self.WO                  # (nq, d_model)

np.random.seed(42)
d_model, h, n = 512, 8, 10
mha = MultiHeadAttention(d_model, h)
x = np.random.randn(n, d_model)
out = mha.forward(x, x, x)
print('Input: ', x.shape, '-> Output:', out.shape)
params = h * (d_model * (d_model//h) * 3) + (h * (d_model//h)) * d_model
print('Total params: {:,} == 4*d_model^2: {:,}'.format(params, 4 * d_model**2))
```

## PyTorch nn.MultiheadAttention

PyTorch fuses the three input projection matrices WQ, WK, WV into a single in_proj_weight of shape (3·d_model, d_model) for efficiency — a single GEMM replaces three. The batch_first=True flag selects the (batch, seq, d_model) convention; the default is (seq, batch, d_model). For cross-attention, pass the decoder states as query and the encoder output as key and value. The returned attn_weights tensor averages attention weights across heads by default; pass average_attn_weights=False to get per-head weights (PyTorch ≥ 1.13).

```python
import torch
import torch.nn as nn

torch.manual_seed(42)
d_model, h, seq_len, batch = 512, 8, 10, 2

mha = nn.MultiheadAttention(
    embed_dim=d_model,
    num_heads=h,
    batch_first=True,
    dropout=0.0
)

# Self-attention: Q = K = V = x
x = torch.randn(batch, seq_len, d_model)
out, attn_w = mha(x, x, x)
print('Input:', tuple(x.shape))
print('Output:', tuple(out.shape))
print('Attn weights (avg across heads):', tuple(attn_w.shape))
print('Row sums:', attn_w[0].sum(dim=-1).round(decimals=4))

# Cross-attention: decoder queries attend to encoder key-value
dec_len, enc_len = 6, 15
q   = torch.randn(batch, dec_len, d_model)
kv  = torch.randn(batch, enc_len, d_model)
out_cross, cross_w = mha(q, kv, kv)
print('Cross-attn output:', tuple(out_cross.shape))
print('Cross-attn weights:', tuple(cross_w.shape), '(dec_len x enc_len)')

total_params = sum(p.numel() for p in mha.parameters())
print('Total MHA params: {:,}  =?= 4*d^2: {:,}'.format(total_params, 4*d_model**2))
```

## Efficient Batched Head Computation

The Python loop over h heads (one attention call per head) is correct but slow. The standard trick is to reshape the projected Q, K, V tensors from (batch, seq, d_model) to (batch, h, seq, dₖ) and execute a single batched matrix multiply across all heads simultaneously. This keeps GPU utilisation high and avoids h separate kernel launches. The reshape is O(1) — it reinterprets the memory layout without copying. After the batched attention, the head outputs are transposed back and reshaped to (batch, seq, h·dv) before the output projection.

```python
import numpy as np

def mha_batched(Q, K, V, WQ, WK, WV, WO, h):
    # Q, K, V: (n, d_model); returns (n, d_model)
    n, d = Q.shape
    dk = d // h
    # Project and split into heads: (n, d) -> (n, h, dk) -> (h, n, dk)
    Qh = (Q @ WQ).reshape(n, h, dk).transpose(1, 0, 2)  # (h, n, dk)
    Kh = (K @ WK).reshape(n, h, dk).transpose(1, 0, 2)
    Vh = (V @ WV).reshape(n, h, dk).transpose(1, 0, 2)
    # Batched scaled dot-product: (h, n, dk) x (h, dk, n) -> (h, n, n)
    S = Qh @ Kh.transpose(0, 2, 1) / np.sqrt(dk)
    S -= S.max(axis=-1, keepdims=True)
    A = np.exp(S); A /= A.sum(axis=-1, keepdims=True)  # (h, n, n)
    # Value aggregation: (h, n, n) x (h, n, dk) -> (h, n, dk)
    O = A @ Vh                        # (h, n, dk)
    O = O.transpose(1, 0, 2)          # (n, h, dk)
    O = O.reshape(n, h * dk)          # (n, h*dk = d_model)
    return O @ WO                     # (n, d_model)

np.random.seed(5)
d_model, h, n = 256, 8, 12
WQ = np.random.randn(d_model, d_model) * 0.02
WK = np.random.randn(d_model, d_model) * 0.02
WV = np.random.randn(d_model, d_model) * 0.02
WO = np.random.randn(d_model, d_model) * 0.02
x = np.random.randn(n, d_model)
out = mha_batched(x, x, x, WQ, WK, WV, WO, h)
print('Input:', x.shape, '-> Output:', out.shape)
print('No Python head loop — single batched matmul across all', h, 'heads.')
```

> **Why the Reshape Trick Works**: After projecting Q to shape (n, d_model), reshaping to (n, h, dₖ) and transposing to (h, n, dₖ) rearranges memory such that each slice [i, :, :] along the first axis corresponds exactly to head i's projected queries. NumPy and PyTorch's batched matmul then processes all h slices in one GPU kernel call, replacing h separate attention kernels with a single one — the same FLOP count but far better hardware utilisation.

## Head Specialisation Visualisation

Different attention heads tend to learn qualitatively different patterns. A head with high diagonal mean attends strongly to the query token itself (self-focus). A head with low entropy attends to a small fixed set of positions (selective retrieval). A head with near-uniform weights aggregates contextual information broadly. Quantifying these per-head statistics — diagonal concentration, entropy, and off-diagonal distribution — is a lightweight diagnostic for understanding what a trained Transformer has learned.

```python
import torch
import torch.nn as nn
import numpy as np

torch.manual_seed(0)
d_model, h, seq_len = 256, 8, 12
mha = nn.MultiheadAttention(d_model, h, batch_first=True)
WQ, WK, WV = mha.in_proj_weight.chunk(3, dim=0)
dk = d_model // h

def head_attention_weights(x_flat, head_idx):
    # x_flat: (seq, d_model) — single sample
    with torch.no_grad():
        Q = (x_flat @ WQ.T)[:, head_idx*dk:(head_idx+1)*dk]
        K = (x_flat @ WK.T)[:, head_idx*dk:(head_idx+1)*dk]
        S = (Q @ K.T / dk**0.5).numpy()
    S -= S.max(1, keepdims=True)
    A = np.exp(S); A /= A.sum(1, keepdims=True)
    return A

x = torch.randn(1, seq_len, d_model)
x_flat = x.squeeze(0)
print('{:>6} {:>10} {:>13} {:>10}'.format('Head', 'DiagMean', 'OffDiagMean', 'Entropy'))
for i in range(h):
    A = head_attention_weights(x_flat, i)
    diag = np.diag(A).mean()
    off  = (A.sum() - np.trace(A)) / (seq_len * (seq_len - 1))
    ent  = -(A * np.log(A + 1e-9)).sum(1).mean()
    print('{:>6} {:>10.4f} {:>13.4f} {:>10.4f}'.format(i, diag, off, ent))
print('High DiagMean = self-focused head. Low entropy = selective head.')
```

## Parameter Count and Hyperparameter Design

With d_model and h heads, each head has WᵢQ, WᵢK ∈ ℝ^{d_model×dₖ} and WᵢV ∈ ℝ^{d_model×dv}. Summing over h heads and adding Wᴼ: total = h·d_model·dₖ + h·d_model·dₖ + h·d_model·dv + (h·dv)·d_model = 4·d_model² when dₖ=dv=d_model/h. This means the parameter count is independent of the number of heads — an 8-head and 16-head MHA with the same d_model have the same parameter budget. Increasing h redistributes parameters into more, narrower projection matrices rather than adding parameters.

| Hyperparameter | GPT-2 Small | BERT-Base (original) | GPT-3 175B (per layer) | Role |
| --- | --- | --- | --- | --- |
| d_model | 768 | 512 | 12288 | Residual stream dimension |
| h (heads) | 12 | 8 | 96 | Number of attention heads |
| dₖ = dv = d_model/h | 64 | 64 | 128 | Per-head key/value dimension |
| Total MHA params | ≈2.4M | ≈1.0M | ≈603M | Always 4 × d_model² |
| Max sequence length | 1024 | 512 | 2048 | Determines O(n²d) cost |

- h must evenly divide d_model so each head gets dimension d_model/h
- Larger h with same d_model: more heads with narrower projections — more diverse patterns but less capacity per head
- Empirical sweet spot: dₖ ≥ 32 per head; below this heads are too narrow to be expressive
- Weight tying: some architectures (T5) share WQ and WK across heads or layers to save parameters
- Grouped Query Attention (GQA, Ainslie et al. 2023): h query heads share g < h key-value head pairs to reduce KV cache size at inference time

---

