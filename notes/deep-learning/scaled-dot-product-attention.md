---
title: "Scaled Dot-Product Attention — Derivation and Numerical Stability"
slug: "scaled-dot-product-attention"
description: "Derive Attention(Q,K,V)=softmax(QKᵀ/√dₖ)V from first principles, prove why √dₖ scaling prevents softmax saturation, and explore O(n²d) complexity and FlashAttention tiling."
tags: ["deep-learning", "transformers", "attention"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Scaled dot-product attention is the computational core of every Transformer. Given queries Q, keys K, and values V it computes a weighted sum of value vectors where the weights are determined by query-key similarity: Attention(Q,K,V) = softmax(QKᵀ/√dₖ)V. Three design choices — dot-product scoring, √dₖ scaling, and softmax normalisation — each have precise mathematical motivations that are easy to miss when reading only the formula."},{"type":"heading","level":2,"content":"Mathematical Definition and Tensor Shapes"},{"type":"text","content":"Queries Q ∈ ℝ^{nq×dₖ} represent nq positions asking for information. Keys K ∈ ℝ^{nk×dₖ} represent nk positions advertising what they contain. Values V ∈ ℝ^{nk×dv} carry the actual content to be retrieved. The score matrix S = QKᵀ/√dₖ ∈ ℝ^{nq×nk} measures pairwise compatibility — entry Sᵢⱼ = qᵢ·kⱼ/√dₖ is how relevant key j is to query i. Applying row-wise softmax gives attention weights A = softmax(S) ∈ ℝ^{nq×nk} with rows summing to one. The output O = AV ∈ ℝ^{nq×dv} is a convex combination of value vectors for each query."},{"type":"math","content":"\\text{Attention}(Q,K,V) = \\text{softmax}\\!\\left(\\frac{QK^\\top}{\\sqrt{d_k}}\\right)V","display":true},{"type":"heading","level":2,"content":"The √dₖ Scaling Factor — Derivation"},{"type":"text","content":"Suppose Q and K have independent entries drawn from N(0,1). The dot product qᵢ·kⱼ = Σₗ qᵢₗkⱼₗ is a sum of dₖ independent terms each with mean 0 and variance 1, so qᵢ·kⱼ ~ N(0, dₖ). The standard deviation is √dₖ — for dₖ=64 this is 8, meaning raw scores span roughly ±24. The softmax exp(x)/Σexp pushes values in its flat saturation region when |x| is large: all probability mass collapses onto the maximum-scoring key. Dividing by √dₖ restores unit variance, keeping scores in the regime where softmax distributes mass across multiple keys and its Jacobian retains non-negligible entries."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn.functional as F\n\ndef sdp_attention_numpy(Q, K, V, mask=None):\n    # Q: (nq, dk), K: (nk, dk), V: (nk, dv)\n    # Returns: output (nq, dv), weights (nq, nk)\n    dk = Q.shape[-1]\n    scores = Q @ K.T / np.sqrt(dk)\n    if mask is not None:\n        scores = scores + mask * -1e9\n    scores = scores - scores.max(axis=-1, keepdims=True)  # numeric stability\n    weights = np.exp(scores)\n    weights = weights / weights.sum(axis=-1, keepdims=True)\n    return weights @ V, weights\n\ndef sdp_attention_torch(Q, K, V):\n    dk = Q.shape[-1]\n    scores = Q @ K.transpose(-2, -1) / dk ** 0.5\n    weights = F.softmax(scores, dim=-1)\n    return weights @ V, weights\n\nnp.random.seed(42)\nnq, nk, dk, dv = 5, 7, 64, 64\nQ = np.random.randn(nq, dk).astype(np.float32)\nK = np.random.randn(nk, dk).astype(np.float32)\nV = np.random.randn(nk, dv).astype(np.float32)\nout_np, w_np = sdp_attention_numpy(Q, K, V)\nQt = torch.tensor(Q); Kt = torch.tensor(K); Vt = torch.tensor(V)\nout_pt, w_pt = sdp_attention_torch(Qt, Kt, Vt)\nprint(\u0027Output shape:\u0027, out_np.shape)\nprint(\u0027Weights row-sum:\u0027, w_np.sum(axis=1).round(5))\nprint(\u0027Max diff NumPy vs PyTorch:\u0027, np.abs(out_np - out_pt.numpy()).max())"},{"type":"heading","level":2,"content":"Softmax Saturation and Gradient Flow"},{"type":"text","content":"The softmax Jacobian ∂σ/∂z = diag(σ) − σσᵀ has entries bounded by σᵢ(1−σᵢ). When softmax approaches a one-hot vector (due to large unscaled scores), all entries σᵢ(1−σᵢ) collapse toward zero and the Frobenius norm of the Jacobian vanishes — blocking gradient flow during backpropagation. With √dₖ scaling the score distribution remains approximately N(0,1) regardless of dₖ, keeping the Jacobian norm stable across all model sizes."},{"type":"code","language":"python","content":"import numpy as np\n\ndef softmax(x):\n    e = np.exp(x - x.max())\n    return e / e.sum()\n\ndef jacobian_frob_norm(s):\n    # Frobenius norm of softmax Jacobian: diag(s) - s*s^T\n    return np.sqrt(np.sum((np.diag(s) - np.outer(s, s)) ** 2))\n\nprint(\u0027{:\u003e5} | {:\u003e9} | {:\u003e11} | {:\u003e14} | {:\u003e12}\u0027.format(\n    \u0027dk\u0027, \u0027dot_std\u0027, \u0027scaled_std\u0027, \u0027J_unscaled\u0027, \u0027J_scaled\u0027))\nprint(\u0027-\u0027 * 60)\nnp.random.seed(0)\nfor dk in [1, 4, 16, 64, 256, 1024]:\n    q = np.random.randn(dk)\n    keys = np.random.randn(6, dk)\n    dots = keys @ q                    # ~ N(0, dk)\n    scaled = dots / np.sqrt(dk)        # ~ N(0, 1)\n    jn_u = jacobian_frob_norm(softmax(dots))\n    jn_s = jacobian_frob_norm(softmax(scaled))\n    print(\u0027{:\u003e5} | {:\u003e9.3f} | {:\u003e11.3f} | {:\u003e14.6f} | {:\u003e12.6f}\u0027.format(\n        dk, dots.std(), scaled.std(), jn_u, jn_s))\nprint(\u0027Unscaled Jacobian norm collapses as dk grows -\u003e vanishing gradients.\u0027)\nprint(\u0027Scaled norm stays near constant -\u003e stable gradient flow.\u0027)"},{"type":"callout","variant":"tip","title":"Numerical Stability in Implementation","content":"Always subtract the row maximum before computing exp: scores -= scores.max(-1, keepdims=True). This prevents overflow without changing the result since exp(x-c)/Σexp(x-c) = exp(x)/Σexp(x). PyTorch F.softmax handles this internally. For custom CUDA kernels this step is non-negotiable — a single inf produced by exp ruins the entire row."},{"type":"heading","level":2,"content":"Attention Pattern Visualisation"},{"type":"text","content":"The attention weight matrix A ∈ ℝ^{nq×nk} is interpretable as a soft routing map: entry Aᵢⱼ is the fraction of value-vector j aggregated into output position i. Visualising A as a heatmap reveals which key positions each query relies on. High-entropy rows (diffuse attention) indicate general information gathering; low-entropy rows (peaked attention) indicate specific retrieval. In language models, patterns like diagonal concentration (local attention), column concentration (attending to a special token), and block structure (phrase-level grouping) each reflect different linguistic behaviours."},{"type":"code","language":"python","content":"import numpy as np\n\ndef sdp_attention(Q, K, V):\n    dk = Q.shape[-1]\n    S = Q @ K.T / np.sqrt(dk)\n    S -= S.max(axis=-1, keepdims=True)\n    A = np.exp(S); A /= A.sum(axis=-1, keepdims=True)\n    return A @ V, A\n\ndef print_heatmap(A, row_labels, col_labels):\n    col_w = max(len(c) for c in col_labels) + 1\n    header = \u0027{:\u003e10}\u0027.format(\u0027\u0027) + \u0027\u0027.join(\u0027{:\u003e{w}}\u0027.format(c, w=col_w) for c in col_labels)\n    print(header)\n    print(\u0027-\u0027 * len(header))\n    for rl, row in zip(row_labels, A):\n        cells = \u0027\u0027.join(\n            \u0027{:\u003e{w}}\u0027.format(\u0027++\u0027 if w \u003e 0.3 else \u0027+\u0027 if w \u003e 0.1 else \u0027.\u0027, w=col_w)\n            for w in row)\n        print(\u0027{:\u003e10}{}\u0027.format(rl[:10], cells) + \u0027  peak-\u003e\u0027 + col_labels[row.argmax()])\n\nnp.random.seed(99)\ntokens = [\u0027The\u0027, \u0027cat\u0027, \u0027sat\u0027, \u0027on\u0027, \u0027the\u0027, \u0027mat\u0027]\ndk, dv = 32, 32\nQ = np.random.randn(len(tokens), dk)\nK = np.random.randn(len(tokens), dk)\nV = np.random.randn(len(tokens), dv)\n_, A = sdp_attention(Q, K, V)\nprint_heatmap(A, tokens, tokens)\nentropy = -(A * np.log(A + 1e-9)).sum(axis=1)\nprint(\u0027Attention entropy per token (nats):\u0027, entropy.round(3))\nprint(\u0027Uniform entropy would be: {:.3f}\u0027.format(np.log(len(tokens))))"},{"type":"heading","level":2,"content":"Computational Complexity"},{"type":"text","content":"Attention has three stages: score computation QKᵀ costs O(nq·nk·dₖ), softmax costs O(nq·nk), and value aggregation AV costs O(nq·nk·dv). Total: O(nq·nk·(dₖ+dv)). For self-attention nq=nk=n, giving O(n²d). This quadratic dependence on sequence length is the primary scalability bottleneck: a 4× sequence length increase costs 16× in computation and 16× in memory for the score matrix S ∈ ℝ^{n×n}. The memory footprint is n²·4 bytes (float32); at n=4096 with dₖ=64 the score matrix alone consumes 64 MB per head."},{"type":"code","language":"python","content":"import numpy as np\nimport time\n\ndef attention_time_ms(seq_len, dk=64, dv=64, n_trials=3):\n    rng = np.random.RandomState(42)\n    timings = []\n    for _ in range(n_trials):\n        Q = rng.randn(seq_len, dk).astype(np.float32)\n        K = rng.randn(seq_len, dk).astype(np.float32)\n        V = rng.randn(seq_len, dv).astype(np.float32)\n        t0 = time.perf_counter()\n        S = Q @ K.T / np.sqrt(dk)         # O(n^2 * dk)\n        S -= S.max(1, keepdims=True)\n        A = np.exp(S); A /= A.sum(1, keepdims=True)\n        _ = A @ V                          # O(n^2 * dv)\n        timings.append(time.perf_counter() - t0)\n    return np.median(timings) * 1000\n\nseq_lens = [128, 256, 512, 1024, 2048]\nprint(\u0027{:\u003e6} {:\u003e9} {:\u003e8} {:\u003e10} {:\u003e8}\u0027.format(\u0027n\u0027, \u0027time_ms\u0027, \u0027ratio\u0027, \u0027n^2_ratio\u0027, \u0027mem_MB\u0027))\nprev_t, prev_n = None, None\nfor n in seq_lens:\n    t = attention_time_ms(n)\n    ratio = t / prev_t if prev_t else 1.0\n    n2r = (n / prev_n) ** 2 if prev_n else 1.0\n    mem = n * n * 4 / 1e6\n    print(\u0027{:\u003e6} {:\u003e9.2f} {:\u003e8.2f} {:\u003e10.2f} {:\u003e8.1f}\u0027.format(n, t, ratio, n2r, mem))\n    prev_t, prev_n = t, n\nprint(\u0027Time ratio tracks n^2 ratio -\u003e O(n^2*d) complexity confirmed.\u0027)"},{"type":"heading","level":2,"content":"Attention as Soft Dictionary Lookup"},{"type":"text","content":"Attention generalises a hard key-value store. In a hard lookup a query exactly matches one key and retrieves the corresponding value. In soft attention the query computes a similarity score with every key and retrieves a differentiable weighted blend of all values. The softmax plays the role of a differentiable argmax — approximating discrete selection while remaining differentiable throughout. This framing clarifies the design: queries ask questions, keys describe what each position knows about itself, and values carry the payload to be aggregated."},{"type":"table","headers":["Component","Shape","Role","Analogy","Extreme Behaviour"],"rows":[["Query (Q)","nq × dₖ","What information am I looking for?","Search query","One-hot attention if scores peak sharply"],["Key (K)","nk × dₖ","What do I advertise?","Index key in a database","Uniform attention if all keys equal"],["Value (V)","nk × dv","What content do I carry?","Stored record / content","Retrieval uninformative if V is constant"],["Score S = QKᵀ/√dₖ","nq × nk","Query-key compatibility","Similarity metric","Large scores saturate softmax → near-zero gradients"],["Weight A = softmax(S)","nq × nk","Normalised importance per query-key pair","Relevance probability","Rows always sum to 1; entropy measures focus"]]},{"type":"heading","level":2,"content":"Efficient Implementations — FlashAttention"},{"type":"text","content":"Standard attention materialises the full n×n score matrix in GPU HBM (high-bandwidth memory), requiring O(n²) memory. FlashAttention (Dao et al. 2022) avoids this by tiling computation in fast on-chip SRAM: it fuses score computation, softmax, and value aggregation into a single kernel pass, maintaining running softmax statistics (online normalisation) to merge partial results correctly. The output O is written to HBM directly — the score matrix S is never materialised. This achieves exact attention in O(n) memory with 2–4× wall-clock speedup on A100 GPUs compared to standard implementations."},{"type":"list","ordered":false,"items":["Tiling: divide Q, K, V into blocks of ~64–128 rows that fit in SRAM","Online softmax: track running maximum and normalisation constant across blocks","No materialisation: never write the n×n score matrix to HBM — write only output O","Recomputation in backward pass: recompute S and A on-the-fly from saved Q, K, V","Memory: O(n) vs O(n²) for standard attention — critical for n \u003e 4096","FlashAttention-2 (Dao 2023) further improves parallelism across the sequence dimension"]},{"type":"divider"}]"
---
# Scaled Dot-Product Attention — Derivation and Numerical Stability

Scaled dot-product attention is the computational core of every Transformer. Given queries Q, keys K, and values V it computes a weighted sum of value vectors where the weights are determined by query-key similarity: Attention(Q,K,V) = softmax(QKᵀ/√dₖ)V. Three design choices — dot-product scoring, √dₖ scaling, and softmax normalisation — each have precise mathematical motivations that are easy to miss when reading only the formula.

## Mathematical Definition and Tensor Shapes

Queries Q ∈ ℝ^{nq×dₖ} represent nq positions asking for information. Keys K ∈ ℝ^{nk×dₖ} represent nk positions advertising what they contain. Values V ∈ ℝ^{nk×dv} carry the actual content to be retrieved. The score matrix S = QKᵀ/√dₖ ∈ ℝ^{nq×nk} measures pairwise compatibility — entry Sᵢⱼ = qᵢ·kⱼ/√dₖ is how relevant key j is to query i. Applying row-wise softmax gives attention weights A = softmax(S) ∈ ℝ^{nq×nk} with rows summing to one. The output O = AV ∈ ℝ^{nq×dv} is a convex combination of value vectors for each query.

$$\text{Attention}(Q,K,V) = \text{softmax}\!\left(\frac{QK^\top}{\sqrt{d_k}}\right)V$$

## The √dₖ Scaling Factor — Derivation

Suppose Q and K have independent entries drawn from N(0,1). The dot product qᵢ·kⱼ = Σₗ qᵢₗkⱼₗ is a sum of dₖ independent terms each with mean 0 and variance 1, so qᵢ·kⱼ ~ N(0, dₖ). The standard deviation is √dₖ — for dₖ=64 this is 8, meaning raw scores span roughly ±24. The softmax exp(x)/Σexp pushes values in its flat saturation region when |x| is large: all probability mass collapses onto the maximum-scoring key. Dividing by √dₖ restores unit variance, keeping scores in the regime where softmax distributes mass across multiple keys and its Jacobian retains non-negligible entries.

```python
import numpy as np
import torch
import torch.nn.functional as F

def sdp_attention_numpy(Q, K, V, mask=None):
    # Q: (nq, dk), K: (nk, dk), V: (nk, dv)
    # Returns: output (nq, dv), weights (nq, nk)
    dk = Q.shape[-1]
    scores = Q @ K.T / np.sqrt(dk)
    if mask is not None:
        scores = scores + mask * -1e9
    scores = scores - scores.max(axis=-1, keepdims=True)  # numeric stability
    weights = np.exp(scores)
    weights = weights / weights.sum(axis=-1, keepdims=True)
    return weights @ V, weights

def sdp_attention_torch(Q, K, V):
    dk = Q.shape[-1]
    scores = Q @ K.transpose(-2, -1) / dk ** 0.5
    weights = F.softmax(scores, dim=-1)
    return weights @ V, weights

np.random.seed(42)
nq, nk, dk, dv = 5, 7, 64, 64
Q = np.random.randn(nq, dk).astype(np.float32)
K = np.random.randn(nk, dk).astype(np.float32)
V = np.random.randn(nk, dv).astype(np.float32)
out_np, w_np = sdp_attention_numpy(Q, K, V)
Qt = torch.tensor(Q); Kt = torch.tensor(K); Vt = torch.tensor(V)
out_pt, w_pt = sdp_attention_torch(Qt, Kt, Vt)
print('Output shape:', out_np.shape)
print('Weights row-sum:', w_np.sum(axis=1).round(5))
print('Max diff NumPy vs PyTorch:', np.abs(out_np - out_pt.numpy()).max())
```

## Softmax Saturation and Gradient Flow

The softmax Jacobian ∂σ/∂z = diag(σ) − σσᵀ has entries bounded by σᵢ(1−σᵢ). When softmax approaches a one-hot vector (due to large unscaled scores), all entries σᵢ(1−σᵢ) collapse toward zero and the Frobenius norm of the Jacobian vanishes — blocking gradient flow during backpropagation. With √dₖ scaling the score distribution remains approximately N(0,1) regardless of dₖ, keeping the Jacobian norm stable across all model sizes.

```python
import numpy as np

def softmax(x):
    e = np.exp(x - x.max())
    return e / e.sum()

def jacobian_frob_norm(s):
    # Frobenius norm of softmax Jacobian: diag(s) - s*s^T
    return np.sqrt(np.sum((np.diag(s) - np.outer(s, s)) ** 2))

print('{:>5} | {:>9} | {:>11} | {:>14} | {:>12}'.format(
    'dk', 'dot_std', 'scaled_std', 'J_unscaled', 'J_scaled'))
print('-' * 60)
np.random.seed(0)
for dk in [1, 4, 16, 64, 256, 1024]:
    q = np.random.randn(dk)
    keys = np.random.randn(6, dk)
    dots = keys @ q                    # ~ N(0, dk)
    scaled = dots / np.sqrt(dk)        # ~ N(0, 1)
    jn_u = jacobian_frob_norm(softmax(dots))
    jn_s = jacobian_frob_norm(softmax(scaled))
    print('{:>5} | {:>9.3f} | {:>11.3f} | {:>14.6f} | {:>12.6f}'.format(
        dk, dots.std(), scaled.std(), jn_u, jn_s))
print('Unscaled Jacobian norm collapses as dk grows -> vanishing gradients.')
print('Scaled norm stays near constant -> stable gradient flow.')
```

> **Numerical Stability in Implementation**: Always subtract the row maximum before computing exp: scores -= scores.max(-1, keepdims=True). This prevents overflow without changing the result since exp(x-c)/Σexp(x-c) = exp(x)/Σexp(x). PyTorch F.softmax handles this internally. For custom CUDA kernels this step is non-negotiable — a single inf produced by exp ruins the entire row.

## Attention Pattern Visualisation

The attention weight matrix A ∈ ℝ^{nq×nk} is interpretable as a soft routing map: entry Aᵢⱼ is the fraction of value-vector j aggregated into output position i. Visualising A as a heatmap reveals which key positions each query relies on. High-entropy rows (diffuse attention) indicate general information gathering; low-entropy rows (peaked attention) indicate specific retrieval. In language models, patterns like diagonal concentration (local attention), column concentration (attending to a special token), and block structure (phrase-level grouping) each reflect different linguistic behaviours.

```python
import numpy as np

def sdp_attention(Q, K, V):
    dk = Q.shape[-1]
    S = Q @ K.T / np.sqrt(dk)
    S -= S.max(axis=-1, keepdims=True)
    A = np.exp(S); A /= A.sum(axis=-1, keepdims=True)
    return A @ V, A

def print_heatmap(A, row_labels, col_labels):
    col_w = max(len(c) for c in col_labels) + 1
    header = '{:>10}'.format('') + ''.join('{:>{w}}'.format(c, w=col_w) for c in col_labels)
    print(header)
    print('-' * len(header))
    for rl, row in zip(row_labels, A):
        cells = ''.join(
            '{:>{w}}'.format('++' if w > 0.3 else '+' if w > 0.1 else '.', w=col_w)
            for w in row)
        print('{:>10}{}'.format(rl[:10], cells) + '  peak->' + col_labels[row.argmax()])

np.random.seed(99)
tokens = ['The', 'cat', 'sat', 'on', 'the', 'mat']
dk, dv = 32, 32
Q = np.random.randn(len(tokens), dk)
K = np.random.randn(len(tokens), dk)
V = np.random.randn(len(tokens), dv)
_, A = sdp_attention(Q, K, V)
print_heatmap(A, tokens, tokens)
entropy = -(A * np.log(A + 1e-9)).sum(axis=1)
print('Attention entropy per token (nats):', entropy.round(3))
print('Uniform entropy would be: {:.3f}'.format(np.log(len(tokens))))
```

## Computational Complexity

Attention has three stages: score computation QKᵀ costs O(nq·nk·dₖ), softmax costs O(nq·nk), and value aggregation AV costs O(nq·nk·dv). Total: O(nq·nk·(dₖ+dv)). For self-attention nq=nk=n, giving O(n²d). This quadratic dependence on sequence length is the primary scalability bottleneck: a 4× sequence length increase costs 16× in computation and 16× in memory for the score matrix S ∈ ℝ^{n×n}. The memory footprint is n²·4 bytes (float32); at n=4096 with dₖ=64 the score matrix alone consumes 64 MB per head.

```python
import numpy as np
import time

def attention_time_ms(seq_len, dk=64, dv=64, n_trials=3):
    rng = np.random.RandomState(42)
    timings = []
    for _ in range(n_trials):
        Q = rng.randn(seq_len, dk).astype(np.float32)
        K = rng.randn(seq_len, dk).astype(np.float32)
        V = rng.randn(seq_len, dv).astype(np.float32)
        t0 = time.perf_counter()
        S = Q @ K.T / np.sqrt(dk)         # O(n^2 * dk)
        S -= S.max(1, keepdims=True)
        A = np.exp(S); A /= A.sum(1, keepdims=True)
        _ = A @ V                          # O(n^2 * dv)
        timings.append(time.perf_counter() - t0)
    return np.median(timings) * 1000

seq_lens = [128, 256, 512, 1024, 2048]
print('{:>6} {:>9} {:>8} {:>10} {:>8}'.format('n', 'time_ms', 'ratio', 'n^2_ratio', 'mem_MB'))
prev_t, prev_n = None, None
for n in seq_lens:
    t = attention_time_ms(n)
    ratio = t / prev_t if prev_t else 1.0
    n2r = (n / prev_n) ** 2 if prev_n else 1.0
    mem = n * n * 4 / 1e6
    print('{:>6} {:>9.2f} {:>8.2f} {:>10.2f} {:>8.1f}'.format(n, t, ratio, n2r, mem))
    prev_t, prev_n = t, n
print('Time ratio tracks n^2 ratio -> O(n^2*d) complexity confirmed.')
```

## Attention as Soft Dictionary Lookup

Attention generalises a hard key-value store. In a hard lookup a query exactly matches one key and retrieves the corresponding value. In soft attention the query computes a similarity score with every key and retrieves a differentiable weighted blend of all values. The softmax plays the role of a differentiable argmax — approximating discrete selection while remaining differentiable throughout. This framing clarifies the design: queries ask questions, keys describe what each position knows about itself, and values carry the payload to be aggregated.

| Component | Shape | Role | Analogy | Extreme Behaviour |
| --- | --- | --- | --- | --- |
| Query (Q) | nq × dₖ | What information am I looking for? | Search query | One-hot attention if scores peak sharply |
| Key (K) | nk × dₖ | What do I advertise? | Index key in a database | Uniform attention if all keys equal |
| Value (V) | nk × dv | What content do I carry? | Stored record / content | Retrieval uninformative if V is constant |
| Score S = QKᵀ/√dₖ | nq × nk | Query-key compatibility | Similarity metric | Large scores saturate softmax → near-zero gradients |
| Weight A = softmax(S) | nq × nk | Normalised importance per query-key pair | Relevance probability | Rows always sum to 1; entropy measures focus |

## Efficient Implementations — FlashAttention

Standard attention materialises the full n×n score matrix in GPU HBM (high-bandwidth memory), requiring O(n²) memory. FlashAttention (Dao et al. 2022) avoids this by tiling computation in fast on-chip SRAM: it fuses score computation, softmax, and value aggregation into a single kernel pass, maintaining running softmax statistics (online normalisation) to merge partial results correctly. The output O is written to HBM directly — the score matrix S is never materialised. This achieves exact attention in O(n) memory with 2–4× wall-clock speedup on A100 GPUs compared to standard implementations.

- Tiling: divide Q, K, V into blocks of ~64–128 rows that fit in SRAM
- Online softmax: track running maximum and normalisation constant across blocks
- No materialisation: never write the n×n score matrix to HBM — write only output O
- Recomputation in backward pass: recompute S and A on-the-fly from saved Q, K, V
- Memory: O(n) vs O(n²) for standard attention — critical for n > 4096
- FlashAttention-2 (Dao 2023) further improves parallelism across the sequence dimension

---

