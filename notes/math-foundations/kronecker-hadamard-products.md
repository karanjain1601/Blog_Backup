---
title: "Kronecker and Hadamard Products"
slug: "kronecker-hadamard-products"
description: "Hadamard elementwise product for gating, Kronecker product block structure, the vectorization identity, and K-FAC optimization."
tags: ["linear-algebra", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[
  {"type":"text","content":"Matrix algebra has two important products beyond ordinary multiplication: the **Hadamard product** (elementwise) and the **Kronecker product** (block-structured). These products appear in gating mechanisms, structured convolutions, second-order optimization, and the vectorization of matrix equations. Understanding them reveals elegant structure in computations that would otherwise seem ad hoc."},
  {"type":"heading","level":2,"content":"The Hadamard Product: Elementwise Multiplication"},
  {"type":"text","content":"The **Hadamard product** (also called elementwise product, or Schur product) of two matrices of the same shape is defined entry-by-entry:\n\n  (**A** ⊙ **B**)[i,j] = A[i,j] · B[i,j]\n\nThis is the default `*` operator in NumPy and PyTorch (when shapes are compatible). Unlike matrix multiplication, the Hadamard product is commutative (**A** ⊙ **B** = **B** ⊙ **A**), associative, and distributes over addition. It is the 'natural' pointwise operation when matrices represent pixel maps, attention masks, or feature-wise weights."},
  {"type":"code","language":"python","content":"import numpy as np, torch\n\nA = np.array([[1, 2], [3, 4]])\nB = np.array([[5, 6], [7, 8]])\n\n# Hadamard product (elementwise)\nC = A * B              # numpy: [[5,12],[21,32]]\nprint('A * B:\\n', C)\n\n# vs matrix multiplication\nprint('A @ B:\\n', A @ B)   # [[19,22],[43,50]] -- very different!\n\n# Properties\nprint('Commutative?', np.allclose(A*B, B*A))          # True\nprint('(A*B)*C == A*(B*C)?', np.allclose((A*B)*A, A*(B*A)))  # True\n\n# Frobenius inner product via Hadamard\nfro_ip = np.sum(A * B)   # = tr(A^T B)\nprint('Frobenius inner product:', fro_ip)   # = 5+12+21+32 = 70"},
  {"type":"heading","level":2,"content":"Hadamard Product in Neural Networks: Gating"},
  {"type":"text","content":"Gating mechanisms use the Hadamard product to selectively pass or suppress information:\n\n- **LSTM gates**: The forget gate computes h' = f ⊙ c (elementwise gate on cell state), where f ∈ [0,1] acts as a learned 'forget factor' for each dimension independently.\n- **GRU update gate**: h = (1-z) ⊙ h_prev + z ⊙ h_candidate\n- **Attention masking**: Multiply attention logits by a binary mask (0/1) before softmax to prevent attending to padding tokens\n- **Feature-wise Linear Modulation (FiLM)**: y = γ(c) ⊙ x + β(c) for conditional generation, where γ and β are computed from conditioning variable c\n- **Mixture of Experts gating**: o = Σᵢ gᵢ ⊙ Eᵢ(x) where g is a soft router"},
  {"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\n# Simplified LSTM cell showing Hadamard gating\ndef lstm_cell(x, h_prev, c_prev, W_x, W_h, b):\n    \"\"\"x: (batch, input_size), h_prev, c_prev: (batch, hidden_size)\"\"\"\n    gates = x @ W_x.T + h_prev @ W_h.T + b  # (batch, 4*hidden)\n    hidden = gates.shape[-1] // 4\n    i, f, g, o = gates.split(hidden, dim=-1)  # input, forget, cell, output\n    i = torch.sigmoid(i)\n    f = torch.sigmoid(f)\n    g = torch.tanh(g)\n    o = torch.sigmoid(o)\n    # Hadamard product: elementwise gating of cell state\n    c_new = f * c_prev + i * g   # forget old + input new\n    h_new = o * torch.tanh(c_new)\n    return h_new, c_new\n\n# FiLM conditioning\nclass FiLM(nn.Module):\n    def __init__(self, cond_dim, feat_dim):\n        super().__init__()\n        self.gamma = nn.Linear(cond_dim, feat_dim)\n        self.beta  = nn.Linear(cond_dim, feat_dim)\n\n    def forward(self, x, cond):\n        return self.gamma(cond) * x + self.beta(cond)  # Hadamard scale+shift"},
  {"type":"heading","level":2,"content":"The Kronecker Product: Block Matrix Structure"},
  {"type":"text","content":"The **Kronecker product** **A** ⊗ **B** of an m×n matrix **A** and a p×q matrix **B** is the mp×nq block matrix:\n\n  **A** ⊗ **B** = [[a₁₁B, a₁₂B, ..., a₁ₙB], [a₂₁B, ..., a₂ₙB], ..., [aₘ₁B, ..., aₘₙB]]\n\nEach entry of **A** is replaced by a scaled copy of **B**. Key properties:\n- (**A** ⊗ **B**)ᵀ = **Aᵀ** ⊗ **Bᵀ**\n- (**A** ⊗ **B**)⁻¹ = **A⁻¹** ⊗ **B⁻¹** (if invertible)\n- (**A** ⊗ **B**)(**C** ⊗ **D**) = (**AC**) ⊗ (**BD**) (mixed product property)\n- Eigenvalues of **A** ⊗ **B** are products of eigenvalues: {λᵢ(A) · μⱼ(B)}"},
  {"type":"code","language":"python","content":"import numpy as np\n\nA = np.array([[1, 2], [3, 4]])\nB = np.array([[0, 5], [6, 7]])\n\n# Kronecker product\nK = np.kron(A, B)   # (4, 4) since both are 2x2\nprint('A ⊗ B:\\n', K)\n# [[0,5,0,10],[6,7,12,14],[0,15,0,20],[18,21,24,28]]\n\n# Eigenvalue product property\nA_sym = A + A.T   # make symmetric for real eigenvalues\nB_sym = B + B.T\neig_A = np.sort(np.linalg.eigvalsh(A_sym))\neig_B = np.sort(np.linalg.eigvalsh(B_sym))\nK_sym = np.kron(A_sym, B_sym)\neig_K = np.sort(np.linalg.eigvalsh(K_sym))\n# Products of eigenvalues\nproducts = np.sort([a*b for a in eig_A for b in eig_B])\nprint('Eigs of K match products?', np.allclose(eig_K, products))"},
  {"type":"heading","level":2,"content":"The Vectorization Trick: vec(AXB) = (Bᵀ ⊗ A) vec(X)"},
  {"type":"text","content":"The most useful identity involving Kronecker products is the **vectorization identity**. The **vec** operator stacks the columns of a matrix into a single long vector: vec(**X**) ∈ ℝᵐⁿ for **X** ∈ ℝᵐˣⁿ.\n\nThe identity states:\n\n  vec(**AXB**) = (**Bᵀ** ⊗ **A**) vec(**X**)\n\nThis converts a matrix equation into a vector-matrix equation, enabling the use of standard linear algebra tools (least squares, eigensolvers) to solve problems involving matrix unknowns. It is the key step in deriving solutions to the Sylvester equation (**AX + XB = C**) and in analyzing Kronecker-factored approximations to the Fisher information matrix."},
  {"type":"code","language":"python","content":"import numpy as np\n\nm, n, p = 3, 4, 2\nA = np.random.randn(m, m)\nX = np.random.randn(m, n)\nB = np.random.randn(n, p)\n\n# Left side: vec(AXB)\nAXB = A @ X @ B          # (m, p)\nvec_AXB = AXB.flatten(order='F')  # column-major vec: stack columns\n\n# Right side: (B^T ⊗ A) vec(X)\nKronecker = np.kron(B.T, A)        # (m*p, m*n)\nvec_X = X.flatten(order='F')       # (m*n,)\nrhs = Kronecker @ vec_X            # (m*p,)\n\nprint('vec(AXB) == (B^T ⊗ A) vec(X)?', np.allclose(vec_AXB, rhs))  # True"},
  {"type":"heading","level":2,"content":"K-FAC: Kronecker-Factored Approximate Curvature"},
  {"type":"text","content":"**K-FAC** (Martens & Grosse, 2015) approximates the Fisher information matrix (FIM) — the exact natural gradient preconditioner — using Kronecker products. For a linear layer y = Wx, the FIM is:\n\n  F_W = E[a aᵀ ⊗ g gᵀ]\n\nwhere **a** is the layer's input and **g** is the gradient of the loss w.r.t. the pre-activation output. K-FAC approximates this as:\n\n  F̂_W = Â ⊗ Ĝ,  where Â = E[aaᵀ], Ĝ = E[ggᵀ]\n\nThis Kronecker factorization makes the preconditioner efficient: inverting F̂_W costs O(d³ + d³) instead of O(d⁶) for the full matrix. The update rule vec(ΔW) = -η F̂_W⁻¹ vec(g_W) becomes ΔW = -η Â⁻¹ G_W Ĝ⁻¹ (simple matrix operations)."},
  {"type":"code","language":"python","content":"import torch\n\nclass KFACLayer:\n    \"\"\"Simplified K-FAC state for one linear layer.\"\"\"\n    def __init__(self, in_dim, out_dim, decay=0.95):\n        self.A_bar = torch.zeros(in_dim, in_dim)   # input covariance\n        self.G_bar = torch.zeros(out_dim, out_dim)  # gradient covariance\n        self.decay = decay\n\n    def update_stats(self, a, g):\n        \"\"\"a: input to layer (batch, in_dim), g: grad of pre-act (batch, out_dim)\"\"\"\n        A = a.T @ a / a.shape[0]   # (in_dim, in_dim)\n        G = g.T @ g / g.shape[0]   # (out_dim, out_dim)\n        self.A_bar = self.decay * self.A_bar + (1-self.decay) * A\n        self.G_bar = self.decay * self.G_bar + (1-self.decay) * G\n\n    def preconditioned_grad(self, dW, damping=1e-3):\n        \"\"\"Apply K-FAC inverse to weight gradient.\"\"\"\n        # Invert A and G separately (much cheaper than full FIM inverse)\n        A_inv = torch.linalg.inv(self.A_bar + damping * torch.eye(self.A_bar.shape[0]))\n        G_inv = torch.linalg.inv(self.G_bar + damping * torch.eye(self.G_bar.shape[0]))\n        return G_inv @ dW @ A_inv  # ΔW = G⁻¹ ∇W A⁻¹"},
  {"type":"heading","level":2,"content":"Structured Matrices and Efficient Computation"},
  {"type":"text","content":"Kronecker products enable representing large structured matrices efficiently. A Kronecker product **A** ⊗ **B** (size mp×nq) requires only mn + pq parameters instead of mnpq. Applying it to a vector costs O(m·n·q + p·q·n) instead of O(mnpq).\n\nApplications:\n- **Separable filters** in image processing: 2D Gaussian blur = 1D horizontal ⊗ 1D vertical Gaussian\n- **Structured weight matrices**: Some architecture work replaces dense layers with Kronecker-structured layers for compression\n- **Multitask learning**: Kronecker priors over task × feature covariance matrices\n- **Neural ODE and Hamiltonian systems**: Kronecker structure arises in physics-informed models"},
  {"type":"callout","variant":"tip","title":"Hadamard vs Kronecker at a Glance","content":"Hadamard (⊙): same-shape elementwise multiply. Result shape = input shape. Used for gating and masking.\n\nKronecker (⊗): block-outer-product. If A is m×n and B is p×q, result is mp×nq. Used for structured linear maps and Fisher matrix approximations.\n\nKronecker can be computed as: np.kron(A, B). Hadamard is just: A * B (or torch.mul)."},
  {"type":"table","headers":["Product","Symbol","Shape Rule","Key Property","ML Application"],"rows":[["Hadamard","A ⊙ B","Same as inputs","Elementwise, commutative","Gating (LSTM/GRU), masking"],["Kronecker","A ⊗ B","(mp)×(nq) from m×n and p×q","Block structure, (B^T⊗A)vec(X)=vec(AXB)","K-FAC, separable filters"],["Standard","A @ B","(m,n)@(n,k)=(m,k)","Non-commutative","Linear layers, attention"],["Outer","u ⊗ v","(m,n) from (m,) and (n,)","Rank-1 update","Gradient of linear layers"]]}
]
"
---

# Kronecker and Hadamard Products

Matrix algebra has two important products beyond ordinary multiplication: the **Hadamard product** (elementwise) and the **Kronecker product** (block-structured). These products appear in gating mechanisms, structured convolutions, second-order optimization, and the vectorization of matrix equations. Understanding them reveals elegant structure in computations that would otherwise seem ad hoc.

## The Hadamard Product: Elementwise Multiplication

The **Hadamard product** (also called elementwise product, or Schur product) of two matrices of the same shape is defined entry-by-entry:

  (**A** ⊙ **B**)[i,j] = A[i,j] · B[i,j]

This is the default `*` operator in NumPy and PyTorch (when shapes are compatible). Unlike matrix multiplication, the Hadamard product is commutative (**A** ⊙ **B** = **B** ⊙ **A**), associative, and distributes over addition. It is the 'natural' pointwise operation when matrices represent pixel maps, attention masks, or feature-wise weights.

```python
import numpy as np, torch

A = np.array([[1, 2], [3, 4]])
B = np.array([[5, 6], [7, 8]])

# Hadamard product (elementwise)
C = A * B              # numpy: [[5,12],[21,32]]
print('A * B:\n', C)

# vs matrix multiplication
print('A @ B:\n', A @ B)   # [[19,22],[43,50]] -- very different!

# Properties
print('Commutative?', np.allclose(A*B, B*A))          # True
print('(A*B)*C == A*(B*C)?', np.allclose((A*B)*A, A*(B*A)))  # True

# Frobenius inner product via Hadamard
fro_ip = np.sum(A * B)   # = tr(A^T B)
print('Frobenius inner product:', fro_ip)   # = 5+12+21+32 = 70
```

## Hadamard Product in Neural Networks: Gating

Gating mechanisms use the Hadamard product to selectively pass or suppress information:

- **LSTM gates**: The forget gate computes h' = f ⊙ c (elementwise gate on cell state), where f ∈ [0,1] acts as a learned 'forget factor' for each dimension independently.
- **GRU update gate**: h = (1-z) ⊙ h_prev + z ⊙ h_candidate
- **Attention masking**: Multiply attention logits by a binary mask (0/1) before softmax to prevent attending to padding tokens
- **Feature-wise Linear Modulation (FiLM)**: y = γ(c) ⊙ x + β(c) for conditional generation, where γ and β are computed from conditioning variable c
- **Mixture of Experts gating**: o = Σᵢ gᵢ ⊙ Eᵢ(x) where g is a soft router

```python
import torch
import torch.nn as nn

# Simplified LSTM cell showing Hadamard gating
def lstm_cell(x, h_prev, c_prev, W_x, W_h, b):
    """x: (batch, input_size), h_prev, c_prev: (batch, hidden_size)"""
    gates = x @ W_x.T + h_prev @ W_h.T + b  # (batch, 4*hidden)
    hidden = gates.shape[-1] // 4
    i, f, g, o = gates.split(hidden, dim=-1)  # input, forget, cell, output
    i = torch.sigmoid(i)
    f = torch.sigmoid(f)
    g = torch.tanh(g)
    o = torch.sigmoid(o)
    # Hadamard product: elementwise gating of cell state
    c_new = f * c_prev + i * g   # forget old + input new
    h_new = o * torch.tanh(c_new)
    return h_new, c_new

# FiLM conditioning
class FiLM(nn.Module):
    def __init__(self, cond_dim, feat_dim):
        super().__init__()
        self.gamma = nn.Linear(cond_dim, feat_dim)
        self.beta  = nn.Linear(cond_dim, feat_dim)

    def forward(self, x, cond):
        return self.gamma(cond) * x + self.beta(cond)  # Hadamard scale+shift
```

## The Kronecker Product: Block Matrix Structure

The **Kronecker product** **A** ⊗ **B** of an m×n matrix **A** and a p×q matrix **B** is the mp×nq block matrix:

  **A** ⊗ **B** = [[a₁₁B, a₁₂B, ..., a₁ₙB], [a₂₁B, ..., a₂ₙB], ..., [aₘ₁B, ..., aₘₙB]]

Each entry of **A** is replaced by a scaled copy of **B**. Key properties:
- (**A** ⊗ **B**)ᵀ = **Aᵀ** ⊗ **Bᵀ**
- (**A** ⊗ **B**)⁻¹ = **A⁻¹** ⊗ **B⁻¹** (if invertible)
- (**A** ⊗ **B**)(**C** ⊗ **D**) = (**AC**) ⊗ (**BD**) (mixed product property)
- Eigenvalues of **A** ⊗ **B** are products of eigenvalues: {λᵢ(A) · μⱼ(B)}

```python
import numpy as np

A = np.array([[1, 2], [3, 4]])
B = np.array([[0, 5], [6, 7]])

# Kronecker product
K = np.kron(A, B)   # (4, 4) since both are 2x2
print('A ⊗ B:\n', K)
# [[0,5,0,10],[6,7,12,14],[0,15,0,20],[18,21,24,28]]

# Eigenvalue product property
A_sym = A + A.T   # make symmetric for real eigenvalues
B_sym = B + B.T
eig_A = np.sort(np.linalg.eigvalsh(A_sym))
eig_B = np.sort(np.linalg.eigvalsh(B_sym))
K_sym = np.kron(A_sym, B_sym)
eig_K = np.sort(np.linalg.eigvalsh(K_sym))
# Products of eigenvalues
products = np.sort([a*b for a in eig_A for b in eig_B])
print('Eigs of K match products?', np.allclose(eig_K, products))
```

## The Vectorization Trick: vec(AXB) = (Bᵀ ⊗ A) vec(X)

The most useful identity involving Kronecker products is the **vectorization identity**. The **vec** operator stacks the columns of a matrix into a single long vector: vec(**X**) ∈ ℝᵐⁿ for **X** ∈ ℝᵐˣⁿ.

The identity states:

  vec(**AXB**) = (**Bᵀ** ⊗ **A**) vec(**X**)

This converts a matrix equation into a vector-matrix equation, enabling the use of standard linear algebra tools (least squares, eigensolvers) to solve problems involving matrix unknowns. It is the key step in deriving solutions to the Sylvester equation (**AX + XB = C**) and in analyzing Kronecker-factored approximations to the Fisher information matrix.

```python
import numpy as np

m, n, p = 3, 4, 2
A = np.random.randn(m, m)
X = np.random.randn(m, n)
B = np.random.randn(n, p)

# Left side: vec(AXB)
AXB = A @ X @ B          # (m, p)
vec_AXB = AXB.flatten(order='F')  # column-major vec: stack columns

# Right side: (B^T ⊗ A) vec(X)
Kronecker = np.kron(B.T, A)        # (m*p, m*n)
vec_X = X.flatten(order='F')       # (m*n,)
rhs = Kronecker @ vec_X            # (m*p,)

print('vec(AXB) == (B^T ⊗ A) vec(X)?', np.allclose(vec_AXB, rhs))  # True
```

## K-FAC: Kronecker-Factored Approximate Curvature

**K-FAC** (Martens & Grosse, 2015) approximates the Fisher information matrix (FIM) — the exact natural gradient preconditioner — using Kronecker products. For a linear layer y = Wx, the FIM is:

  F_W = E[a aᵀ ⊗ g gᵀ]

where **a** is the layer's input and **g** is the gradient of the loss w.r.t. the pre-activation output. K-FAC approximates this as:

  F̂_W = Â ⊗ Ĝ,  where Â = E[aaᵀ], Ĝ = E[ggᵀ]

This Kronecker factorization makes the preconditioner efficient: inverting F̂_W costs O(d³ + d³) instead of O(d⁶) for the full matrix. The update rule vec(ΔW) = -η F̂_W⁻¹ vec(g_W) becomes ΔW = -η Â⁻¹ G_W Ĝ⁻¹ (simple matrix operations).

```python
import torch

class KFACLayer:
    """Simplified K-FAC state for one linear layer."""
    def __init__(self, in_dim, out_dim, decay=0.95):
        self.A_bar = torch.zeros(in_dim, in_dim)   # input covariance
        self.G_bar = torch.zeros(out_dim, out_dim)  # gradient covariance
        self.decay = decay

    def update_stats(self, a, g):
        """a: input to layer (batch, in_dim), g: grad of pre-act (batch, out_dim)"""
        A = a.T @ a / a.shape[0]   # (in_dim, in_dim)
        G = g.T @ g / g.shape[0]   # (out_dim, out_dim)
        self.A_bar = self.decay * self.A_bar + (1-self.decay) * A
        self.G_bar = self.decay * self.G_bar + (1-self.decay) * G

    def preconditioned_grad(self, dW, damping=1e-3):
        """Apply K-FAC inverse to weight gradient."""
        # Invert A and G separately (much cheaper than full FIM inverse)
        A_inv = torch.linalg.inv(self.A_bar + damping * torch.eye(self.A_bar.shape[0]))
        G_inv = torch.linalg.inv(self.G_bar + damping * torch.eye(self.G_bar.shape[0]))
        return G_inv @ dW @ A_inv  # ΔW = G⁻¹ ∇W A⁻¹
```

## Structured Matrices and Efficient Computation

Kronecker products enable representing large structured matrices efficiently. A Kronecker product **A** ⊗ **B** (size mp×nq) requires only mn + pq parameters instead of mnpq. Applying it to a vector costs O(m·n·q + p·q·n) instead of O(mnpq).

Applications:
- **Separable filters** in image processing: 2D Gaussian blur = 1D horizontal ⊗ 1D vertical Gaussian
- **Structured weight matrices**: Some architecture work replaces dense layers with Kronecker-structured layers for compression
- **Multitask learning**: Kronecker priors over task × feature covariance matrices
- **Neural ODE and Hamiltonian systems**: Kronecker structure arises in physics-informed models

> **[TIP] Hadamard vs Kronecker at a Glance**
>
> Hadamard (⊙): same-shape elementwise multiply. Result shape = input shape. Used for gating and masking.

Kronecker (⊗): block-outer-product. If A is m×n and B is p×q, result is mp×nq. Used for structured linear maps and Fisher matrix approximations.

Kronecker can be computed as: np.kron(A, B). Hadamard is just: A * B (or torch.mul).

| Product | Symbol | Shape Rule | Key Property | ML Application |
| --- | --- | --- | --- | --- |
| Hadamard | A ⊙ B | Same as inputs | Elementwise, commutative | Gating (LSTM/GRU), masking |
| Kronecker | A ⊗ B | (mp)×(nq) from m×n and p×q | Block structure, (B^T⊗A)vec(X)=vec(AXB) | K-FAC, separable filters |
| Standard | A @ B | (m,n)@(n,k)=(m,k) | Non-commutative | Linear layers, attention |
| Outer | u ⊗ v | (m,n) from (m,) and (n,) | Rank-1 update | Gradient of linear layers |
