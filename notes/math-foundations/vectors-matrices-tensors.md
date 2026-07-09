---
title: "Vectors, Matrices, and Tensors"
slug: "vectors-matrices-tensors"
description: "A deep dive into shapes, rank, memory layout, strides, broadcasting, and GPU performance for vectors, matrices, and tensors."
tags: ["linear-algebra", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[
  {"type":"text","content":"Vectors, matrices, and tensors are the foundational data structures of machine learning. A **vector** is a 1D ordered list of numbers, a **matrix** is a 2D rectangular array, and a **tensor** is the N-dimensional generalization. Mastering how these structures are shaped, laid out in memory, and operated on is essential for writing correct and high-performance ML code — from NumPy scripts to CUDA kernels."},
  {"type":"heading","level":2,"content":"Shapes, Rank, and Dimensionality"},
  {"type":"text","content":"The **rank** of a tensor is its number of axes (dimensions). This is distinct from *matrix rank* (linear independence of rows/columns). A scalar is rank-0, a vector rank-1, a matrix rank-2. Modern deep learning uses rank-4 tensors routinely: shape `(B, C, H, W)` represents a batch of B images each with C channels, height H, and width W. Every element is addressed by an index tuple, e.g., `T[b, c, h, w]`."},
  {"type":"code","language":"python","content":"import numpy as np, torch\n\nscalar = np.float32(3.14)           # rank-0, shape ()\nvector = np.array([1., 2., 3.])     # rank-1, shape (3,)\nmatrix = np.ones((4, 5))            # rank-2, shape (4,5)\ntensor = torch.zeros(32, 3, 224, 224)  # rank-4, shape (32,3,224,224)\n\nfor t in [scalar, vector, matrix]:\n    print(f'ndim={t.ndim}  shape={t.shape}  dtype={t.dtype}')"},
  {"type":"heading","level":2,"content":"Broadcasting Rules (NumPy/PyTorch Style)"},
  {"type":"text","content":"Broadcasting lets you apply element-wise operations on arrays of different (but compatible) shapes without explicit data copying. Rules are applied **right-to-left** across dimensions:\n\n1. Prepend 1s to the shorter shape until both have the same number of axes.\n2. In each axis, sizes must be equal, or one of them must be 1 (which is virtually stretched).\n3. If neither condition holds, an error is raised.\n\nExamples: `(3,1) + (1,4) → (3,4)`, `(32,512) + (512,) → (32,512)`, `(8,1,4) * (3,4) → (8,3,4)`. This is ubiquitous in ML: adding a bias vector across a batch, scaling rows by a weight vector, computing pairwise distances."},
  {"type":"code","language":"python","content":"import numpy as np\n\n# Classic bias addition: no for-loop needed\nbatch = np.random.randn(32, 512)   # (batch_size, features)\nbias  = np.random.randn(512)       # (features,) -> broadcast to (1,512)\nout   = batch + bias               # (32, 512)\n\n# Outer product via broadcasting\nu = np.array([[1],[2],[3]])        # (3,1)\nv = np.array([[10,20,30,40]])      # (1,4)\nouter = u * v                      # (3,4) -- outer product!\nprint(outer)\n\n# Pairwise L2 distances: (n,1,d) - (1,m,d) -> (n,m,d) -> (n,m)\nX = np.random.randn(100, 64)\nY = np.random.randn(200, 64)\ndiff = X[:,None,:] - Y[None,:,:]   # (100,200,64)\ndists = np.sqrt((diff**2).sum(-1)) # (100,200)"},
  {"type":"heading","level":2,"content":"Memory Layout: Row-Major vs Column-Major"},
  {"type":"text","content":"Multi-dimensional arrays are stored as a flat 1D sequence in RAM. The **memory layout** determines the ordering of elements:\n\n- **Row-major (C order)**: Rightmost axis varies fastest. For `[[a,b,c],[d,e,f]]`, memory is `a,b,c,d,e,f`. Used by C, NumPy (default), PyTorch.\n- **Column-major (Fortran order)**: Leftmost axis varies fastest. Memory is `a,d,b,e,c,f`. Used by Fortran, MATLAB, R, Julia.\n\nThis matters enormously for performance: CPUs load data in cache lines (64 bytes = 16 floats). Accessing elements in storage order achieves near-peak throughput; accessing across the stride direction causes cache misses and can be 10–100× slower."},
  {"type":"callout","variant":"warning","title":"BLAS Libraries and Layout Assumptions","content":"BLAS and LAPACK (the backends for numpy.dot and torch.mm) were written in Fortran and originally expected column-major arrays. NumPy handles this transparently by passing appropriate transpose flags to BLAS routines, so you normally don't need to worry. However, if you're writing custom C extensions or calling BLAS directly, always check which layout is expected to avoid subtle correctness and performance bugs."},
  {"type":"heading","level":2,"content":"Strides: The Mechanism Behind Zero-Copy Operations"},
  {"type":"text","content":"A **stride** is the number of elements to advance in memory when moving one step along a given axis. For a float32 matrix of shape `(3,4)` in row-major order:\n\n- Stride along axis 0 (next row): 4 elements\n- Stride along axis 1 (next column): 1 element\n\nTransposing a matrix just **swaps the strides** — no data movement occurs. `A.T` has strides `(1,4)` instead of `(4,1)`. This makes transpose O(1) in time and memory, but the result is *non-contiguous*: successive elements of any row are 4 elements apart in memory, which hurts cache performance for subsequent row-oriented operations."},
  {"type":"code","language":"python","content":"import torch\n\nA = torch.randn(3, 4)              # contiguous row-major\nprint('shape:', A.shape)           # (3, 4)\nprint('strides:', A.stride())      # (4, 1) -- in elements\nprint('contiguous?', A.is_contiguous())  # True\n\nAT = A.T                           # NO copy -- just swapped strides\nprint('AT strides:', AT.stride())         # (1, 4)\nprint('AT contiguous?', AT.is_contiguous()) # False!\n\n# .contiguous() allocates new memory and copies elements in C order\nAT_c = AT.contiguous()\nprint('AT_c strides:', AT_c.stride())      # (3, 1) -- back to C order\n\n# Verify: transposing twice costs one copy (not zero)\nimport time\nbig = torch.randn(4096, 4096)\n_ = big.T.contiguous()  # one allocation + memcopy"},
  {"type":"heading","level":2,"content":"Reshape vs View in PyTorch"},
  {"type":"text","content":"Both operations change an array's shape, but their memory semantics differ:\n\n- **`view(new_shape)`**: Returns a tensor sharing the *same storage*. Zero-copy. Requires the tensor to be contiguous in memory. Raises `RuntimeError` if called on a non-contiguous tensor. The shape must be compatible (same number of elements).\n- **`reshape(new_shape)`**: Returns a view if the tensor is contiguous, otherwise silently allocates and copies. Always succeeds for compatible shapes. Hides memory allocations from the caller.\n\nA guiding principle: use `view` in performance-critical paths when you have verified contiguity, so that unexpected copies surface as errors. Use `reshape` for correctness when contiguity is uncertain."},
  {"type":"code","language":"python","content":"import torch\n\nx = torch.randn(2, 3, 4)           # 24 elements, contiguous\n\n# view: zero-copy, same storage\ny = x.view(6, 4)\nprint(y.data_ptr() == x.data_ptr())  # True\n\n# permute -> non-contiguous\nxp = x.permute(2, 0, 1)            # (4, 2, 3), non-contiguous\ntry:\n    xp.view(8, 3)                   # RuntimeError!\nexcept RuntimeError as e:\n    print('view failed:', e)\n\nyr = xp.reshape(8, 3)              # silent copy -- data_ptr differs\nprint(yr.data_ptr() == xp.data_ptr())  # False\n\n# Transformer pattern: split heads after projection\nB, T, C = 8, 128, 512\nH, D = 8, 64                       # 8 heads, 64 dims each\nq = torch.randn(B, T, C)\nq_heads = q.view(B, T, H, D)       # zero-copy head split\nq_heads = q_heads.transpose(1, 2)  # (B, H, T, D) for attention"},
  {"type":"heading","level":2,"content":"GPU Memory Coalescing and Layout Performance"},
  {"type":"text","content":"NVIDIA GPU threads execute in groups of 32 called **warps**. Peak memory bandwidth is achieved only when all 32 threads in a warp access a contiguous 128-byte region — called **coalesced access**. Non-coalesced (strided) access can reduce effective bandwidth from 900 GB/s (A100) to under 30 GB/s.\n\nFor CNN feature maps, **NCHW** layout (PyTorch default) means channel data for one pixel is spread across memory, while **NHWC** keeps all channels of one pixel together. cuDNN selects the fastest algorithm per operation; `torch.channels_last` enables NHWC storage. For transformer models with large matrix multiplies, ensuring both operands are contiguous and row-major before `torch.matmul` is critical."},
  {"type":"callout","variant":"tip","title":"Channels Last for CNN Acceleration","content":"Convert CNN models to channels-last memory format for 20–50% speedups on Ampere+ GPUs:\n\n  model = model.to(memory_format=torch.channels_last)\n  x = x.to(memory_format=torch.channels_last)\n\nThis aligns feature map layout with Tensor Core input requirements. PyTorch propagates the format through most Conv/BN/ReLU operations automatically."},
  {"type":"table","headers":["Operation","Copies Data?","Requires Contiguous?","Use Case"],"rows":[["tensor.view()","Never","Yes (error if not)","Performance-critical reshape"],["tensor.reshape()","Only if needed","No (copies silently)","General-purpose reshape"],["tensor.T / .transpose()","Never","No (changes strides)","Logical transpose"],["tensor.permute()","Never","No (reorders strides)","Arbitrary axis reorder"],["tensor.contiguous()","If non-contiguous","N/A","Prepare for view or CUDA kernel"],["tensor.expand()","Never (virtual)","No","Broadcast without copy"]]},
  {"type":"callout","variant":"info","title":"Tensors in JAX and NumPy","content":"JAX arrays are always immutable and represent values, not views. JAX's jit-compilation traces through shape/dtype statically, so dynamic reshapes must use shapes known at trace time. NumPy follows the same contiguity rules as PyTorch but uses .flags['C_CONTIGUOUS'] to check layout. The stride-based mental model applies equally to all frameworks."}
]
"
---

# Vectors, Matrices, and Tensors

Vectors, matrices, and tensors are the foundational data structures of machine learning. A **vector** is a 1D ordered list of numbers, a **matrix** is a 2D rectangular array, and a **tensor** is the N-dimensional generalization. Mastering how these structures are shaped, laid out in memory, and operated on is essential for writing correct and high-performance ML code — from NumPy scripts to CUDA kernels.

## Shapes, Rank, and Dimensionality

The **rank** of a tensor is its number of axes (dimensions). This is distinct from *matrix rank* (linear independence of rows/columns). A scalar is rank-0, a vector rank-1, a matrix rank-2. Modern deep learning uses rank-4 tensors routinely: shape `(B, C, H, W)` represents a batch of B images each with C channels, height H, and width W. Every element is addressed by an index tuple, e.g., `T[b, c, h, w]`.

```python
import numpy as np, torch

scalar = np.float32(3.14)           # rank-0, shape ()
vector = np.array([1., 2., 3.])     # rank-1, shape (3,)
matrix = np.ones((4, 5))            # rank-2, shape (4,5)
tensor = torch.zeros(32, 3, 224, 224)  # rank-4, shape (32,3,224,224)

for t in [scalar, vector, matrix]:
    print(f'ndim={t.ndim}  shape={t.shape}  dtype={t.dtype}')
```

## Broadcasting Rules (NumPy/PyTorch Style)

Broadcasting lets you apply element-wise operations on arrays of different (but compatible) shapes without explicit data copying. Rules are applied **right-to-left** across dimensions:

1. Prepend 1s to the shorter shape until both have the same number of axes.
2. In each axis, sizes must be equal, or one of them must be 1 (which is virtually stretched).
3. If neither condition holds, an error is raised.

Examples: `(3,1) + (1,4) → (3,4)`, `(32,512) + (512,) → (32,512)`, `(8,1,4) * (3,4) → (8,3,4)`. This is ubiquitous in ML: adding a bias vector across a batch, scaling rows by a weight vector, computing pairwise distances.

```python
import numpy as np

# Classic bias addition: no for-loop needed
batch = np.random.randn(32, 512)   # (batch_size, features)
bias  = np.random.randn(512)       # (features,) -> broadcast to (1,512)
out   = batch + bias               # (32, 512)

# Outer product via broadcasting
u = np.array([[1],[2],[3]])        # (3,1)
v = np.array([[10,20,30,40]])      # (1,4)
outer = u * v                      # (3,4) -- outer product!
print(outer)

# Pairwise L2 distances: (n,1,d) - (1,m,d) -> (n,m,d) -> (n,m)
X = np.random.randn(100, 64)
Y = np.random.randn(200, 64)
diff = X[:,None,:] - Y[None,:,:]   # (100,200,64)
dists = np.sqrt((diff**2).sum(-1)) # (100,200)
```

## Memory Layout: Row-Major vs Column-Major

Multi-dimensional arrays are stored as a flat 1D sequence in RAM. The **memory layout** determines the ordering of elements:

- **Row-major (C order)**: Rightmost axis varies fastest. For `[[a,b,c],[d,e,f]]`, memory is `a,b,c,d,e,f`. Used by C, NumPy (default), PyTorch.
- **Column-major (Fortran order)**: Leftmost axis varies fastest. Memory is `a,d,b,e,c,f`. Used by Fortran, MATLAB, R, Julia.

This matters enormously for performance: CPUs load data in cache lines (64 bytes = 16 floats). Accessing elements in storage order achieves near-peak throughput; accessing across the stride direction causes cache misses and can be 10–100× slower.

> **[WARNING] BLAS Libraries and Layout Assumptions**
>
> BLAS and LAPACK (the backends for numpy.dot and torch.mm) were written in Fortran and originally expected column-major arrays. NumPy handles this transparently by passing appropriate transpose flags to BLAS routines, so you normally don't need to worry. However, if you're writing custom C extensions or calling BLAS directly, always check which layout is expected to avoid subtle correctness and performance bugs.

## Strides: The Mechanism Behind Zero-Copy Operations

A **stride** is the number of elements to advance in memory when moving one step along a given axis. For a float32 matrix of shape `(3,4)` in row-major order:

- Stride along axis 0 (next row): 4 elements
- Stride along axis 1 (next column): 1 element

Transposing a matrix just **swaps the strides** — no data movement occurs. `A.T` has strides `(1,4)` instead of `(4,1)`. This makes transpose O(1) in time and memory, but the result is *non-contiguous*: successive elements of any row are 4 elements apart in memory, which hurts cache performance for subsequent row-oriented operations.

```python
import torch

A = torch.randn(3, 4)              # contiguous row-major
print('shape:', A.shape)           # (3, 4)
print('strides:', A.stride())      # (4, 1) -- in elements
print('contiguous?', A.is_contiguous())  # True

AT = A.T                           # NO copy -- just swapped strides
print('AT strides:', AT.stride())         # (1, 4)
print('AT contiguous?', AT.is_contiguous()) # False!

# .contiguous() allocates new memory and copies elements in C order
AT_c = AT.contiguous()
print('AT_c strides:', AT_c.stride())      # (3, 1) -- back to C order

# Verify: transposing twice costs one copy (not zero)
import time
big = torch.randn(4096, 4096)
_ = big.T.contiguous()  # one allocation + memcopy
```

## Reshape vs View in PyTorch

Both operations change an array's shape, but their memory semantics differ:

- **`view(new_shape)`**: Returns a tensor sharing the *same storage*. Zero-copy. Requires the tensor to be contiguous in memory. Raises `RuntimeError` if called on a non-contiguous tensor. The shape must be compatible (same number of elements).
- **`reshape(new_shape)`**: Returns a view if the tensor is contiguous, otherwise silently allocates and copies. Always succeeds for compatible shapes. Hides memory allocations from the caller.

A guiding principle: use `view` in performance-critical paths when you have verified contiguity, so that unexpected copies surface as errors. Use `reshape` for correctness when contiguity is uncertain.

```python
import torch

x = torch.randn(2, 3, 4)           # 24 elements, contiguous

# view: zero-copy, same storage
y = x.view(6, 4)
print(y.data_ptr() == x.data_ptr())  # True

# permute -> non-contiguous
xp = x.permute(2, 0, 1)            # (4, 2, 3), non-contiguous
try:
    xp.view(8, 3)                   # RuntimeError!
except RuntimeError as e:
    print('view failed:', e)

yr = xp.reshape(8, 3)              # silent copy -- data_ptr differs
print(yr.data_ptr() == xp.data_ptr())  # False

# Transformer pattern: split heads after projection
B, T, C = 8, 128, 512
H, D = 8, 64                       # 8 heads, 64 dims each
q = torch.randn(B, T, C)
q_heads = q.view(B, T, H, D)       # zero-copy head split
q_heads = q_heads.transpose(1, 2)  # (B, H, T, D) for attention
```

## GPU Memory Coalescing and Layout Performance

NVIDIA GPU threads execute in groups of 32 called **warps**. Peak memory bandwidth is achieved only when all 32 threads in a warp access a contiguous 128-byte region — called **coalesced access**. Non-coalesced (strided) access can reduce effective bandwidth from 900 GB/s (A100) to under 30 GB/s.

For CNN feature maps, **NCHW** layout (PyTorch default) means channel data for one pixel is spread across memory, while **NHWC** keeps all channels of one pixel together. cuDNN selects the fastest algorithm per operation; `torch.channels_last` enables NHWC storage. For transformer models with large matrix multiplies, ensuring both operands are contiguous and row-major before `torch.matmul` is critical.

> **[TIP] Channels Last for CNN Acceleration**
>
> Convert CNN models to channels-last memory format for 20–50% speedups on Ampere+ GPUs:

  model = model.to(memory_format=torch.channels_last)
  x = x.to(memory_format=torch.channels_last)

This aligns feature map layout with Tensor Core input requirements. PyTorch propagates the format through most Conv/BN/ReLU operations automatically.

| Operation | Copies Data? | Requires Contiguous? | Use Case |
| --- | --- | --- | --- |
| tensor.view() | Never | Yes (error if not) | Performance-critical reshape |
| tensor.reshape() | Only if needed | No (copies silently) | General-purpose reshape |
| tensor.T / .transpose() | Never | No (changes strides) | Logical transpose |
| tensor.permute() | Never | No (reorders strides) | Arbitrary axis reorder |
| tensor.contiguous() | If non-contiguous | N/A | Prepare for view or CUDA kernel |
| tensor.expand() | Never (virtual) | No | Broadcast without copy |

> **[INFO] Tensors in JAX and NumPy**
>
> JAX arrays are always immutable and represent values, not views. JAX's jit-compilation traces through shape/dtype statically, so dynamic reshapes must use shapes known at trace time. NumPy follows the same contiguity rules as PyTorch but uses .flags['C_CONTIGUOUS'] to check layout. The stride-based mental model applies equally to all frameworks.
