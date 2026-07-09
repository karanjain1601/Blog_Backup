---
title: "Singular Value Decomposition (SVD)"
slug: "singular-value-decomposition"
description: "The full SVD formula, geometric interpretation, truncated SVD for low-rank approximation, pseudoinverse, and ML applications."
tags: ["linear-algebra", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[
  {"type":"text","content":"Singular Value Decomposition (SVD) is arguably the most important matrix factorization in applied mathematics. Unlike eigendecomposition (which requires square matrices), SVD works on any matrix of any shape and reveals the intrinsic geometric structure of the linear transformation it represents. SVD underpins PCA, recommender systems, natural language processing, compressed sensing, and numerical linear algebra solvers."},
  {"type":"heading","level":2,"content":"The SVD Formula: A = UΣVᵀ"},
  {"type":"text","content":"Every real matrix **A** (m×n) can be factored as:\n\n  **A = UΣVᵀ**\n\nwhere:\n- **U** is m×m orthogonal (**UᵀU = I**): left singular vectors (columns span column space of A)\n- **Σ** is m×n diagonal with non-negative entries σ₁ ≥ σ₂ ≥ ... ≥ σₘᵢₙ₍ₘ,ₙ₎ ≥ 0: the **singular values**\n- **V** is n×n orthogonal (**VᵀV = I**): right singular vectors (columns span row space of A)\n\nThe number of nonzero singular values equals the **rank** of **A**. The singular values are always real and non-negative, even when A is not square or not symmetric."},
  {"type":"code","language":"python","content":"import numpy as np\n\nA = np.array([[1, 2, 0],\n              [0, 3, 1],\n              [1, 1, 2]], dtype=float)\n\nU, sigma, Vt = np.linalg.svd(A)    # full SVD\nprint('U shape:', U.shape)          # (3,3)\nprint('sigma:', sigma)              # [4.11, 2.54, 0.76] (sorted desc)\nprint('Vt shape:', Vt.shape)        # (3,3)\n\n# Reconstruct A\nSigma = np.zeros_like(A)\nnp.fill_diagonal(Sigma, sigma)\nA_reconstructed = U @ Sigma @ Vt\nprint('Reconstruction error:', np.linalg.norm(A - A_reconstructed))  # ~1e-15\n\n# Rank\nrank = np.sum(sigma > 1e-10)\nprint('Rank:', rank)"},
  {"type":"heading","level":2,"content":"Geometric Interpretation: Rotation-Scale-Rotation"},
  {"type":"text","content":"The SVD **A = UΣVᵀ** decomposes the linear transformation into three stages, applied right-to-left:\n\n1. **Vᵀ**: Rotate/reflect the input space (orthogonal transformation — preserves lengths and angles)\n2. **Σ**: Scale along the coordinate axes by σ₁, σ₂, ..., σₖ (purely stretching/compressing)\n3. **U**: Rotate/reflect into the output space (another orthogonal transformation)\n\nThis means *every linear transformation is just rotations and scalings in disguise*. The singular values measure the stretching: the unit sphere in input space gets mapped to an ellipsoid in output space, where the semi-axis lengths are exactly the singular values, and the axis directions are the left/right singular vectors."},
  {"type":"heading","level":2,"content":"Relationship to Eigendecomposition"},
  {"type":"text","content":"SVD and eigendecomposition are intimately related. The right singular vectors (columns of **V**) are the eigenvectors of **AᵀA**, and the left singular vectors (columns of **U**) are the eigenvectors of **AAᵀ**:\n\n  **AᵀA = VΣᵀΣVᵀ** → eigendecomposition of AᵀA\n  **AAᵀ = UΣΣᵀUᵀ** → eigendecomposition of AAᵀ\n\nThe singular values satisfy σᵢ = √λᵢ where λᵢ are the eigenvalues of **AᵀA** (all non-negative for PSD matrices). For a square symmetric matrix **A**, the singular values are the absolute values of the eigenvalues. This is why SVD is preferred for general matrices: it avoids squaring the condition number (and thus losing numerical precision) that happens when computing AᵀA explicitly."},
  {"type":"heading","level":2,"content":"Truncated SVD for Low-Rank Approximation"},
  {"type":"text","content":"The **Eckart-Young-Mirsky theorem** states that the best rank-k approximation of **A** (in both Frobenius and spectral norms) is given by keeping only the top-k singular values:\n\n  **Aₖ = UₖΣₖVₖᵀ**\n\nwhere **Uₖ** uses only the first k columns of **U**, **Σₖ** is k×k diagonal, and **Vₖᵀ** uses the first k rows of **Vᵀ**. The approximation error is: ||A - Aₖ||_F² = σₖ₊₁² + ... + σᵣ². This is the mathematical foundation of:\n- PCA (project data onto top-k principal axes)\n- Recommender systems (approximate the user-item matrix)\n- Image compression (store k singular triplets instead of all pixels)\n- Latent Semantic Analysis (low-rank approximation of term-document matrix)"},
  {"type":"code","language":"python","content":"import numpy as np\n\n# Image compression via truncated SVD\nnp.random.seed(0)\nimg = np.random.randn(256, 256)  # simulate grayscale image\n\nU, sigma, Vt = np.linalg.svd(img, full_matrices=False)  # economy SVD\n\nfor k in [5, 20, 50]:\n    img_k = U[:, :k] @ np.diag(sigma[:k]) @ Vt[:k, :]\n    error = np.linalg.norm(img - img_k, 'fro') / np.linalg.norm(img, 'fro')\n    compression = k * (256 + 1 + 256) / (256 * 256)\n    print(f'k={k:3d}: error={error:.3f}, size={compression:.1%} of original')\n\n# Explained variance\nvar_explained = np.cumsum(sigma**2) / np.sum(sigma**2)\nprint(f'Top-5 explains {var_explained[4]:.1%} of Frobenius norm squared')"},
  {"type":"heading","level":2,"content":"The Pseudoinverse (Moore-Penrose Inverse)"},
  {"type":"text","content":"For non-square or rank-deficient matrices that lack a true inverse, the **Moore-Penrose pseudoinverse** **A⁺** is the generalization that satisfies the least-squares solution. Given **A = UΣVᵀ**, the pseudoinverse is:\n\n  **A⁺ = VΣ⁺Uᵀ**\n\nwhere **Σ⁺** replaces each nonzero singular value σᵢ with 1/σᵢ (and leaves zeros as zeros). The least-squares solution to **Ax ≈ b** is **x* = A⁺b**, which minimizes ||Ax - b||₂. When the system is underdetermined (infinitely many solutions), **A⁺b** gives the minimum-norm solution. This is why SVD is the workhorse behind `numpy.linalg.lstsq`."},
  {"type":"code","language":"python","content":"import numpy as np\n\n# Solve overdetermined system Ax = b via pseudoinverse\nnp.random.seed(1)\nA = np.random.randn(10, 3)   # 10 equations, 3 unknowns\nb = np.random.randn(10)\n\n# Via SVD (pseudoinverse)\nU, s, Vt = np.linalg.svd(A, full_matrices=False)\ns_inv = 1.0 / s              # reciprocal singular values\nx_svd = Vt.T @ (np.diag(s_inv) @ (U.T @ b))\n\n# Via numpy lstsq (also SVD-based internally)\nx_lstsq, _, _, _ = np.linalg.lstsq(A, b, rcond=None)\n\nprint('||Ax - b|| via SVD:', np.linalg.norm(A @ x_svd - b))\nprint('||Ax - b|| via lstsq:', np.linalg.norm(A @ x_lstsq - b))\nprint('Solutions match:', np.allclose(x_svd, x_lstsq))"},
  {"type":"heading","level":2,"content":"SVD in Recommender Systems"},
  {"type":"text","content":"A user-item rating matrix **R** (m users × n items) is typically very sparse (most users have rated few items). **Matrix factorization** approximates **R ≈ UVᵀ** where **U** (m×k) represents users and **V** (n×k) represents items in a k-dimensional latent space. Each latent dimension captures a concept (genre, style, theme).\n\nThe classic **Simon Funk SVD** (used in the Netflix Prize) solves this via stochastic gradient descent on observed entries only, learning user/item embeddings that predict ratings for unobserved pairs. This is **collaborative filtering**: similar users (close in U) tend to like similar items (close in V), enabling personalized recommendations without item content."},
  {"type":"heading","level":2,"content":"Latent Semantic Analysis and Word Embeddings"},
  {"type":"text","content":"**Latent Semantic Analysis (LSA)** applies truncated SVD to a term-document matrix **M** where M[i,j] = TF-IDF weight of term i in document j. The low-rank approximation **Mₖ = UₖΣₖVₖᵀ** maps both terms and documents into a shared k-dimensional semantic space.\n\nWords used in similar contexts end up close in this space, capturing semantic similarity even when exact word matches fail (synonymy and polysemy handling). LSA predates neural word embeddings (word2vec, GloVe) but motivated the same core insight: semantic meaning can be captured by low-rank structure in co-occurrence statistics."},
  {"type":"callout","variant":"warning","title":"Economy vs Full SVD — Memory Implications","content":"numpy.linalg.svd(A) by default computes the full SVD, returning U as (m,m) even for a (m,n) matrix with m >> n. For A with shape (10000, 100), the full U is 10000×10000 = 800MB. Use full_matrices=False (economy/thin SVD) to get U as (m, min(m,n)) = (10000, 100) — a 100× memory reduction. Similarly, scipy.sparse.linalg.svds computes only the top-k singular triplets and is essential for very large sparse matrices."},
  {"type":"table","headers":["Application","Matrix","Low-Rank Meaning"],"rows":[["Image compression","Pixel matrix","Top-k visual patterns (edges, textures)"],["PCA","Data matrix X","Top variance directions"],["Recommender systems","User × Item ratings","Latent taste/style factors"],["NLP (LSA)","Term × Document TF-IDF","Latent semantic topics"],["Neural net compression","Weight matrix W","Remove low-variance transformation directions"],["Data whitening","Covariance matrix C","Normalize and decorrelate features"]]},
  {"type":"callout","variant":"tip","title":"Numerical Rank via Singular Values","content":"To determine the numerical rank of a matrix (how many singular values are 'effectively nonzero'), use: rank = np.sum(sigma > threshold * sigma[0] * max(m,n) * eps) where eps = np.finfo(float).eps (~2.2e-16). This is exactly what numpy.linalg.matrix_rank uses internally. Never compute rank via determinant (numerically unstable) or row reduction without pivoting."}
]
"
---

# Singular Value Decomposition (SVD)

Singular Value Decomposition (SVD) is arguably the most important matrix factorization in applied mathematics. Unlike eigendecomposition (which requires square matrices), SVD works on any matrix of any shape and reveals the intrinsic geometric structure of the linear transformation it represents. SVD underpins PCA, recommender systems, natural language processing, compressed sensing, and numerical linear algebra solvers.

## The SVD Formula: A = UΣVᵀ

Every real matrix **A** (m×n) can be factored as:

  **A = UΣVᵀ**

where:
- **U** is m×m orthogonal (**UᵀU = I**): left singular vectors (columns span column space of A)
- **Σ** is m×n diagonal with non-negative entries σ₁ ≥ σ₂ ≥ ... ≥ σₘᵢₙ₍ₘ,ₙ₎ ≥ 0: the **singular values**
- **V** is n×n orthogonal (**VᵀV = I**): right singular vectors (columns span row space of A)

The number of nonzero singular values equals the **rank** of **A**. The singular values are always real and non-negative, even when A is not square or not symmetric.

```python
import numpy as np

A = np.array([[1, 2, 0],
              [0, 3, 1],
              [1, 1, 2]], dtype=float)

U, sigma, Vt = np.linalg.svd(A)    # full SVD
print('U shape:', U.shape)          # (3,3)
print('sigma:', sigma)              # [4.11, 2.54, 0.76] (sorted desc)
print('Vt shape:', Vt.shape)        # (3,3)

# Reconstruct A
Sigma = np.zeros_like(A)
np.fill_diagonal(Sigma, sigma)
A_reconstructed = U @ Sigma @ Vt
print('Reconstruction error:', np.linalg.norm(A - A_reconstructed))  # ~1e-15

# Rank
rank = np.sum(sigma > 1e-10)
print('Rank:', rank)
```

## Geometric Interpretation: Rotation-Scale-Rotation

The SVD **A = UΣVᵀ** decomposes the linear transformation into three stages, applied right-to-left:

1. **Vᵀ**: Rotate/reflect the input space (orthogonal transformation — preserves lengths and angles)
2. **Σ**: Scale along the coordinate axes by σ₁, σ₂, ..., σₖ (purely stretching/compressing)
3. **U**: Rotate/reflect into the output space (another orthogonal transformation)

This means *every linear transformation is just rotations and scalings in disguise*. The singular values measure the stretching: the unit sphere in input space gets mapped to an ellipsoid in output space, where the semi-axis lengths are exactly the singular values, and the axis directions are the left/right singular vectors.

## Relationship to Eigendecomposition

SVD and eigendecomposition are intimately related. The right singular vectors (columns of **V**) are the eigenvectors of **AᵀA**, and the left singular vectors (columns of **U**) are the eigenvectors of **AAᵀ**:

  **AᵀA = VΣᵀΣVᵀ** → eigendecomposition of AᵀA
  **AAᵀ = UΣΣᵀUᵀ** → eigendecomposition of AAᵀ

The singular values satisfy σᵢ = √λᵢ where λᵢ are the eigenvalues of **AᵀA** (all non-negative for PSD matrices). For a square symmetric matrix **A**, the singular values are the absolute values of the eigenvalues. This is why SVD is preferred for general matrices: it avoids squaring the condition number (and thus losing numerical precision) that happens when computing AᵀA explicitly.

## Truncated SVD for Low-Rank Approximation

The **Eckart-Young-Mirsky theorem** states that the best rank-k approximation of **A** (in both Frobenius and spectral norms) is given by keeping only the top-k singular values:

  **Aₖ = UₖΣₖVₖᵀ**

where **Uₖ** uses only the first k columns of **U**, **Σₖ** is k×k diagonal, and **Vₖᵀ** uses the first k rows of **Vᵀ**. The approximation error is: ||A - Aₖ||_F² = σₖ₊₁² + ... + σᵣ². This is the mathematical foundation of:
- PCA (project data onto top-k principal axes)
- Recommender systems (approximate the user-item matrix)
- Image compression (store k singular triplets instead of all pixels)
- Latent Semantic Analysis (low-rank approximation of term-document matrix)

```python
import numpy as np

# Image compression via truncated SVD
np.random.seed(0)
img = np.random.randn(256, 256)  # simulate grayscale image

U, sigma, Vt = np.linalg.svd(img, full_matrices=False)  # economy SVD

for k in [5, 20, 50]:
    img_k = U[:, :k] @ np.diag(sigma[:k]) @ Vt[:k, :]
    error = np.linalg.norm(img - img_k, 'fro') / np.linalg.norm(img, 'fro')
    compression = k * (256 + 1 + 256) / (256 * 256)
    print(f'k={k:3d}: error={error:.3f}, size={compression:.1%} of original')

# Explained variance
var_explained = np.cumsum(sigma**2) / np.sum(sigma**2)
print(f'Top-5 explains {var_explained[4]:.1%} of Frobenius norm squared')
```

## The Pseudoinverse (Moore-Penrose Inverse)

For non-square or rank-deficient matrices that lack a true inverse, the **Moore-Penrose pseudoinverse** **A⁺** is the generalization that satisfies the least-squares solution. Given **A = UΣVᵀ**, the pseudoinverse is:

  **A⁺ = VΣ⁺Uᵀ**

where **Σ⁺** replaces each nonzero singular value σᵢ with 1/σᵢ (and leaves zeros as zeros). The least-squares solution to **Ax ≈ b** is **x* = A⁺b**, which minimizes ||Ax - b||₂. When the system is underdetermined (infinitely many solutions), **A⁺b** gives the minimum-norm solution. This is why SVD is the workhorse behind `numpy.linalg.lstsq`.

```python
import numpy as np

# Solve overdetermined system Ax = b via pseudoinverse
np.random.seed(1)
A = np.random.randn(10, 3)   # 10 equations, 3 unknowns
b = np.random.randn(10)

# Via SVD (pseudoinverse)
U, s, Vt = np.linalg.svd(A, full_matrices=False)
s_inv = 1.0 / s              # reciprocal singular values
x_svd = Vt.T @ (np.diag(s_inv) @ (U.T @ b))

# Via numpy lstsq (also SVD-based internally)
x_lstsq, _, _, _ = np.linalg.lstsq(A, b, rcond=None)

print('||Ax - b|| via SVD:', np.linalg.norm(A @ x_svd - b))
print('||Ax - b|| via lstsq:', np.linalg.norm(A @ x_lstsq - b))
print('Solutions match:', np.allclose(x_svd, x_lstsq))
```

## SVD in Recommender Systems

A user-item rating matrix **R** (m users × n items) is typically very sparse (most users have rated few items). **Matrix factorization** approximates **R ≈ UVᵀ** where **U** (m×k) represents users and **V** (n×k) represents items in a k-dimensional latent space. Each latent dimension captures a concept (genre, style, theme).

The classic **Simon Funk SVD** (used in the Netflix Prize) solves this via stochastic gradient descent on observed entries only, learning user/item embeddings that predict ratings for unobserved pairs. This is **collaborative filtering**: similar users (close in U) tend to like similar items (close in V), enabling personalized recommendations without item content.

## Latent Semantic Analysis and Word Embeddings

**Latent Semantic Analysis (LSA)** applies truncated SVD to a term-document matrix **M** where M[i,j] = TF-IDF weight of term i in document j. The low-rank approximation **Mₖ = UₖΣₖVₖᵀ** maps both terms and documents into a shared k-dimensional semantic space.

Words used in similar contexts end up close in this space, capturing semantic similarity even when exact word matches fail (synonymy and polysemy handling). LSA predates neural word embeddings (word2vec, GloVe) but motivated the same core insight: semantic meaning can be captured by low-rank structure in co-occurrence statistics.

> **[WARNING] Economy vs Full SVD — Memory Implications**
>
> numpy.linalg.svd(A) by default computes the full SVD, returning U as (m,m) even for a (m,n) matrix with m >> n. For A with shape (10000, 100), the full U is 10000×10000 = 800MB. Use full_matrices=False (economy/thin SVD) to get U as (m, min(m,n)) = (10000, 100) — a 100× memory reduction. Similarly, scipy.sparse.linalg.svds computes only the top-k singular triplets and is essential for very large sparse matrices.

| Application | Matrix | Low-Rank Meaning |
| --- | --- | --- |
| Image compression | Pixel matrix | Top-k visual patterns (edges, textures) |
| PCA | Data matrix X | Top variance directions |
| Recommender systems | User × Item ratings | Latent taste/style factors |
| NLP (LSA) | Term × Document TF-IDF | Latent semantic topics |
| Neural net compression | Weight matrix W | Remove low-variance transformation directions |
| Data whitening | Covariance matrix C | Normalize and decorrelate features |

> **[TIP] Numerical Rank via Singular Values**
>
> To determine the numerical rank of a matrix (how many singular values are 'effectively nonzero'), use: rank = np.sum(sigma > threshold * sigma[0] * max(m,n) * eps) where eps = np.finfo(float).eps (~2.2e-16). This is exactly what numpy.linalg.matrix_rank uses internally. Never compute rank via determinant (numerically unstable) or row reduction without pivoting.
