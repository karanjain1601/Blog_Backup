---
title: "MobileNet: Lightweight CNNs for Edge Deployment"
slug: "mobilenet-lightweight"
description: "Depthwise separable convolutions in MobileNetV1, the inverted residual block in MobileNetV2, and hard-swish + SE modules in MobileNetV3 — optimized for mobile and edge inference."
tags: ["computer-vision"]
topic: "computer-vision"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"MobileNet is a family of efficient CNNs designed for mobile and embedded applications. V1 (2017) introduced depthwise separable convolutions to cut compute dramatically. V2 (2018) added inverted residuals with linear bottlenecks. V3 (2019) incorporated neural architecture search, hard-swish activation, and squeeze-and-excitation modules to further boost accuracy-per-FLOP."},{"type":"text","content":"The MobileNet series prioritizes real-world deployability over raw benchmark accuracy. All three versions are quantization-friendly, widely supported in TFLite, CoreML, and ONNX Runtime, and serve as backbones for detection (SSD, YOLO), segmentation (DeepLab), and classification on devices ranging from Raspberry Pi to Apple Neural Engine."},{"type":"heading","level":2,"content":"Depthwise Separable Convolution"},{"type":"text","content":"A standard conv with kernel K×K on C_in channels to C_out channels costs K²·C_in·C_out FLOPs per spatial position. Depthwise separable convolution splits this into a depthwise step (one filter per input channel, K²·C_in) and a pointwise step (1×1 conv, C_in·C_out). The FLOPs ratio vs standard conv is 1/C_out + 1/K², roughly 8–9× cheaper for K=3."},{"type":"code","language":"python","content":"import torch.nn as nn\n\ndef dw_sep_block(C_in, C_out, stride=1):\n    return nn.Sequential(\n        # Depthwise: groups=C_in applies one filter per channel\n        nn.Conv2d(C_in, C_in, 3, stride=stride, padding=1, groups=C_in, bias=False),\n        nn.BatchNorm2d(C_in),\n        nn.ReLU6(inplace=True),\n        # Pointwise: 1×1 conv mixes channels\n        nn.Conv2d(C_in, C_out, 1, bias=False),\n        nn.BatchNorm2d(C_out),\n        nn.ReLU6(inplace=True),\n    )\n# FLOPs ratio vs standard conv: 1/C_out + 1/K²\n# For K=3, C_out=32: ratio ≈ 1/32 + 1/9 ≈ 0.14  (≈7× cheaper)"},{"type":"text","content":"MobileNetV1 stacks 13 such depthwise separable blocks with a width multiplier α ∈ {0.25, 0.5, 0.75, 1.0} that uniformly scales channels, and a resolution multiplier ρ that scales input size. Together they allow an accuracy-latency trade-off tunable to the target hardware without retraining the entire architecture from scratch."},{"type":"heading","level":2,"content":"MobileNetV2 Inverted Residual"},{"type":"text","content":"V2 flips the traditional residual design. Where ResNet bottlenecks compress to a narrow middle layer, MobileNetV2 expands channel count by factor t (typically 6) before the depthwise convolution, then projects back down. This keeps the depthwise conv operating in a rich high-dimensional space while the skip connection runs in the compact low-dimensional bottleneck space."},{"type":"code","language":"python","content":"class InvertedResidual(nn.Module):\n    def __init__(self, C_in, C_out, stride, expand_ratio=6):\n        super().__init__()\n        C_mid = C_in * expand_ratio\n        self.use_skip = (stride == 1 and C_in == C_out)\n        self.conv = nn.Sequential(\n            nn.Conv2d(C_in, C_mid, 1, bias=False), nn.BatchNorm2d(C_mid), nn.ReLU6(inplace=True),\n            nn.Conv2d(C_mid, C_mid, 3, stride=stride, padding=1, groups=C_mid, bias=False), nn.BatchNorm2d(C_mid), nn.ReLU6(inplace=True),\n            # Linear bottleneck: NO ReLU after project — preserves information\n            nn.Conv2d(C_mid, C_out, 1, bias=False), nn.BatchNorm2d(C_out),\n        )\n    def forward(self, x):\n        return x + self.conv(x) if self.use_skip else self.conv(x)"},{"type":"text","content":"The linear bottleneck (no ReLU after the final 1×1) is crucial: applying a non-linearity in low-dimensional space destroys information. Skip connections apply only when stride=1 and input/output channels match, preserving gradient flow without inflating parameter count. This design achieves ImageNet Top-1 of 72.0% at only 300M FLOPs, half the compute of V1."},{"type":"heading","level":2,"content":"MobileNetV3 Hard-Swish and SE"},{"type":"text","content":"MobileNetV3 (2019) was co-designed with neural architecture search using MnasNet as a starting point, then refined with NetAdapt. Two variants exist: V3-Large targeting high accuracy and V3-Small targeting extreme efficiency. The architecture introduces hard-swish activation and squeeze-and-excitation (SE) channel attention, both absent in V1 and V2."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\n# Hard-swish: piecewise linear approximation of swish\ndef hard_swish(x):\n    return x * F.hardtanh(x + 3, 0.0, 6.0) / 6.0\n    # Equivalent: x * min(max(x+3, 0), 6) / 6\n\nx = torch.linspace(-4, 4, 9)\nprint(\"x         :\", x.numpy().round(1))\nprint(\"ReLU      :\", F.relu(x).numpy().round(3))\nprint(\"Swish     :\", (x * torch.sigmoid(x)).numpy().round(3))\nprint(\"Hard-swish:\", hard_swish(x).numpy().round(3))\n# Hard-swish: ~15% faster than swish (no sigmoid), accuracy parity on ImageNet"},{"type":"text","content":"Squeeze-and-excitation adds a lightweight channel attention gate: global average pool → FC(C/4) → ReLU → FC(C) → hard-sigmoid. This recalibrates feature maps by learning which channels are most informative. V3 applies SE only in later blocks to limit latency cost, since SE with large channel counts is expensive on mobile CPUs lacking wide SIMD units."},{"type":"heading","level":2,"content":"Deployment and Latency"},{"type":"text","content":"FLOPs are a useful proxy for model complexity but correlate poorly with real inference latency on mobile hardware. Memory bandwidth, cache pressure, operator fusion, and hardware-specific kernels all play larger roles. TFLite with full-integer quantization (INT8) typically delivers 2–4× speedup over FP32 on ARM Cortex-A CPUs, with further gains on NPUs and DSPs."},{"type":"code","language":"python","content":"import torch\nimport torchvision.models as models\nfrom torch.utils.benchmark import Timer\n\ndef benchmark(model, shape=(1,3,224,224), n=100):\n    model.eval()\n    x = torch.randn(*shape)\n    t = Timer(stmt=\"model(x)\", globals={\"model\": model, \"x\": x})\n    return t.timeit(n).mean * 1e3  # ms\n\nbench = {\"V2-1.0\": models.mobilenet_v2(),\n         \"V3-Small\": models.mobilenet_v3_small(),\n         \"V3-Large\": models.mobilenet_v3_large()}\nfor k, m in bench.items():\n    print(f\"{k}: {benchmark(m):.1f} ms\")"},{"type":"callout","calloutType":"warning","title":"FLOPs ≠ Mobile Latency","content":"FLOPs do not predict mobile latency — memory bandwidth, quantization support, and kernel fusion determine real speed. Always benchmark on the actual target device with TFLite or CoreML."},{"type":"table","content":"| Model | Top-1 % | Params (M) | FLOPs (M) | CPU Latency (ms) | Target |\n|---|---|---|---|---|---|\n| V1-1.0 | 70.6 | 4.2 | 575 | 113 | General mobile |\n| V2-1.0 | 72.0 | 3.4 | 300 | 75 | General mobile |\n| V3-Small | 67.4 | 2.5 | 56 | 22 | Extreme efficiency |\n| V3-Large | 75.2 | 5.4 | 219 | 51 | High accuracy mobile |\n| EfficientNet-Lite0 | 75.1 | 4.7 | 407 | 98 | Balanced |"},{"type":"text","content":"On a Pixel 4 CPU (ARM Cortex-A76), V3-Small at 22 ms is roughly 5× faster than V1 at 113 ms while reaching similar accuracy. V3-Large matches EfficientNet-Lite0 accuracy at nearly half the latency. After INT8 quantization via TFLite, all models see a 2–3× speedup, with V3-Small dropping below 10 ms — fast enough for real-time video at 30 fps on mid-range devices."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"Choose V3-Small when power budget or memory is the primary constraint — it runs under 10 ms on-device after INT8 quantization at ~67% ImageNet Top-1. V3-Large is the default starting point for new mobile projects: it matches EfficientNet-Lite0 accuracy at lower latency and is natively supported in PyTorch, TensorFlow, and MediaPipe."},{"type":"text","content":"When adapting MobileNets to a custom task via transfer learning, freeze all depthwise conv weights in early blocks and fine-tune only the pointwise layers and the final classifier. This reduces training cost dramatically because depthwise filters learn low-level edge detectors that transfer universally, while pointwise mixers encode task-specific semantics."},{"type":"text","content":"For production deployment, export with torch.export or tf.lite.TFLiteConverter, enable per-channel quantization (more accurate than per-tensor for pointwise layers), and profile layer-by-layer with the TFLite benchmark tool or Instruments on iOS. Squeeze-and-excitation blocks are the main latency hotspot — consider disabling SE on devices without vector units."}]"
---
# MobileNet: Lightweight CNNs for Edge Deployment

## Overview

MobileNet is a family of efficient CNNs designed for mobile and embedded applications. V1 (2017) introduced depthwise separable convolutions to cut compute dramatically. V2 (2018) added inverted residuals with linear bottlenecks. V3 (2019) incorporated neural architecture search, hard-swish activation, and squeeze-and-excitation modules to further boost accuracy-per-FLOP.

The MobileNet series prioritizes real-world deployability over raw benchmark accuracy. All three versions are quantization-friendly, widely supported in TFLite, CoreML, and ONNX Runtime, and serve as backbones for detection (SSD, YOLO), segmentation (DeepLab), and classification on devices ranging from Raspberry Pi to Apple Neural Engine.

## Depthwise Separable Convolution

A standard conv with kernel K×K on C_in channels to C_out channels costs K²·C_in·C_out FLOPs per spatial position. Depthwise separable convolution splits this into a depthwise step (one filter per input channel, K²·C_in) and a pointwise step (1×1 conv, C_in·C_out). The FLOPs ratio vs standard conv is 1/C_out + 1/K², roughly 8–9× cheaper for K=3.

```python
import torch.nn as nn

def dw_sep_block(C_in, C_out, stride=1):
    return nn.Sequential(
        # Depthwise: groups=C_in applies one filter per channel
        nn.Conv2d(C_in, C_in, 3, stride=stride, padding=1, groups=C_in, bias=False),
        nn.BatchNorm2d(C_in),
        nn.ReLU6(inplace=True),
        # Pointwise: 1×1 conv mixes channels
        nn.Conv2d(C_in, C_out, 1, bias=False),
        nn.BatchNorm2d(C_out),
        nn.ReLU6(inplace=True),
    )
# FLOPs ratio vs standard conv: 1/C_out + 1/K²
# For K=3, C_out=32: ratio ≈ 1/32 + 1/9 ≈ 0.14  (≈7× cheaper)
```

MobileNetV1 stacks 13 such depthwise separable blocks with a width multiplier α ∈ {0.25, 0.5, 0.75, 1.0} that uniformly scales channels, and a resolution multiplier ρ that scales input size. Together they allow an accuracy-latency trade-off tunable to the target hardware without retraining the entire architecture from scratch.

## MobileNetV2 Inverted Residual

V2 flips the traditional residual design. Where ResNet bottlenecks compress to a narrow middle layer, MobileNetV2 expands channel count by factor t (typically 6) before the depthwise convolution, then projects back down. This keeps the depthwise conv operating in a rich high-dimensional space while the skip connection runs in the compact low-dimensional bottleneck space.

```python
class InvertedResidual(nn.Module):
    def __init__(self, C_in, C_out, stride, expand_ratio=6):
        super().__init__()
        C_mid = C_in * expand_ratio
        self.use_skip = (stride == 1 and C_in == C_out)
        self.conv = nn.Sequential(
            nn.Conv2d(C_in, C_mid, 1, bias=False), nn.BatchNorm2d(C_mid), nn.ReLU6(inplace=True),
            nn.Conv2d(C_mid, C_mid, 3, stride=stride, padding=1, groups=C_mid, bias=False), nn.BatchNorm2d(C_mid), nn.ReLU6(inplace=True),
            # Linear bottleneck: NO ReLU after project — preserves information
            nn.Conv2d(C_mid, C_out, 1, bias=False), nn.BatchNorm2d(C_out),
        )
    def forward(self, x):
        return x + self.conv(x) if self.use_skip else self.conv(x)
```

The linear bottleneck (no ReLU after the final 1×1) is crucial: applying a non-linearity in low-dimensional space destroys information. Skip connections apply only when stride=1 and input/output channels match, preserving gradient flow without inflating parameter count. This design achieves ImageNet Top-1 of 72.0% at only 300M FLOPs, half the compute of V1.

## MobileNetV3 Hard-Swish and SE

MobileNetV3 (2019) was co-designed with neural architecture search using MnasNet as a starting point, then refined with NetAdapt. Two variants exist: V3-Large targeting high accuracy and V3-Small targeting extreme efficiency. The architecture introduces hard-swish activation and squeeze-and-excitation (SE) channel attention, both absent in V1 and V2.

```python
import torch
import torch.nn.functional as F

# Hard-swish: piecewise linear approximation of swish
def hard_swish(x):
    return x * F.hardtanh(x + 3, 0.0, 6.0) / 6.0
    # Equivalent: x * min(max(x+3, 0), 6) / 6

x = torch.linspace(-4, 4, 9)
print("x         :", x.numpy().round(1))
print("ReLU      :", F.relu(x).numpy().round(3))
print("Swish     :", (x * torch.sigmoid(x)).numpy().round(3))
print("Hard-swish:", hard_swish(x).numpy().round(3))
# Hard-swish: ~15% faster than swish (no sigmoid), accuracy parity on ImageNet
```

Squeeze-and-excitation adds a lightweight channel attention gate: global average pool → FC(C/4) → ReLU → FC(C) → hard-sigmoid. This recalibrates feature maps by learning which channels are most informative. V3 applies SE only in later blocks to limit latency cost, since SE with large channel counts is expensive on mobile CPUs lacking wide SIMD units.

## Deployment and Latency

FLOPs are a useful proxy for model complexity but correlate poorly with real inference latency on mobile hardware. Memory bandwidth, cache pressure, operator fusion, and hardware-specific kernels all play larger roles. TFLite with full-integer quantization (INT8) typically delivers 2–4× speedup over FP32 on ARM Cortex-A CPUs, with further gains on NPUs and DSPs.

```python
import torch
import torchvision.models as models
from torch.utils.benchmark import Timer

def benchmark(model, shape=(1,3,224,224), n=100):
    model.eval()
    x = torch.randn(*shape)
    t = Timer(stmt="model(x)", globals={"model": model, "x": x})
    return t.timeit(n).mean * 1e3  # ms

bench = {"V2-1.0": models.mobilenet_v2(),
         "V3-Small": models.mobilenet_v3_small(),
         "V3-Large": models.mobilenet_v3_large()}
for k, m in bench.items():
    print(f"{k}: {benchmark(m):.1f} ms")
```

> **FLOPs ≠ Mobile Latency**: FLOPs do not predict mobile latency — memory bandwidth, quantization support, and kernel fusion determine real speed. Always benchmark on the actual target device with TFLite or CoreML.

|  |
| --- |

On a Pixel 4 CPU (ARM Cortex-A76), V3-Small at 22 ms is roughly 5× faster than V1 at 113 ms while reaching similar accuracy. V3-Large matches EfficientNet-Lite0 accuracy at nearly half the latency. After INT8 quantization via TFLite, all models see a 2–3× speedup, with V3-Small dropping below 10 ms — fast enough for real-time video at 30 fps on mid-range devices.

## Key Takeaways

Choose V3-Small when power budget or memory is the primary constraint — it runs under 10 ms on-device after INT8 quantization at ~67% ImageNet Top-1. V3-Large is the default starting point for new mobile projects: it matches EfficientNet-Lite0 accuracy at lower latency and is natively supported in PyTorch, TensorFlow, and MediaPipe.

When adapting MobileNets to a custom task via transfer learning, freeze all depthwise conv weights in early blocks and fine-tune only the pointwise layers and the final classifier. This reduces training cost dramatically because depthwise filters learn low-level edge detectors that transfer universally, while pointwise mixers encode task-specific semantics.

For production deployment, export with torch.export or tf.lite.TFLiteConverter, enable per-channel quantization (more accurate than per-tensor for pointwise layers), and profile layer-by-layer with the TFLite benchmark tool or Instruments on iOS. Squeeze-and-excitation blocks are the main latency hotspot — consider disabling SE on devices without vector units.

