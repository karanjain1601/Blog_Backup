---
title: "Tensor Operations in ML"
slug: "tensor-operations"
description: "Higher-order tensors, einsum notation, tensor contractions, CP and Tucker decompositions, convolutions, and tensor parallelism."
tags: ["linear-algebra", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[
  {"type":"text","content":"Tensors generalize matrices to higher dimensions — a 4D tensor holds an image batch, a 5D tensor holds a video batch. Tensor operations are the computational substrate of deep learning: convolutions, attention, batched matrix multiplies, and embedding lookups are all tensor operations. Mastering einsum notation and understanding tensor decompositions enables both efficient implementation and model compression."},
  {"type":"heading","level":2,"content":"Higher-Order Tensors in Deep Learning"},
  {"type":"text","content":"A rank-N tensor has N axes (dimensions). The most common tensor shapes in deep learning:\n\n- **Rank-1**: `(d,)` — vector, embedding\n- **Rank-2**: `(B, d)` — batch of embeddings\n- **Rank-3**: `(B, T, d)` — batch of sequences (text, time series)\n- **Rank-4**: `(B, C, H, W)` or `(B, H, W, C)` — batch of images\n- **Rank-5**: `(B, T, C, H, W)` — batch of video frames\n\nThe **batch dimension B** is almost always the first axis in PyTorch convention. Operations are vectorized over the batch, enabling GPUs to process hundreds of examples simultaneously."},
  {"type":"code","language":"python","content":"import torch\n\n# Common tensor shapes in ML\ntokens    = torch.randn(32, 128, 512)   # (batch, seq_len, d_model)\nimage     = torch.randn(32, 3, 224, 224) # (batch, channels, H, W)\nattention = torch.randn(32, 8, 128, 128) # (batch, heads, T_q, T_k)\nvideo     = torch.randn(4, 16, 3, 112, 112) # (batch, frames, C, H, W)\n\nfor name, t in [('tokens', tokens), ('image', image),\n                ('attention', attention), ('video', video)]:\n    print(f'{name}: shape={t.shape}, numel={t.numel():,}, MB={t.nbytes/1e6:.1f}')"},
  {"type":"heading","level":2,"content":"Einstein Summation Notation (einsum)"},
  {"type":"text","content":"**Einsum** is a compact notation for expressing any multilinear operation (dot products, matrix multiplies, outer products, traces, transposes, and beyond) using index labels:\n\n  output[i,k] = Σⱼ A[i,j] * B[j,k]  →  einsum('ij,jk->ik', A, B)\n\nThe rules: free indices (appearing in the output) are kept; contracted indices (appearing in inputs but not output) are summed over. This notation is more expressive than any single function and often generates more efficient code than explicit loops or nested operations.\n\nEinsum avoids materializing intermediate tensors, supports batching naturally, and is available in NumPy, PyTorch, JAX (where it's even JIT-compiled). Reading einsum: the arrow separates input index patterns from the output index pattern."},
  {"type":"code","language":"python","content":"import torch\n\nA = torch.randn(3, 4)\nB = torch.randn(4, 5)\nx = torch.randn(4)\n\n# Matrix multiply: C[i,k] = sum_j A[i,j] * B[j,k]\nC = torch.einsum('ij,jk->ik', A, B)   # (3,5)\nprint('matmul:', C.shape, torch.allclose(C, A @ B))\n\n# Matrix-vector: y[i] = sum_j A[i,j] * x[j]\ny = torch.einsum('ij,j->i', A, x)     # (3,)\nprint('matvec:', y.shape, torch.allclose(y, A @ x))\n\n# Outer product: P[i,j] = u[i] * v[j]\nu, v = torch.randn(3), torch.randn(5)\nP = torch.einsum('i,j->ij', u, v)     # (3,5)\n\n# Batch matrix multiply: C[b,i,k] = sum_j A[b,i,j]*B[b,j,k]\nA3 = torch.randn(8, 3, 4)\nB3 = torch.randn(8, 4, 5)\nC3 = torch.einsum('bij,bjk->bik', A3, B3)  # (8,3,5)\nprint('batch matmul:', C3.shape, torch.allclose(C3, torch.bmm(A3, B3)))\n\n# Trace: tr(A)\nAsq = torch.randn(4, 4)\ntrace = torch.einsum('ii->', Asq)      # scalar\nprint('trace:', trace.item(), torch.trace(Asq).item())"},
  {"type":"heading","level":2,"content":"Tensor Contractions"},
  {"type":"text","content":"A **tensor contraction** sums over shared indices between two tensors, generalizing matrix multiplication to higher-order tensors. Einsum compactly expresses any contraction:\n\n- Matrix multiply: contract over one shared index\n- Double contraction (e.g., Frobenius inner product ⟨A,B⟩ = Σᵢⱼ AᵢⱼBᵢⱼ): contract over all shared indices\n- Multi-index contraction: used in tensor network methods\n\nIn deep learning, multi-head attention is a four-way operation. Convolution is equivalent to a tensor contraction between the input feature map and the filter tensor."},
  {"type":"code","language":"python","content":"import torch\n\n# Multi-head attention einsum: scores[b,h,i,j] = Q[b,h,i,d] * K[b,h,j,d]\nB, H, T, D = 2, 8, 16, 64\nQ = torch.randn(B, H, T, D)\nK = torch.randn(B, H, T, D)\nV = torch.randn(B, H, T, D)\n\n# QK^T via einsum (avoids transpose + matmul)\nscores = torch.einsum('bhid,bhjd->bhij', Q, K) / D**0.5  # (B,H,T,T)\nweights = torch.softmax(scores, dim=-1)\n# Weighted sum of values\noutput = torch.einsum('bhij,bhjd->bhid', weights, V)    # (B,H,T,D)\nprint('Attention output:', output.shape)\n\n# Frobenius inner product: sum of elementwise products\nA = torch.randn(3, 4)\nB_ = torch.randn(3, 4)\nfro_ip = torch.einsum('ij,ij->', A, B_)  # scalar\nprint('Frob inner product:', fro_ip.item(), (A * B_).sum().item())"},
  {"type":"heading","level":2,"content":"CP Decomposition"},
  {"type":"text","content":"**CANDECOMP/PARAFAC (CP) decomposition** expresses a rank-R approximation of a tensor **T** as a sum of R rank-1 terms:\n\n  T ≈ Σᵣ₌₁ᴿ aᵣ ⊗ bᵣ ⊗ cᵣ\n\nwhere **a**ᵣ ⊗ **b**ᵣ ⊗ **c**ᵣ denotes the outer product of vectors. This is the tensor generalization of SVD's rank-1 decomposition A = Σᵢ σᵢ uᵢvᵢᵀ. CP decomposition is used for:\n- Compressing 3D weight tensors in CNNs/RNNs\n- Discovering latent factors in multi-relational data (knowledge graphs)\n- Approximating interaction tensors in polynomial networks"},
  {"type":"heading","level":2,"content":"Tucker and Tensor Train Decompositions"},
  {"type":"text","content":"**Tucker decomposition** generalizes CP by using a core tensor **G** with factor matrices along each mode:\n\n  T ≈ G ×₁ A ×₂ B ×₃ C\n\nwhere ×ₙ denotes mode-n product. Tucker compresses each mode independently and can represent more general structure than CP. It is the tensor analog of truncated SVD.\n\n**Tensor Train (TT) decomposition** represents a high-order tensor as a sequence of 3D 'cores' connected like a chain: T[i₁,...,iₙ] = G₁[i₁] G₂[i₂] ... Gₙ[iₙ] (matrix products). TT decomposition can represent exponentially large tensors with polynomial storage — used for compressing embedding tables in recommendation systems and approximating high-dimensional functions."},
  {"type":"heading","level":2,"content":"Convolutions as Tensor Operations"},
  {"type":"text","content":"A 2D convolution between input **X** (shape B×Cᵢₙ×H×W) and filters **W** (Cₒᵤₜ×Cᵢₙ×kH×kW) is a tensor contraction:\n\n  Y[b, c_out, h, w] = Σ_{c_in, kh, kw} W[c_out, c_in, kh, kw] · X[b, c_in, h+kh, w+kw]\n\nThis is a local contraction over the spatial (kH, kW) and channel (Cᵢₙ) dimensions. Efficient convolution implementations (im2col, Winograd, FFT-based) all reduce this tensor operation to batched matrix multiplies, exploiting BLAS routines and Tensor Cores."},
  {"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\n# Explicit small convolution for understanding\nX = torch.randn(2, 3, 8, 8)     # (B, C_in, H, W)\nW = torch.randn(16, 3, 3, 3)    # (C_out, C_in, kH, kW)\nY = F.conv2d(X, W, padding=1)   # (2, 16, 8, 8)\nprint('Conv output:', Y.shape)\n\n# Equivalent einsum (naive, no sliding — just to show structure)\n# For a single position (no sliding window):\nX_patch = X[:, :, :3, :3]       # (2, 3, 3, 3) -- top-left patch\nY_00 = torch.einsum('bcij,ocij->bo', X_patch, W)  # (2, 16)\nprint('Single position result shape:', Y_00.shape)\n\n# Batched matmul (bmm): batch of matrix multiplies\nA = torch.randn(32, 128, 64)   # (batch, T, d)\nB_ = torch.randn(32, 64, 128)  # (batch, d, T)\nC = torch.bmm(A, B_)           # (32, 128, 128) -- batch matmul\nprint('BMM output:', C.shape)"},
  {"type":"heading","level":2,"content":"Tensor Parallelism in Distributed Training"},
  {"type":"text","content":"For models too large to fit on a single GPU, **tensor parallelism** shards individual weight tensors across multiple GPUs. A linear layer **Y = XW** can be split:\n\n- **Column-parallel**: W split by columns → W = [W₁|W₂]; each GPU computes XWᵢ and results are concatenated\n- **Row-parallel**: W split by rows → W = [W₁;W₂]; each GPU holds a slice of X and part of W, results are all-reduced\n\nMegatron-LM (NVIDIA) pioneered tensor parallelism for transformer attention and feedforward layers. The key insight: the matmul is the most compute-intensive operation and can be partitioned with minimal inter-GPU communication (only one all-reduce per layer half, not per multiply)."},
  {"type":"callout","variant":"tip","title":"Prefer einsum Over Explicit Reshape+Matmul","content":"Expressing multi-dimensional contractions with einsum is cleaner, less error-prone, and often faster than sequences of reshape/transpose/matmul. PyTorch's einsum can fuse operations and reduce temporary allocations. torch.einsum('bhid,bhjd->bhij', Q, K) is clearer and equivalent to (Q @ K.transpose(-2,-1)), but generalizes to arbitrary index patterns. Use opt_einsum library for optimal contraction order on large networks."},
  {"type":"table","headers":["Decomposition","Formula","Key Use Case"],"rows":[["CP","Σ aᵣ⊗bᵣ⊗cᵣ","CNN weight compression, factor models"],["Tucker","G ×₁ A ×₂ B ×₃ C","Multi-mode dimensionality reduction"],["Tensor Train","G₁G₂...Gₙ","Embedding compression, high-dim approx"],["SVD (matrix)","UΣVᵀ","Matrix factorization, PCA"],["Matrix product state","Same as TT","Quantum physics, sequence modeling"]]}
]
"
---

# Tensor Operations in ML

Tensors generalize matrices to higher dimensions — a 4D tensor holds an image batch, a 5D tensor holds a video batch. Tensor operations are the computational substrate of deep learning: convolutions, attention, batched matrix multiplies, and embedding lookups are all tensor operations. Mastering einsum notation and understanding tensor decompositions enables both efficient implementation and model compression.

## Higher-Order Tensors in Deep Learning

A rank-N tensor has N axes (dimensions). The most common tensor shapes in deep learning:

- **Rank-1**: `(d,)` — vector, embedding
- **Rank-2**: `(B, d)` — batch of embeddings
- **Rank-3**: `(B, T, d)` — batch of sequences (text, time series)
- **Rank-4**: `(B, C, H, W)` or `(B, H, W, C)` — batch of images
- **Rank-5**: `(B, T, C, H, W)` — batch of video frames

The **batch dimension B** is almost always the first axis in PyTorch convention. Operations are vectorized over the batch, enabling GPUs to process hundreds of examples simultaneously.

```python
import torch

# Common tensor shapes in ML
tokens    = torch.randn(32, 128, 512)   # (batch, seq_len, d_model)
image     = torch.randn(32, 3, 224, 224) # (batch, channels, H, W)
attention = torch.randn(32, 8, 128, 128) # (batch, heads, T_q, T_k)
video     = torch.randn(4, 16, 3, 112, 112) # (batch, frames, C, H, W)

for name, t in [('tokens', tokens), ('image', image),
                ('attention', attention), ('video', video)]:
    print(f'{name}: shape={t.shape}, numel={t.numel():,}, MB={t.nbytes/1e6:.1f}')
```

## Einstein Summation Notation (einsum)

**Einsum** is a compact notation for expressing any multilinear operation (dot products, matrix multiplies, outer products, traces, transposes, and beyond) using index labels:

  output[i,k] = Σⱼ A[i,j] * B[j,k]  →  einsum('ij,jk->ik', A, B)

The rules: free indices (appearing in the output) are kept; contracted indices (appearing in inputs but not output) are summed over. This notation is more expressive than any single function and often generates more efficient code than explicit loops or nested operations.

Einsum avoids materializing intermediate tensors, supports batching naturally, and is available in NumPy, PyTorch, JAX (where it's even JIT-compiled). Reading einsum: the arrow separates input index patterns from the output index pattern.

```python
import torch

A = torch.randn(3, 4)
B = torch.randn(4, 5)
x = torch.randn(4)

# Matrix multiply: C[i,k] = sum_j A[i,j] * B[j,k]
C = torch.einsum('ij,jk->ik', A, B)   # (3,5)
print('matmul:', C.shape, torch.allclose(C, A @ B))

# Matrix-vector: y[i] = sum_j A[i,j] * x[j]
y = torch.einsum('ij,j->i', A, x)     # (3,)
print('matvec:', y.shape, torch.allclose(y, A @ x))

# Outer product: P[i,j] = u[i] * v[j]
u, v = torch.randn(3), torch.randn(5)
P = torch.einsum('i,j->ij', u, v)     # (3,5)

# Batch matrix multiply: C[b,i,k] = sum_j A[b,i,j]*B[b,j,k]
A3 = torch.randn(8, 3, 4)
B3 = torch.randn(8, 4, 5)
C3 = torch.einsum('bij,bjk->bik', A3, B3)  # (8,3,5)
print('batch matmul:', C3.shape, torch.allclose(C3, torch.bmm(A3, B3)))

# Trace: tr(A)
Asq = torch.randn(4, 4)
trace = torch.einsum('ii->', Asq)      # scalar
print('trace:', trace.item(), torch.trace(Asq).item())
```

## Tensor Contractions

A **tensor contraction** sums over shared indices between two tensors, generalizing matrix multiplication to higher-order tensors. Einsum compactly expresses any contraction:

- Matrix multiply: contract over one shared index
- Double contraction (e.g., Frobenius inner product ⟨A,B⟩ = Σᵢⱼ AᵢⱼBᵢⱼ): contract over all shared indices
- Multi-index contraction: used in tensor network methods

In deep learning, multi-head attention is a four-way operation. Convolution is equivalent to a tensor contraction between the input feature map and the filter tensor.

```python
import torch

# Multi-head attention einsum: scores[b,h,i,j] = Q[b,h,i,d] * K[b,h,j,d]
B, H, T, D = 2, 8, 16, 64
Q = torch.randn(B, H, T, D)
K = torch.randn(B, H, T, D)
V = torch.randn(B, H, T, D)

# QK^T via einsum (avoids transpose + matmul)
scores = torch.einsum('bhid,bhjd->bhij', Q, K) / D**0.5  # (B,H,T,T)
weights = torch.softmax(scores, dim=-1)
# Weighted sum of values
output = torch.einsum('bhij,bhjd->bhid', weights, V)    # (B,H,T,D)
print('Attention output:', output.shape)

# Frobenius inner product: sum of elementwise products
A = torch.randn(3, 4)
B_ = torch.randn(3, 4)
fro_ip = torch.einsum('ij,ij->', A, B_)  # scalar
print('Frob inner product:', fro_ip.item(), (A * B_).sum().item())
```

## CP Decomposition

**CANDECOMP/PARAFAC (CP) decomposition** expresses a rank-R approximation of a tensor **T** as a sum of R rank-1 terms:

  T ≈ Σᵣ₌₁ᴿ aᵣ ⊗ bᵣ ⊗ cᵣ

where **a**ᵣ ⊗ **b**ᵣ ⊗ **c**ᵣ denotes the outer product of vectors. This is the tensor generalization of SVD's rank-1 decomposition A = Σᵢ σᵢ uᵢvᵢᵀ. CP decomposition is used for:
- Compressing 3D weight tensors in CNNs/RNNs
- Discovering latent factors in multi-relational data (knowledge graphs)
- Approximating interaction tensors in polynomial networks

## Tucker and Tensor Train Decompositions

**Tucker decomposition** generalizes CP by using a core tensor **G** with factor matrices along each mode:

  T ≈ G ×₁ A ×₂ B ×₃ C

where ×ₙ denotes mode-n product. Tucker compresses each mode independently and can represent more general structure than CP. It is the tensor analog of truncated SVD.

**Tensor Train (TT) decomposition** represents a high-order tensor as a sequence of 3D 'cores' connected like a chain: T[i₁,...,iₙ] = G₁[i₁] G₂[i₂] ... Gₙ[iₙ] (matrix products). TT decomposition can represent exponentially large tensors with polynomial storage — used for compressing embedding tables in recommendation systems and approximating high-dimensional functions.

## Convolutions as Tensor Operations

A 2D convolution between input **X** (shape B×Cᵢₙ×H×W) and filters **W** (Cₒᵤₜ×Cᵢₙ×kH×kW) is a tensor contraction:

  Y[b, c_out, h, w] = Σ_{c_in, kh, kw} W[c_out, c_in, kh, kw] · X[b, c_in, h+kh, w+kw]

This is a local contraction over the spatial (kH, kW) and channel (Cᵢₙ) dimensions. Efficient convolution implementations (im2col, Winograd, FFT-based) all reduce this tensor operation to batched matrix multiplies, exploiting BLAS routines and Tensor Cores.

```python
import torch
import torch.nn.functional as F

# Explicit small convolution for understanding
X = torch.randn(2, 3, 8, 8)     # (B, C_in, H, W)
W = torch.randn(16, 3, 3, 3)    # (C_out, C_in, kH, kW)
Y = F.conv2d(X, W, padding=1)   # (2, 16, 8, 8)
print('Conv output:', Y.shape)

# Equivalent einsum (naive, no sliding — just to show structure)
# For a single position (no sliding window):
X_patch = X[:, :, :3, :3]       # (2, 3, 3, 3) -- top-left patch
Y_00 = torch.einsum('bcij,ocij->bo', X_patch, W)  # (2, 16)
print('Single position result shape:', Y_00.shape)

# Batched matmul (bmm): batch of matrix multiplies
A = torch.randn(32, 128, 64)   # (batch, T, d)
B_ = torch.randn(32, 64, 128)  # (batch, d, T)
C = torch.bmm(A, B_)           # (32, 128, 128) -- batch matmul
print('BMM output:', C.shape)
```

## Tensor Parallelism in Distributed Training

For models too large to fit on a single GPU, **tensor parallelism** shards individual weight tensors across multiple GPUs. A linear layer **Y = XW** can be split:

- **Column-parallel**: W split by columns → W = [W₁|W₂]; each GPU computes XWᵢ and results are concatenated
- **Row-parallel**: W split by rows → W = [W₁;W₂]; each GPU holds a slice of X and part of W, results are all-reduced

Megatron-LM (NVIDIA) pioneered tensor parallelism for transformer attention and feedforward layers. The key insight: the matmul is the most compute-intensive operation and can be partitioned with minimal inter-GPU communication (only one all-reduce per layer half, not per multiply).

> **[TIP] Prefer einsum Over Explicit Reshape+Matmul**
>
> Expressing multi-dimensional contractions with einsum is cleaner, less error-prone, and often faster than sequences of reshape/transpose/matmul. PyTorch's einsum can fuse operations and reduce temporary allocations. torch.einsum('bhid,bhjd->bhij', Q, K) is clearer and equivalent to (Q @ K.transpose(-2,-1)), but generalizes to arbitrary index patterns. Use opt_einsum library for optimal contraction order on large networks.

| Decomposition | Formula | Key Use Case |
| --- | --- | --- |
| CP | Σ aᵣ⊗bᵣ⊗cᵣ | CNN weight compression, factor models |
| Tucker | G ×₁ A ×₂ B ×₃ C | Multi-mode dimensionality reduction |
| Tensor Train | G₁G₂...Gₙ | Embedding compression, high-dim approx |
| SVD (matrix) | UΣVᵀ | Matrix factorization, PCA |
| Matrix product state | Same as TT | Quantum physics, sequence modeling |
