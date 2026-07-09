---
title: "torch.compile — Dynamo Tracing and Inductor Code Generation"
slug: "torch-compile"
description: "torch.compile wraps Python model code in three optimization stages — Dynamo bytecode analysis, AOT Autograd, and Inductor kernel generation — delivering 1.5–4x speedup with one line of code."
tags: ["pytorch", "tools", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"torch.compile (PyTorch 2.0+) transforms eager Python model code into optimized compiled kernels without requiring model rewrites. A single decorator — @torch.compile or torch.compile(model) — triggers three compilation stages that fuse operators, eliminate Python overhead, and generate hardware-optimized CUDA/Triton or C++ code."},{"type":"heading","level":2,"content":"Three Compilation Stages"},{"type":"text","content":"Understanding each stage clarifies what torch.compile can and cannot optimize, and why graph breaks occur."},{"type":"list","ordered":false,"items":["Stage 1 — TorchDynamo: Python bytecode analysis; identifies compilable subgraphs; generates an FX graph; creates a graph break when Python control flow or side effects prevent tracing","Stage 2 — AOT Autograd: captures the backward graph ahead of time (not lazily at backward() call); fuses forward and backward into a single compiled artifact","Stage 3 — TorchInductor: takes the FX graph and generates optimized C++/OpenMP (CPU) or Triton (CUDA) kernels; performs operator fusion, memory layout optimization, and loop ordering","Graph breaks: points where Dynamo gives up and falls back to eager — common causes: Python print, data-dependent shapes, unsupported Python builtins","Compilation overhead: first forward pass triggers JIT compilation (seconds); subsequent calls use the compiled kernel (cached)"]},{"type":"heading","level":2,"content":"Basic Usage and Speedup Measurement"},{"type":"text","content":"torch.compile wraps any callable — a model, a function, even a training step. The API is a single function call with no model modifications required."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport time\n\nclass DeepMLP(nn.Module):\n    def __init__(self, dim: int = 512, depth: int = 8):\n        super().__init__()\n        layers = []\n        for _ in range(depth):\n            layers += [nn.Linear(dim, dim), nn.LayerNorm(dim), nn.GELU()]\n        self.net = nn.Sequential(*layers)\n        self.head = nn.Linear(dim, 10)\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        return self.head(self.net(x))\n\ndevice = \u0027cuda\u0027 if torch.cuda.is_available() else \u0027cpu\u0027\nmodel_eager   = DeepMLP().to(device)\nmodel_compiled = torch.compile(model_eager, mode=\u0027default\u0027)\n\nx = torch.randn(256, 512, device=device)\n\n# Warm up both (compiled model JIT-compiles on first call)\nfor _ in range(3):\n    _ = model_eager(x)\n    _ = model_compiled(x)\n\nif device == \u0027cuda\u0027:\n    torch.cuda.synchronize()\n\nt0 = time.perf_counter()\nfor _ in range(100):\n    _ = model_eager(x)\nif device == \u0027cuda\u0027: torch.cuda.synchronize()\neager_t = time.perf_counter() - t0\n\nt0 = time.perf_counter()\nfor _ in range(100):\n    _ = model_compiled(x)\nif device == \u0027cuda\u0027: torch.cuda.synchronize()\ncompiled_t = time.perf_counter() - t0\n\nprint(f\u0027Eager:    {eager_t*10:.2f} ms/iter\u0027)\nprint(f\u0027Compiled: {compiled_t*10:.2f} ms/iter\u0027)\nprint(f\u0027Speedup:  {eager_t/compiled_t:.2f}x\u0027)"},{"type":"heading","level":2,"content":"Compilation Modes"},{"type":"table","headers":["Mode","Compile Time","Runtime Speedup","Best For","Graph Break Handling"],"rows":[["default","Seconds","1.5–2x typical","Balanced — first choice","Allowed — falls back to eager"],["reduce-overhead","Longer","2–3x (CUDA graphs)","Inference with fixed shapes","Allowed — CUDA graph captures entire loop"],["max-autotune","Minutes","2–4x potential","Production serving — fixed shapes","Minimal — maximizes fusion"],["eager (no compile)","None","1x baseline","Debugging graph breaks","N/A — runs in Python"]]},{"type":"heading","level":2,"content":"Understanding Graph Breaks"},{"type":"text","content":"A graph break occurs when Dynamo encounters Python code it cannot trace symbolically — typically data-dependent control flow, Python side effects, or unsupported operations. Each graph break adds overhead and reduces the optimization scope."},{"type":"code","language":"python","content":"import torch\nimport torch._dynamo as dynamo\n\n# Model with a graph break (print is a side effect)\nclass BreakingModel(torch.nn.Module):\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        x = torch.relu(x)\n        print(f\u0027Shape: {x.shape}\u0027)  # \u003c-- graph break! print is a Python side effect\n        return x * 2\n\n# Explain graph breaks without actually compiling\nmodel = BreakingModel()\nexplanation = dynamo.explain(model)(torch.randn(4, 8))\nprint(f\u0027Number of graphs: {explanation.graph_count}\u0027)\nprint(f\u0027Number of breaks: {explanation.break_reasons}\u0027)\n\n# Fixed model — remove print, use Tensor operations only\nclass FixedModel(torch.nn.Module):\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        x = torch.relu(x)\n        return x * 2\n\nfixed_compiled = torch.compile(FixedModel())\nout = fixed_compiled(torch.randn(4, 8))\nprint(f\u0027Output shape: {out.shape}\u0027)"},{"type":"heading","level":2,"content":"CUDA Graph Capture with reduce-overhead"},{"type":"text","content":"CUDA graphs capture an entire sequence of GPU operations and replay them with a single CPU launch — eliminating per-kernel CPU-GPU synchronization overhead. The reduce-overhead compile mode does this automatically."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\n# reduce-overhead: best for fixed-shape inference (no dynamic shapes)\nmodel = nn.Sequential(\n    nn.Linear(512, 256), nn.GELU(),\n    nn.Linear(256, 128), nn.GELU(),\n    nn.Linear(128, 10)\n)\n\ndevice = \u0027cuda\u0027 if torch.cuda.is_available() else \u0027cpu\u0027\nmodel = model.to(device)\n\n# Compile with CUDA graph mode\ncompiled = torch.compile(model, mode=\u0027reduce-overhead\u0027)\n\nx = torch.randn(64, 512, device=device)\n\n# First few calls: warm up and capture the CUDA graph\nfor _ in range(5):\n    with torch.no_grad():\n        out = compiled(x)\n\nif device == \u0027cuda\u0027:\n    torch.cuda.synchronize()\n    print(f\u0027GPU memory: {torch.cuda.memory_allocated()/1e6:.1f} MB\u0027)\n\n# Note: input shape must stay fixed for CUDA graph to be valid\n# Changing x.shape triggers recompilation\nprint(f\u0027Output shape: {out.shape}\u0027)\nprint(\u0027CUDA graph captured and ready for fast inference\u0027)"},{"type":"heading","level":2,"content":"Measuring Compilation Overhead"},{"type":"text","content":"torch.compile incurs a one-time compilation cost on the first call. Subsequent calls are fast. For short-running scripts, the compile overhead can outweigh the runtime benefit — compile is worth it only when the compiled kernel will be called many times."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport time\n\nmodel = nn.Sequential(\n    nn.Linear(256, 512), nn.GELU(),\n    nn.Linear(512, 256), nn.GELU(),\n    nn.Linear(256, 10)\n)\ndevice = \u0027cuda\u0027 if torch.cuda.is_available() else \u0027cpu\u0027\nmodel = model.to(device)\ncompiled = torch.compile(model, mode=\u0027default\u0027)\n\nx = torch.randn(128, 256, device=device)\n\n# First call: triggers compilation (expensive)\nt0 = time.perf_counter()\nwith torch.no_grad():\n    _ = compiled(x)\nif device == \u0027cuda\u0027: torch.cuda.synchronize()\nfirst_call_t = time.perf_counter() - t0\n\n# Subsequent calls: use cached compiled kernel\ntimes = []\nfor _ in range(50):\n    t0 = time.perf_counter()\n    with torch.no_grad():\n        _ = compiled(x)\n    if device == \u0027cuda\u0027: torch.cuda.synchronize()\n    times.append(time.perf_counter() - t0)\n\nprint(f\u0027First call (compile): {first_call_t*1000:.1f} ms\u0027)\nprint(f\u0027Subsequent avg:       {sum(times)/len(times)*1000:.2f} ms\u0027)\nprint(f\u0027Break-even at:        {int(first_call_t / (sum(times)/len(times)))} inference calls\u0027)"},{"type":"divider"},{"type":"callout","variant":"info","title":"When torch.compile Helps Most","content":"torch.compile delivers the largest speedups for (1) models with many small operations that benefit from fusion (Transformers, attention), (2) training loops where AOT Autograd fuses forward+backward into one kernel sequence, and (3) models running on A100/H100 GPUs with Triton-compatible operations. Small models on CPU may see negligible or negative speedup due to compilation overhead."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"list","ordered":false,"items":["torch.compile has three stages: Dynamo (Python trace → FX graph), AOT Autograd (fused forward+backward), Inductor (Triton/C++ kernels)","Graph breaks reduce optimization scope — avoid Python print, data-dependent shapes, and side effects in compiled code","default mode: balanced first choice; reduce-overhead: CUDA graphs for fixed-shape inference; max-autotune: tuned kernels for production","First forward pass is slow (JIT compilation); subsequent calls use the cached compiled kernel","Use torch._dynamo.explain(model)(x) to diagnose graph breaks before optimizing"]}]"
---
# torch.compile — Dynamo Tracing and Inductor Code Generation

torch.compile (PyTorch 2.0+) transforms eager Python model code into optimized compiled kernels without requiring model rewrites. A single decorator — @torch.compile or torch.compile(model) — triggers three compilation stages that fuse operators, eliminate Python overhead, and generate hardware-optimized CUDA/Triton or C++ code.

## Three Compilation Stages

Understanding each stage clarifies what torch.compile can and cannot optimize, and why graph breaks occur.

- Stage 1 — TorchDynamo: Python bytecode analysis; identifies compilable subgraphs; generates an FX graph; creates a graph break when Python control flow or side effects prevent tracing
- Stage 2 — AOT Autograd: captures the backward graph ahead of time (not lazily at backward() call); fuses forward and backward into a single compiled artifact
- Stage 3 — TorchInductor: takes the FX graph and generates optimized C++/OpenMP (CPU) or Triton (CUDA) kernels; performs operator fusion, memory layout optimization, and loop ordering
- Graph breaks: points where Dynamo gives up and falls back to eager — common causes: Python print, data-dependent shapes, unsupported Python builtins
- Compilation overhead: first forward pass triggers JIT compilation (seconds); subsequent calls use the compiled kernel (cached)

## Basic Usage and Speedup Measurement

torch.compile wraps any callable — a model, a function, even a training step. The API is a single function call with no model modifications required.

```python
import torch
import torch.nn as nn
import time

class DeepMLP(nn.Module):
    def __init__(self, dim: int = 512, depth: int = 8):
        super().__init__()
        layers = []
        for _ in range(depth):
            layers += [nn.Linear(dim, dim), nn.LayerNorm(dim), nn.GELU()]
        self.net = nn.Sequential(*layers)
        self.head = nn.Linear(dim, 10)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        return self.head(self.net(x))

device = 'cuda' if torch.cuda.is_available() else 'cpu'
model_eager   = DeepMLP().to(device)
model_compiled = torch.compile(model_eager, mode='default')

x = torch.randn(256, 512, device=device)

# Warm up both (compiled model JIT-compiles on first call)
for _ in range(3):
    _ = model_eager(x)
    _ = model_compiled(x)

if device == 'cuda':
    torch.cuda.synchronize()

t0 = time.perf_counter()
for _ in range(100):
    _ = model_eager(x)
if device == 'cuda': torch.cuda.synchronize()
eager_t = time.perf_counter() - t0

t0 = time.perf_counter()
for _ in range(100):
    _ = model_compiled(x)
if device == 'cuda': torch.cuda.synchronize()
compiled_t = time.perf_counter() - t0

print(f'Eager:    {eager_t*10:.2f} ms/iter')
print(f'Compiled: {compiled_t*10:.2f} ms/iter')
print(f'Speedup:  {eager_t/compiled_t:.2f}x')
```

## Compilation Modes

| Mode | Compile Time | Runtime Speedup | Best For | Graph Break Handling |
| --- | --- | --- | --- | --- |
| default | Seconds | 1.5–2x typical | Balanced — first choice | Allowed — falls back to eager |
| reduce-overhead | Longer | 2–3x (CUDA graphs) | Inference with fixed shapes | Allowed — CUDA graph captures entire loop |
| max-autotune | Minutes | 2–4x potential | Production serving — fixed shapes | Minimal — maximizes fusion |
| eager (no compile) | None | 1x baseline | Debugging graph breaks | N/A — runs in Python |

## Understanding Graph Breaks

A graph break occurs when Dynamo encounters Python code it cannot trace symbolically — typically data-dependent control flow, Python side effects, or unsupported operations. Each graph break adds overhead and reduces the optimization scope.

```python
import torch
import torch._dynamo as dynamo

# Model with a graph break (print is a side effect)
class BreakingModel(torch.nn.Module):
    def forward(self, x: torch.Tensor) -> torch.Tensor:
        x = torch.relu(x)
        print(f'Shape: {x.shape}')  # <-- graph break! print is a Python side effect
        return x * 2

# Explain graph breaks without actually compiling
model = BreakingModel()
explanation = dynamo.explain(model)(torch.randn(4, 8))
print(f'Number of graphs: {explanation.graph_count}')
print(f'Number of breaks: {explanation.break_reasons}')

# Fixed model — remove print, use Tensor operations only
class FixedModel(torch.nn.Module):
    def forward(self, x: torch.Tensor) -> torch.Tensor:
        x = torch.relu(x)
        return x * 2

fixed_compiled = torch.compile(FixedModel())
out = fixed_compiled(torch.randn(4, 8))
print(f'Output shape: {out.shape}')
```

## CUDA Graph Capture with reduce-overhead

CUDA graphs capture an entire sequence of GPU operations and replay them with a single CPU launch — eliminating per-kernel CPU-GPU synchronization overhead. The reduce-overhead compile mode does this automatically.

```python
import torch
import torch.nn as nn

# reduce-overhead: best for fixed-shape inference (no dynamic shapes)
model = nn.Sequential(
    nn.Linear(512, 256), nn.GELU(),
    nn.Linear(256, 128), nn.GELU(),
    nn.Linear(128, 10)
)

device = 'cuda' if torch.cuda.is_available() else 'cpu'
model = model.to(device)

# Compile with CUDA graph mode
compiled = torch.compile(model, mode='reduce-overhead')

x = torch.randn(64, 512, device=device)

# First few calls: warm up and capture the CUDA graph
for _ in range(5):
    with torch.no_grad():
        out = compiled(x)

if device == 'cuda':
    torch.cuda.synchronize()
    print(f'GPU memory: {torch.cuda.memory_allocated()/1e6:.1f} MB')

# Note: input shape must stay fixed for CUDA graph to be valid
# Changing x.shape triggers recompilation
print(f'Output shape: {out.shape}')
print('CUDA graph captured and ready for fast inference')
```

## Measuring Compilation Overhead

torch.compile incurs a one-time compilation cost on the first call. Subsequent calls are fast. For short-running scripts, the compile overhead can outweigh the runtime benefit — compile is worth it only when the compiled kernel will be called many times.

```python
import torch
import torch.nn as nn
import time

model = nn.Sequential(
    nn.Linear(256, 512), nn.GELU(),
    nn.Linear(512, 256), nn.GELU(),
    nn.Linear(256, 10)
)
device = 'cuda' if torch.cuda.is_available() else 'cpu'
model = model.to(device)
compiled = torch.compile(model, mode='default')

x = torch.randn(128, 256, device=device)

# First call: triggers compilation (expensive)
t0 = time.perf_counter()
with torch.no_grad():
    _ = compiled(x)
if device == 'cuda': torch.cuda.synchronize()
first_call_t = time.perf_counter() - t0

# Subsequent calls: use cached compiled kernel
times = []
for _ in range(50):
    t0 = time.perf_counter()
    with torch.no_grad():
        _ = compiled(x)
    if device == 'cuda': torch.cuda.synchronize()
    times.append(time.perf_counter() - t0)

print(f'First call (compile): {first_call_t*1000:.1f} ms')
print(f'Subsequent avg:       {sum(times)/len(times)*1000:.2f} ms')
print(f'Break-even at:        {int(first_call_t / (sum(times)/len(times)))} inference calls')
```

---

> **When torch.compile Helps Most**: torch.compile delivers the largest speedups for (1) models with many small operations that benefit from fusion (Transformers, attention), (2) training loops where AOT Autograd fuses forward+backward into one kernel sequence, and (3) models running on A100/H100 GPUs with Triton-compatible operations. Small models on CPU may see negligible or negative speedup due to compilation overhead.

## Key Takeaways

- torch.compile has three stages: Dynamo (Python trace → FX graph), AOT Autograd (fused forward+backward), Inductor (Triton/C++ kernels)
- Graph breaks reduce optimization scope — avoid Python print, data-dependent shapes, and side effects in compiled code
- default mode: balanced first choice; reduce-overhead: CUDA graphs for fixed-shape inference; max-autotune: tuned kernels for production
- First forward pass is slow (JIT compilation); subsequent calls use the cached compiled kernel
- Use torch._dynamo.explain(model)(x) to diagnose graph breaks before optimizing

