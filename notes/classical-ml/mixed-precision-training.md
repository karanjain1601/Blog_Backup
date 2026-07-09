---
title: "Mixed Precision Training — FP16, BF16, and GradScaler"
slug: "mixed-precision-training"
description: "Automatic mixed precision training: using FP16/BF16 for forward activations with FP32 master weights, gradient scaling to prevent underflow, and torch.autocast for seamless integration."
tags: ["pytorch", "tools", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Mixed precision training runs the forward pass in FP16 or BF16 while maintaining FP32 master weights. This delivers ~2x memory savings on activations and 2–8x compute speedup on tensor cores, with minimal accuracy degradation when combined with gradient scaling. It is now standard practice for training on modern GPUs."},{"type":"list","ordered":false,"items":["Memory saving: activations stored in FP16/BF16 use half the bytes — enables larger batch sizes or bigger models","Compute speedup: NVIDIA tensor cores perform FP16 GEMM at 2–8x the FP32 throughput","Master weights in FP32: optimizer states and weights stay in FP32 — accuracy preserved","Gradient scaling (FP16 only): multiply loss before backward, divide after — prevents gradient underflow","BF16 needs no scaling: same exponent range as FP32 — native on A100/H100/TPU"]},{"type":"heading","level":2,"content":"FP32 vs FP16 vs BF16"},{"type":"text","content":"The three floating-point formats differ in exponent range and mantissa precision. These differences determine overflow risk, numerical stability, and which operations must stay in FP32."},{"type":"table","headers":["Format","Exponent bits","Mantissa bits","Range","Precision","Overflow risk","GPU support","Recommended use"],"rows":[["FP32","8","23","~1.2e-38 to ~3.4e+38","~7 decimal digits","Very low","All GPUs","Master weights, loss accumulation"],["FP16","5","10","~6e-8 to ~65504","~3 decimal digits","High (max=65504)","V100, A100, H100, consumer","Forward activations with GradScaler"],["BF16","8","7","~1.2e-38 to ~3.4e+38","~2 decimal digits","Very low (FP32 range)","A100, H100, TPU, newer Ampere","Preferred for training — no scaler needed"]]},{"type":"heading","level":2,"content":"torch.autocast and GradScaler"},{"type":"text","content":"torch.autocast automatically selects the appropriate dtype for each operation within its context — GEMM and convolutions run in FP16 for speed; loss functions and normalization stay in FP32 for stability. GradScaler multiplies the loss by a scale factor before backward() to prevent gradient underflow."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torch.cuda.amp import autocast, GradScaler\n\ndevice = \u0027cuda\u0027 if torch.cuda.is_available() else \u0027cpu\u0027\n\nmodel     = nn.Sequential(nn.Linear(512, 256), nn.GELU(), nn.Linear(256, 10)).to(device)\noptimizer = torch.optim.AdamW(model.parameters(), lr=1e-3)\nscaler    = GradScaler()  # manages dynamic loss scaling for FP16\n\nX = torch.randn(128, 512, device=device)\ny = torch.randint(0, 10, (128,), device=device)\ncriterion = nn.CrossEntropyLoss()\n\nfor step in range(5):\n    optimizer.zero_grad(set_to_none=True)\n\n    # autocast: forward pass in FP16 (or BF16 on Ampere)\n    with autocast(device_type=device, dtype=torch.float16):\n        logits = model(X)\n        loss   = criterion(logits, y)\n\n    # scaler.scale(): multiply loss by scale to prevent gradient underflow\n    scaler.scale(loss).backward()\n\n    # scaler.step(): unscale gradients, check for inf/nan, then optimizer step\n    # (skips step if inf/nan found — protects weights)\n    scaler.step(optimizer)\n\n    # scaler.update(): adjust scale factor for next step\n    scaler.update()\n\n    print(f\u0027Step {step+1}: loss={loss.item():.4f}  scale={scaler.get_scale():.0f}\u0027)"},{"type":"heading","level":2,"content":"Why GradScaler is Needed for FP16"},{"type":"text","content":"FP16 gradients underflow to zero when their magnitude is below ~6e-8. GradScaler prevents this by scaling up the loss before backward(), keeping gradients in the representable FP16 range, then unscaling before the optimizer update."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\n# Demonstrate FP16 underflow without scaling\nx = torch.tensor([1e-5], dtype=torch.float16)\nprint(f\u0027FP16 value 1e-5: {x.item()}\u0027)  # prints 0.0 — underflow!\n\nx_fp32 = torch.tensor([1e-5], dtype=torch.float32)\nprint(f\u0027FP32 value 1e-5: {x_fp32.item()}\u0027)  # prints 1e-5 correctly\n\n# GradScaler behavior: scale loss by S, divide gradients by S after backward\nS = 65536.0  # typical initial scale value\nsmall_grad = torch.tensor([1e-5])  # would underflow in FP16\nscaled_grad = small_grad * S      # now within FP16 range\nprint(f\u0027\\nScaled grad in FP16: {scaled_grad.to(torch.float16).item()}\u0027)\nprint(f\u0027Unscaled:            {(scaled_grad.to(torch.float16) / S).item()}\u0027)\n\n# BF16 does NOT need GradScaler (same exponent range as FP32)\ndevice = \u0027cuda\u0027 if torch.cuda.is_available() else \u0027cpu\u0027\nmodel = nn.Linear(10, 5).to(device)\nwith torch.autocast(device_type=device, dtype=torch.bfloat16):\n    out = model(torch.randn(4, 10, device=device))\nprint(f\u0027\\nBF16 output dtype: {out.dtype}\u0027)  # bfloat16"},{"type":"heading","level":2,"content":"BF16 vs FP16 Training Stability"},{"type":"text","content":"BF16 is preferred for training on Ampere (A100) and later GPUs because it has the same exponent range as FP32 — no overflow risk — with only reduced mantissa precision. No gradient scaling is needed. FP16 is still used where BF16 hardware support is unavailable."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torch.cuda.amp import autocast, GradScaler\nimport time\n\ndevice = \u0027cuda\u0027 if torch.cuda.is_available() else \u0027cpu\u0027\n\ndef train_precision(dtype, use_scaler, n_steps=20):\n    model = nn.Sequential(\n        nn.Linear(1024, 512), nn.GELU(),\n        nn.Linear(512, 256), nn.GELU(),\n        nn.Linear(256, 10)\n    ).to(device)\n    optimizer = torch.optim.AdamW(model.parameters(), lr=1e-3)\n    scaler    = GradScaler() if use_scaler else None\n    X = torch.randn(256, 1024, device=device)\n    y = torch.randint(0, 10, (256,), device=device)\n    criterion = nn.CrossEntropyLoss()\n    losses = []\n    t0 = time.perf_counter()\n    for _ in range(n_steps):\n        optimizer.zero_grad(set_to_none=True)\n        with autocast(device_type=device, dtype=dtype):\n            loss = criterion(model(X), y)\n        if scaler:\n            scaler.scale(loss).backward(); scaler.step(optimizer); scaler.update()\n        else:\n            loss.backward(); optimizer.step()\n        losses.append(loss.item())\n    elapsed = time.perf_counter() - t0\n    return losses[-1], elapsed\n\nfor name, dt, sc in [(\u0027FP32\u0027, torch.float32, False),\n                      (\u0027FP16+scaler\u0027, torch.float16, True),\n                      (\u0027BF16\u0027, torch.bfloat16, False)]:\n    final_loss, t = train_precision(dt, sc)\n    print(f\u0027{name:\u003c15}: final_loss={final_loss:.4f}  time={t:.2f}s\u0027)"},{"type":"divider"},{"type":"heading","level":2,"content":"Memory Profiling with Mixed Precision"},{"type":"text","content":"Mixed precision cuts activation memory roughly in half. The FP32 master weights and optimizer states remain, so the savings depend on the ratio of activation memory to parameter memory — larger batch sizes amplify the benefit."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torch.cuda.amp import autocast\n\nif not torch.cuda.is_available():\n    print(\u0027CUDA not available — skipping memory profiling\u0027)\nelse:\n    device = \u0027cuda\u0027\n    model = nn.Sequential(\n        nn.Linear(2048, 1024), nn.GELU(),\n        nn.Linear(1024, 512), nn.GELU(),\n        nn.Linear(512, 10)\n    ).to(device)\n    X = torch.randn(512, 2048, device=device)\n\n    # FP32 baseline\n    torch.cuda.reset_peak_memory_stats()\n    out_fp32 = model(X)\n    fp32_mem = torch.cuda.max_memory_allocated() / 1e6\n    del out_fp32; torch.cuda.empty_cache()\n\n    # FP16 with autocast\n    torch.cuda.reset_peak_memory_stats()\n    with autocast(device_type=\u0027cuda\u0027, dtype=torch.float16):\n        out_fp16 = model(X)\n    fp16_mem = torch.cuda.max_memory_allocated() / 1e6\n    del out_fp16; torch.cuda.empty_cache()\n\n    print(f\u0027FP32 peak memory: {fp32_mem:.1f} MB\u0027)\n    print(f\u0027FP16 peak memory: {fp16_mem:.1f} MB\u0027)\n    print(f\u0027Memory reduction: {100*(1-fp16_mem/fp32_mem):.1f}%\u0027)"},{"type":"text","content":"For production training pipelines, mixed precision is nearly always worth enabling. The memory savings allow larger batch sizes or models that would OOM in FP32, and the throughput increase shortens experiment iteration time. The one exception: very small models where the overhead of autocast context switching exceeds the compute savings."},{"type":"callout","variant":"info","title":"BF16 for A100+ Training","content":"On Ampere (A100) and later GPUs, use torch.autocast(device_type=\u0027cuda\u0027, dtype=torch.bfloat16) without a GradScaler. BF16 is numerically safer than FP16 (same exponent range as FP32) and equally fast on A100 tensor cores. FP16 with GradScaler remains necessary on Volta (V100) and older consumer GPUs."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"list","ordered":false,"items":["FP16 max value is ~65504 — gradients below ~6e-8 underflow to zero; GradScaler scales loss to keep gradients representable","BF16 has FP32\u0027s exponent range — no overflow or underflow risk; preferred for A100/H100 training without GradScaler","torch.autocast selects dtype per operation — GEMM/conv in FP16, normalization and loss in FP32 for stability","GradScaler workflow: scale(loss).backward() → step(optimizer) → update() → automatically adjusts scale factor","Mixed precision cuts activation memory ~2x and delivers 2–8x compute speedup via tensor core GEMM"]}]"
---
# Mixed Precision Training — FP16, BF16, and GradScaler

Mixed precision training runs the forward pass in FP16 or BF16 while maintaining FP32 master weights. This delivers ~2x memory savings on activations and 2–8x compute speedup on tensor cores, with minimal accuracy degradation when combined with gradient scaling. It is now standard practice for training on modern GPUs.

- Memory saving: activations stored in FP16/BF16 use half the bytes — enables larger batch sizes or bigger models
- Compute speedup: NVIDIA tensor cores perform FP16 GEMM at 2–8x the FP32 throughput
- Master weights in FP32: optimizer states and weights stay in FP32 — accuracy preserved
- Gradient scaling (FP16 only): multiply loss before backward, divide after — prevents gradient underflow
- BF16 needs no scaling: same exponent range as FP32 — native on A100/H100/TPU

## FP32 vs FP16 vs BF16

The three floating-point formats differ in exponent range and mantissa precision. These differences determine overflow risk, numerical stability, and which operations must stay in FP32.

| Format | Exponent bits | Mantissa bits | Range | Precision | Overflow risk | GPU support | Recommended use |
| --- | --- | --- | --- | --- | --- | --- | --- |
| FP32 | 8 | 23 | ~1.2e-38 to ~3.4e+38 | ~7 decimal digits | Very low | All GPUs | Master weights, loss accumulation |
| FP16 | 5 | 10 | ~6e-8 to ~65504 | ~3 decimal digits | High (max=65504) | V100, A100, H100, consumer | Forward activations with GradScaler |
| BF16 | 8 | 7 | ~1.2e-38 to ~3.4e+38 | ~2 decimal digits | Very low (FP32 range) | A100, H100, TPU, newer Ampere | Preferred for training — no scaler needed |

## torch.autocast and GradScaler

torch.autocast automatically selects the appropriate dtype for each operation within its context — GEMM and convolutions run in FP16 for speed; loss functions and normalization stay in FP32 for stability. GradScaler multiplies the loss by a scale factor before backward() to prevent gradient underflow.

```python
import torch
import torch.nn as nn
from torch.cuda.amp import autocast, GradScaler

device = 'cuda' if torch.cuda.is_available() else 'cpu'

model     = nn.Sequential(nn.Linear(512, 256), nn.GELU(), nn.Linear(256, 10)).to(device)
optimizer = torch.optim.AdamW(model.parameters(), lr=1e-3)
scaler    = GradScaler()  # manages dynamic loss scaling for FP16

X = torch.randn(128, 512, device=device)
y = torch.randint(0, 10, (128,), device=device)
criterion = nn.CrossEntropyLoss()

for step in range(5):
    optimizer.zero_grad(set_to_none=True)

    # autocast: forward pass in FP16 (or BF16 on Ampere)
    with autocast(device_type=device, dtype=torch.float16):
        logits = model(X)
        loss   = criterion(logits, y)

    # scaler.scale(): multiply loss by scale to prevent gradient underflow
    scaler.scale(loss).backward()

    # scaler.step(): unscale gradients, check for inf/nan, then optimizer step
    # (skips step if inf/nan found — protects weights)
    scaler.step(optimizer)

    # scaler.update(): adjust scale factor for next step
    scaler.update()

    print(f'Step {step+1}: loss={loss.item():.4f}  scale={scaler.get_scale():.0f}')
```

## Why GradScaler is Needed for FP16

FP16 gradients underflow to zero when their magnitude is below ~6e-8. GradScaler prevents this by scaling up the loss before backward(), keeping gradients in the representable FP16 range, then unscaling before the optimizer update.

```python
import torch
import torch.nn as nn

# Demonstrate FP16 underflow without scaling
x = torch.tensor([1e-5], dtype=torch.float16)
print(f'FP16 value 1e-5: {x.item()}')  # prints 0.0 — underflow!

x_fp32 = torch.tensor([1e-5], dtype=torch.float32)
print(f'FP32 value 1e-5: {x_fp32.item()}')  # prints 1e-5 correctly

# GradScaler behavior: scale loss by S, divide gradients by S after backward
S = 65536.0  # typical initial scale value
small_grad = torch.tensor([1e-5])  # would underflow in FP16
scaled_grad = small_grad * S      # now within FP16 range
print(f'\nScaled grad in FP16: {scaled_grad.to(torch.float16).item()}')
print(f'Unscaled:            {(scaled_grad.to(torch.float16) / S).item()}')

# BF16 does NOT need GradScaler (same exponent range as FP32)
device = 'cuda' if torch.cuda.is_available() else 'cpu'
model = nn.Linear(10, 5).to(device)
with torch.autocast(device_type=device, dtype=torch.bfloat16):
    out = model(torch.randn(4, 10, device=device))
print(f'\nBF16 output dtype: {out.dtype}')  # bfloat16
```

## BF16 vs FP16 Training Stability

BF16 is preferred for training on Ampere (A100) and later GPUs because it has the same exponent range as FP32 — no overflow risk — with only reduced mantissa precision. No gradient scaling is needed. FP16 is still used where BF16 hardware support is unavailable.

```python
import torch
import torch.nn as nn
from torch.cuda.amp import autocast, GradScaler
import time

device = 'cuda' if torch.cuda.is_available() else 'cpu'

def train_precision(dtype, use_scaler, n_steps=20):
    model = nn.Sequential(
        nn.Linear(1024, 512), nn.GELU(),
        nn.Linear(512, 256), nn.GELU(),
        nn.Linear(256, 10)
    ).to(device)
    optimizer = torch.optim.AdamW(model.parameters(), lr=1e-3)
    scaler    = GradScaler() if use_scaler else None
    X = torch.randn(256, 1024, device=device)
    y = torch.randint(0, 10, (256,), device=device)
    criterion = nn.CrossEntropyLoss()
    losses = []
    t0 = time.perf_counter()
    for _ in range(n_steps):
        optimizer.zero_grad(set_to_none=True)
        with autocast(device_type=device, dtype=dtype):
            loss = criterion(model(X), y)
        if scaler:
            scaler.scale(loss).backward(); scaler.step(optimizer); scaler.update()
        else:
            loss.backward(); optimizer.step()
        losses.append(loss.item())
    elapsed = time.perf_counter() - t0
    return losses[-1], elapsed

for name, dt, sc in [('FP32', torch.float32, False),
                      ('FP16+scaler', torch.float16, True),
                      ('BF16', torch.bfloat16, False)]:
    final_loss, t = train_precision(dt, sc)
    print(f'{name:<15}: final_loss={final_loss:.4f}  time={t:.2f}s')
```

---

## Memory Profiling with Mixed Precision

Mixed precision cuts activation memory roughly in half. The FP32 master weights and optimizer states remain, so the savings depend on the ratio of activation memory to parameter memory — larger batch sizes amplify the benefit.

```python
import torch
import torch.nn as nn
from torch.cuda.amp import autocast

if not torch.cuda.is_available():
    print('CUDA not available — skipping memory profiling')
else:
    device = 'cuda'
    model = nn.Sequential(
        nn.Linear(2048, 1024), nn.GELU(),
        nn.Linear(1024, 512), nn.GELU(),
        nn.Linear(512, 10)
    ).to(device)
    X = torch.randn(512, 2048, device=device)

    # FP32 baseline
    torch.cuda.reset_peak_memory_stats()
    out_fp32 = model(X)
    fp32_mem = torch.cuda.max_memory_allocated() / 1e6
    del out_fp32; torch.cuda.empty_cache()

    # FP16 with autocast
    torch.cuda.reset_peak_memory_stats()
    with autocast(device_type='cuda', dtype=torch.float16):
        out_fp16 = model(X)
    fp16_mem = torch.cuda.max_memory_allocated() / 1e6
    del out_fp16; torch.cuda.empty_cache()

    print(f'FP32 peak memory: {fp32_mem:.1f} MB')
    print(f'FP16 peak memory: {fp16_mem:.1f} MB')
    print(f'Memory reduction: {100*(1-fp16_mem/fp32_mem):.1f}%')
```

For production training pipelines, mixed precision is nearly always worth enabling. The memory savings allow larger batch sizes or models that would OOM in FP32, and the throughput increase shortens experiment iteration time. The one exception: very small models where the overhead of autocast context switching exceeds the compute savings.

> **BF16 for A100+ Training**: On Ampere (A100) and later GPUs, use torch.autocast(device_type='cuda', dtype=torch.bfloat16) without a GradScaler. BF16 is numerically safer than FP16 (same exponent range as FP32) and equally fast on A100 tensor cores. FP16 with GradScaler remains necessary on Volta (V100) and older consumer GPUs.

## Key Takeaways

- FP16 max value is ~65504 — gradients below ~6e-8 underflow to zero; GradScaler scales loss to keep gradients representable
- BF16 has FP32's exponent range — no overflow or underflow risk; preferred for A100/H100 training without GradScaler
- torch.autocast selects dtype per operation — GEMM/conv in FP16, normalization and loss in FP32 for stability
- GradScaler workflow: scale(loss).backward() → step(optimizer) → update() → automatically adjusts scale factor
- Mixed precision cuts activation memory ~2x and delivers 2–8x compute speedup via tensor core GEMM

