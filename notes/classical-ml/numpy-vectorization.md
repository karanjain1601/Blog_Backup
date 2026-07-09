---
title: "NumPy — Broadcasting, Vectorization, and Advanced Indexing"
slug: "numpy-vectorization"
description: "NumPy's core patterns for high-performance array computing: broadcasting rules, replacing Python loops with vectorized operations, fancy and boolean indexing, and einsum for tensor contractions."
tags: ["pytorch", "tools", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"NumPy is the foundation of scientific Python computing. Its performance advantage over pure Python comes from three mechanisms: vectorized operations (C-compiled kernels over entire arrays), broadcasting (implicit shape alignment without copying), and advanced indexing (fancy and boolean masks). Mastering these replaces slow Python loops with fast, readable array expressions."},{"type":"list","ordered":false,"items":["Vectorized ops: C-compiled, no Python loop overhead — 10–1000x faster than for loops for numerical work","Broadcasting: implicit shape alignment without data copying — shapes expanded logically, not physically","Fancy indexing: select arbitrary elements with integer arrays — always returns a copy (safe to modify)","Boolean indexing: mask arrays with boolean conditions — use np.where for conditional assignment","einsum: Einstein notation for arbitrary tensor contractions — clearer and often faster than chained dots"]},{"type":"heading","level":2,"content":"Vectorization: Replacing Python Loops"},{"type":"text","content":"Python loops over array elements are slow because each iteration incurs Python interpreter overhead. NumPy operations execute in C over contiguous memory blocks — 10 to 1000x faster for numerical computations."},{"type":"code","language":"python","content":"import numpy as np\nimport time\n\n# Benchmark: compute pairwise squared distances\n# Python loop version\ndef pairwise_dist_python(X):\n    n = len(X)\n    D = np.zeros((n, n))\n    for i in range(n):\n        for j in range(n):\n            diff = X[i] - X[j]\n            D[i, j] = np.dot(diff, diff)\n    return D\n\n# Vectorized version using broadcasting\ndef pairwise_dist_numpy(X):\n    # ||x_i - x_j||^2 = ||x_i||^2 + ||x_j||^2 - 2 x_i·x_j\n    sq_norms = (X ** 2).sum(axis=1)       # (n,)\n    D = sq_norms[:, None] + sq_norms[None, :] - 2 * X @ X.T\n    return np.maximum(D, 0)               # clip numerical negatives\n\nrng = np.random.default_rng(42)\nX   = rng.standard_normal((200, 32))\n\nt0 = time.perf_counter()\nD_py = pairwise_dist_python(X)\npy_t = time.perf_counter() - t0\n\nt0 = time.perf_counter()\nD_np = pairwise_dist_numpy(X)\nnp_t = time.perf_counter() - t0\n\nprint(f\u0027Python loop: {py_t*1000:.1f} ms\u0027)\nprint(f\u0027NumPy vec:   {np_t*1000:.2f} ms\u0027)\nprint(f\u0027Speedup:     {py_t/np_t:.0f}x\u0027)\nprint(f\u0027Results match: {np.allclose(D_py, D_np, atol=1e-8)}\u0027)"},{"type":"heading","level":2,"content":"Broadcasting Rules"},{"type":"text","content":"Broadcasting allows operations between arrays of different shapes without explicit copying. The rules are applied to trailing dimensions: arrays are compatible if corresponding dimensions are equal or one of them is 1."},{"type":"list","ordered":false,"items":["Step 1: Prepend 1s to the shorter shape until both have the same number of dimensions","Step 2: Output shape = max of each pair of dimensions (error if neither is 1 and they differ)","Example: (3, 1, 5) + (4, 1) → (3, 1, 5) + (1, 4, 1) → output (3, 4, 5)","No data is copied — broadcasting is a virtual replication applied during computation","Common use: subtract row mean (X - X.mean(axis=1, keepdims=True)) — keepdims preserves broadcastable shape"]},{"type":"code","language":"python","content":"import numpy as np\n\nrng = np.random.default_rng(0)\nX   = rng.integers(0, 10, (4, 3))   # (4, 3) matrix\nprint(\u0027X shape:\u0027, X.shape)\n\n# Subtract column mean (broadcast over rows)\ncol_mean = X.mean(axis=0)            # (3,)\nX_centered = X - col_mean            # (4, 3) - (3,) -\u003e broadcasts to (4, 3)\nprint(\u0027Column-centered shape:\u0027, X_centered.shape)\n\n# Subtract row mean\nrow_mean = X.mean(axis=1, keepdims=True)  # (4, 1) — keepdims preserves rank\nX_row_centered = X - row_mean             # (4, 3) - (4, 1) -\u003e broadcasts to (4, 3)\nprint(\u0027Row-centered shape:\u0027, X_row_centered.shape)\n\n# Outer product via broadcasting\na = np.array([1, 2, 3])   # (3,)\nb = np.array([10, 20])    # (2,)\nouter = a[:, None] * b[None, :]  # (3, 1) * (1, 2) -\u003e (3, 2)\nprint(\u0027Outer product:\u0027, outer)\n\n# Pairwise differences between two sets of points\nA = rng.standard_normal((5, 4))  # 5 points in R^4\nB = rng.standard_normal((3, 4))  # 3 points in R^4\ndiff = A[:, None, :] - B[None, :, :]  # (5, 1, 4) - (1, 3, 4) -\u003e (5, 3, 4)\nprint(\u0027Pairwise diff shape:\u0027, diff.shape)"},{"type":"heading","level":2,"content":"Advanced Indexing: Fancy and Boolean"},{"type":"text","content":"Advanced indexing selects arbitrary subsets of an array by providing integer arrays (fancy indexing — gather operation) or boolean masks. Advanced indexing always returns a copy, unlike basic slicing which returns a view."},{"type":"code","language":"python","content":"import numpy as np\n\nrng = np.random.default_rng(42)\nX   = rng.integers(0, 100, (8, 5))\nprint(\u0027X shape:\u0027, X.shape)\n\n# Fancy indexing: select specific rows by index array\nrow_indices = np.array([0, 3, 7, 2])\nselected = X[row_indices]    # (4, 5) — copies rows 0, 3, 7, 2\nprint(\u0027Fancy indexed shape:\u0027, selected.shape)\n\n# Boolean indexing (mask)\nmask = X[:, 0] \u003e 50          # (8,) boolean mask on first column\nX_filtered = X[mask]         # rows where first column \u003e 50\nprint(f\u0027Boolean filtered: {X_filtered.shape[0]} rows kept\u0027)\n\n# Combined: fancy row + column indexing (gather)\nrows = np.array([0, 1, 2, 3])\ncols = np.array([4, 3, 2, 1])  # one col per row\ndiag_like = X[rows, cols]      # (4,) — element (0,4), (1,3), (2,2), (3,1)\nprint(\u0027Scatter gather result:\u0027, diag_like)\n\n# Scatter: place values at specific indices\nout = np.zeros((10, 5), dtype=int)\nout[row_indices] = selected    # scatter rows back\nprint(\u0027Scatter output shape:\u0027, out.shape)\n\n# Advanced index is a COPY — modifying does not affect original\nX_filtered[0, 0] = 999\nprint(f\u0027Original X[0,0] unchanged: {X[0,0] != 999}\u0027)"},{"type":"heading","level":2,"content":"einsum for Tensor Contractions"},{"type":"text","content":"np.einsum (Einstein summation notation) expresses arbitrary tensor operations in a concise string syntax. It replaces nested dot products, transpositions, and trace operations with a single readable expression, and can be compiled to optimized BLAS calls."},{"type":"code","language":"python","content":"import numpy as np\n\nrng  = np.random.default_rng(0)\nA    = rng.standard_normal((3, 4))\nB    = rng.standard_normal((4, 5))\nC    = rng.standard_normal((3, 4, 5))\nD    = rng.standard_normal((3, 4))\n\n# Matrix multiply: ij,jk -\u003e ik\nAB   = np.einsum(\u0027ij,jk-\u003eik\u0027, A, B)\nassert AB.shape == (3, 5)\nassert np.allclose(AB, A @ B)\nprint(f\u0027matmul:        {AB.shape}\u0027)\n\n# Outer product: i,j -\u003e ij\na, b = np.array([1., 2., 3.]), np.array([10., 20., 30., 40.])\nouter = np.einsum(\u0027i,j-\u003eij\u0027, a, b)\nassert np.allclose(outer, np.outer(a, b))\nprint(f\u0027outer product: {outer.shape}\u0027)\n\n# Trace: ii -\u003e (scalar)\nsq = rng.standard_normal((5, 5))\ntrace = np.einsum(\u0027ii-\u003e\u0027, sq)\nassert np.isclose(trace, np.trace(sq))\nprint(f\u0027trace:         {trace:.4f}\u0027)\n\n# Batch matrix multiply: bij,bjk -\u003e bik\nbatch_A = rng.standard_normal((8, 3, 4))\nbatch_B = rng.standard_normal((8, 4, 5))\nbatch_AB = np.einsum(\u0027bij,bjk-\u003ebik\u0027, batch_A, batch_B)\nassert batch_AB.shape == (8, 3, 5)\nprint(f\u0027batch matmul:  {batch_AB.shape}\u0027)\n\n# Attention scores: bhqd,bhkd -\u003e bhqk\nQ = rng.standard_normal((2, 4, 10, 64))  # batch, heads, queries, d\nK = rng.standard_normal((2, 4, 12, 64))  # batch, heads, keys, d\nscores = np.einsum(\u0027bhqd,bhkd-\u003ebhqk\u0027, Q, K)\nprint(f\u0027attention:     {scores.shape}\u0027)  # (2, 4, 10, 12)"},{"type":"divider"},{"type":"heading","level":2,"content":"einsum Pattern Reference"},{"type":"table","headers":["Operation","einsum Notation","Equivalent NumPy Call","Use Case"],"rows":[["Matrix multiply","ij,jk-\u003eik","A @ B","Linear layers, attention"],["Outer product","i,j-\u003eij","np.outer(a, b)","Rank-1 update, embedding outer"],["Trace","ii-\u003e","np.trace(A)","Regularization terms"],["Batch matmul","bij,bjk-\u003ebik","np.matmul(A, B)","Batched linear transforms"],["Attention scores","bhqd,bhkd-\u003ebhqk","(Q @ K.T) per head","Multi-head self-attention"],["Element sum over axis","ij-\u003ei","A.sum(axis=1)","Row reduction"]]},{"type":"text","content":"For performance-critical paths, benchmark np.einsum against manual @ chains. On small arrays, einsum overhead can dominate; on large tensors (\u003e1000 elements per dimension), einsum often matches or beats manual implementations because NumPy selects optimal BLAS routines internally."},{"type":"callout","variant":"tip","title":"einsum Optimization with optimize=True","content":"For einsum expressions involving three or more tensors, use np.einsum(\u0027...\u0027, A, B, C, optimize=True). NumPy finds the optimal contraction order — which can reduce complexity from O(n^6) to O(n^4) for a three-tensor contraction. Always benchmark against manual @ chains for performance-critical paths."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"list","ordered":false,"items":["Vectorization replaces Python loops with C-compiled array operations — 10-1000x speedup","Broadcasting: align trailing dims, prepend 1s to shorter shape, expand dims with size 1 — no data copy","Fancy indexing returns a copy; basic slicing returns a view — modifying a fancy index result is safe","einsum expresses arbitrary tensor contractions in Einstein notation — clearer than nested transposes and dots","Use optimize=True in einsum for multi-tensor contractions and np.einsum_path for profiling the contraction order"]}]"
---
# NumPy — Broadcasting, Vectorization, and Advanced Indexing

NumPy is the foundation of scientific Python computing. Its performance advantage over pure Python comes from three mechanisms: vectorized operations (C-compiled kernels over entire arrays), broadcasting (implicit shape alignment without copying), and advanced indexing (fancy and boolean masks). Mastering these replaces slow Python loops with fast, readable array expressions.

- Vectorized ops: C-compiled, no Python loop overhead — 10–1000x faster than for loops for numerical work
- Broadcasting: implicit shape alignment without data copying — shapes expanded logically, not physically
- Fancy indexing: select arbitrary elements with integer arrays — always returns a copy (safe to modify)
- Boolean indexing: mask arrays with boolean conditions — use np.where for conditional assignment
- einsum: Einstein notation for arbitrary tensor contractions — clearer and often faster than chained dots

## Vectorization: Replacing Python Loops

Python loops over array elements are slow because each iteration incurs Python interpreter overhead. NumPy operations execute in C over contiguous memory blocks — 10 to 1000x faster for numerical computations.

```python
import numpy as np
import time

# Benchmark: compute pairwise squared distances
# Python loop version
def pairwise_dist_python(X):
    n = len(X)
    D = np.zeros((n, n))
    for i in range(n):
        for j in range(n):
            diff = X[i] - X[j]
            D[i, j] = np.dot(diff, diff)
    return D

# Vectorized version using broadcasting
def pairwise_dist_numpy(X):
    # ||x_i - x_j||^2 = ||x_i||^2 + ||x_j||^2 - 2 x_i·x_j
    sq_norms = (X ** 2).sum(axis=1)       # (n,)
    D = sq_norms[:, None] + sq_norms[None, :] - 2 * X @ X.T
    return np.maximum(D, 0)               # clip numerical negatives

rng = np.random.default_rng(42)
X   = rng.standard_normal((200, 32))

t0 = time.perf_counter()
D_py = pairwise_dist_python(X)
py_t = time.perf_counter() - t0

t0 = time.perf_counter()
D_np = pairwise_dist_numpy(X)
np_t = time.perf_counter() - t0

print(f'Python loop: {py_t*1000:.1f} ms')
print(f'NumPy vec:   {np_t*1000:.2f} ms')
print(f'Speedup:     {py_t/np_t:.0f}x')
print(f'Results match: {np.allclose(D_py, D_np, atol=1e-8)}')
```

## Broadcasting Rules

Broadcasting allows operations between arrays of different shapes without explicit copying. The rules are applied to trailing dimensions: arrays are compatible if corresponding dimensions are equal or one of them is 1.

- Step 1: Prepend 1s to the shorter shape until both have the same number of dimensions
- Step 2: Output shape = max of each pair of dimensions (error if neither is 1 and they differ)
- Example: (3, 1, 5) + (4, 1) → (3, 1, 5) + (1, 4, 1) → output (3, 4, 5)
- No data is copied — broadcasting is a virtual replication applied during computation
- Common use: subtract row mean (X - X.mean(axis=1, keepdims=True)) — keepdims preserves broadcastable shape

```python
import numpy as np

rng = np.random.default_rng(0)
X   = rng.integers(0, 10, (4, 3))   # (4, 3) matrix
print('X shape:', X.shape)

# Subtract column mean (broadcast over rows)
col_mean = X.mean(axis=0)            # (3,)
X_centered = X - col_mean            # (4, 3) - (3,) -> broadcasts to (4, 3)
print('Column-centered shape:', X_centered.shape)

# Subtract row mean
row_mean = X.mean(axis=1, keepdims=True)  # (4, 1) — keepdims preserves rank
X_row_centered = X - row_mean             # (4, 3) - (4, 1) -> broadcasts to (4, 3)
print('Row-centered shape:', X_row_centered.shape)

# Outer product via broadcasting
a = np.array([1, 2, 3])   # (3,)
b = np.array([10, 20])    # (2,)
outer = a[:, None] * b[None, :]  # (3, 1) * (1, 2) -> (3, 2)
print('Outer product:', outer)

# Pairwise differences between two sets of points
A = rng.standard_normal((5, 4))  # 5 points in R^4
B = rng.standard_normal((3, 4))  # 3 points in R^4
diff = A[:, None, :] - B[None, :, :]  # (5, 1, 4) - (1, 3, 4) -> (5, 3, 4)
print('Pairwise diff shape:', diff.shape)
```

## Advanced Indexing: Fancy and Boolean

Advanced indexing selects arbitrary subsets of an array by providing integer arrays (fancy indexing — gather operation) or boolean masks. Advanced indexing always returns a copy, unlike basic slicing which returns a view.

```python
import numpy as np

rng = np.random.default_rng(42)
X   = rng.integers(0, 100, (8, 5))
print('X shape:', X.shape)

# Fancy indexing: select specific rows by index array
row_indices = np.array([0, 3, 7, 2])
selected = X[row_indices]    # (4, 5) — copies rows 0, 3, 7, 2
print('Fancy indexed shape:', selected.shape)

# Boolean indexing (mask)
mask = X[:, 0] > 50          # (8,) boolean mask on first column
X_filtered = X[mask]         # rows where first column > 50
print(f'Boolean filtered: {X_filtered.shape[0]} rows kept')

# Combined: fancy row + column indexing (gather)
rows = np.array([0, 1, 2, 3])
cols = np.array([4, 3, 2, 1])  # one col per row
diag_like = X[rows, cols]      # (4,) — element (0,4), (1,3), (2,2), (3,1)
print('Scatter gather result:', diag_like)

# Scatter: place values at specific indices
out = np.zeros((10, 5), dtype=int)
out[row_indices] = selected    # scatter rows back
print('Scatter output shape:', out.shape)

# Advanced index is a COPY — modifying does not affect original
X_filtered[0, 0] = 999
print(f'Original X[0,0] unchanged: {X[0,0] != 999}')
```

## einsum for Tensor Contractions

np.einsum (Einstein summation notation) expresses arbitrary tensor operations in a concise string syntax. It replaces nested dot products, transpositions, and trace operations with a single readable expression, and can be compiled to optimized BLAS calls.

```python
import numpy as np

rng  = np.random.default_rng(0)
A    = rng.standard_normal((3, 4))
B    = rng.standard_normal((4, 5))
C    = rng.standard_normal((3, 4, 5))
D    = rng.standard_normal((3, 4))

# Matrix multiply: ij,jk -> ik
AB   = np.einsum('ij,jk->ik', A, B)
assert AB.shape == (3, 5)
assert np.allclose(AB, A @ B)
print(f'matmul:        {AB.shape}')

# Outer product: i,j -> ij
a, b = np.array([1., 2., 3.]), np.array([10., 20., 30., 40.])
outer = np.einsum('i,j->ij', a, b)
assert np.allclose(outer, np.outer(a, b))
print(f'outer product: {outer.shape}')

# Trace: ii -> (scalar)
sq = rng.standard_normal((5, 5))
trace = np.einsum('ii->', sq)
assert np.isclose(trace, np.trace(sq))
print(f'trace:         {trace:.4f}')

# Batch matrix multiply: bij,bjk -> bik
batch_A = rng.standard_normal((8, 3, 4))
batch_B = rng.standard_normal((8, 4, 5))
batch_AB = np.einsum('bij,bjk->bik', batch_A, batch_B)
assert batch_AB.shape == (8, 3, 5)
print(f'batch matmul:  {batch_AB.shape}')

# Attention scores: bhqd,bhkd -> bhqk
Q = rng.standard_normal((2, 4, 10, 64))  # batch, heads, queries, d
K = rng.standard_normal((2, 4, 12, 64))  # batch, heads, keys, d
scores = np.einsum('bhqd,bhkd->bhqk', Q, K)
print(f'attention:     {scores.shape}')  # (2, 4, 10, 12)
```

---

## einsum Pattern Reference

| Operation | einsum Notation | Equivalent NumPy Call | Use Case |
| --- | --- | --- | --- |
| Matrix multiply | ij,jk->ik | A @ B | Linear layers, attention |
| Outer product | i,j->ij | np.outer(a, b) | Rank-1 update, embedding outer |
| Trace | ii-> | np.trace(A) | Regularization terms |
| Batch matmul | bij,bjk->bik | np.matmul(A, B) | Batched linear transforms |
| Attention scores | bhqd,bhkd->bhqk | (Q @ K.T) per head | Multi-head self-attention |
| Element sum over axis | ij->i | A.sum(axis=1) | Row reduction |

For performance-critical paths, benchmark np.einsum against manual @ chains. On small arrays, einsum overhead can dominate; on large tensors (>1000 elements per dimension), einsum often matches or beats manual implementations because NumPy selects optimal BLAS routines internally.

> **einsum Optimization with optimize=True**: For einsum expressions involving three or more tensors, use np.einsum('...', A, B, C, optimize=True). NumPy finds the optimal contraction order — which can reduce complexity from O(n^6) to O(n^4) for a three-tensor contraction. Always benchmark against manual @ chains for performance-critical paths.

## Key Takeaways

- Vectorization replaces Python loops with C-compiled array operations — 10-1000x speedup
- Broadcasting: align trailing dims, prepend 1s to shorter shape, expand dims with size 1 — no data copy
- Fancy indexing returns a copy; basic slicing returns a view — modifying a fancy index result is safe
- einsum expresses arbitrary tensor contractions in Einstein notation — clearer than nested transposes and dots
- Use optimize=True in einsum for multi-tensor contractions and np.einsum_path for profiling the contraction order

