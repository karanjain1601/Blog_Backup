---
title: "1D, 2D, and 3D Convolutions — Applications for Each"
slug: "convolutions-1d-2d-3d"
description: "Compare 1D, 2D, and 3D convolutions across input shapes, parameter counts, and domains — from time-series and audio to images, video, and volumetric medical data."
tags: ["deep-learning", "cnns"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Convolution generalises naturally across dimensionalities: 1D slides a kernel along a single axis (time or sequence length), 2D slides over a spatial plane (height × width), and 3D slides over a volume (depth × height × width or time × height × width). Choosing the right dimensionality is not arbitrary — it encodes a structural assumption about where local correlations exist in the data, and matching that assumption to the true data geometry is the first architectural decision for any CNN design."},{"type":"heading","level":2,"content":"1D Convolution — Sequences, Audio, and Time Series"},{"type":"text","content":"nn.Conv1d takes input of shape (N, C, L) — batch, channels, length — and produces output (N, C_out, L_out). The kernel slides along the L dimension only. Applications: time-series classification (ECG, accelerometer), audio waveform modelling (WaveNet stacks dilated 1D convs to achieve receptive fields of thousands of samples), text classification (TextCNN applies multiple kernel sizes like 3, 4, 5 then max-pools), and position mixing in hybrid models. 1D conv is much faster than RNNs for fixed-context tasks and fully parallelisable during training. WaveNet achieved state-of-the-art text-to-speech by stacking 30 dilated 1D conv layers with dilation rates [1,2,4,...,512] repeated."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass ECGClassifier(nn.Module):\n    \"\"\"1D CNN for time-series (ECG) classification.\"\"\"\n    def __init__(self, n_classes=5):\n        super().__init__()\n        self.conv1 = nn.Conv1d(1, 32, kernel_size=7, padding=3)   # (N,32,L)\n        self.conv2 = nn.Conv1d(32, 64, kernel_size=5, padding=2)  # (N,64,L)\n        self.conv3 = nn.Conv1d(64, 128, kernel_size=3, padding=1) # (N,128,L)\n        self.pool  = nn.AdaptiveAvgPool1d(1)                       # (N,128,1)\n        self.fc    = nn.Linear(128, n_classes)\n\n    def forward(self, x):\n        x = F.relu(self.conv1(x))\n        x = F.max_pool1d(x, 2)          # halve sequence length\n        x = F.relu(self.conv2(x))\n        x = F.max_pool1d(x, 2)\n        x = F.relu(self.conv3(x))\n        x = self.pool(x).squeeze(-1)    # global avg pool -\u003e (N,128)\n        return self.fc(x)\n\nmodel = ECGClassifier()\nx = torch.randn(8, 1, 256)  # 8 ECG traces, single lead, 256 timesteps\nout = model(x)\nprint(f\u0027Input:  {tuple(x.shape)}\u0027)\nprint(f\u0027Output: {tuple(out.shape)}\u0027)\nparams = sum(p.numel() for p in model.parameters())\nprint(f\u0027Total params: {params:,}\u0027)"},{"type":"heading","level":2,"content":"2D Convolution — Images and Spatial Feature Maps"},{"type":"text","content":"nn.Conv2d takes input (N, C, H, W) and is the standard building block for image tasks. It slides the kernel over two spatial dimensions simultaneously, learning translation-equivariant feature detectors. Virtually all image classification, detection, and segmentation networks (VGG, ResNet, EfficientNet, YOLO, Mask R-CNN) are built on 2D conv. The key design choices are: how many channels (width), how deep to go (depth), where to downsample (stride or pool), and what kernel sizes to use. The trend since 2015 has been toward all-3×3 kernels (VGG insight: two 3×3 convs have the same RF as one 5×5 but fewer parameters), skip connections (ResNet), and depthwise separable convs (MobileNet)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass SmallImageCNN(nn.Module):\n    \"\"\"Compact 2D CNN for CIFAR-10 (32x32 input).\"\"\"\n    def __init__(self, num_classes=10):\n        super().__init__()\n        self.features = nn.Sequential(\n            nn.Conv2d(3, 32, 3, padding=1), nn.BatchNorm2d(32), nn.ReLU(),\n            nn.Conv2d(32, 64, 3, padding=1), nn.BatchNorm2d(64), nn.ReLU(),\n            nn.MaxPool2d(2),                 # 32-\u003e16\n            nn.Conv2d(64, 128, 3, padding=1), nn.BatchNorm2d(128), nn.ReLU(),\n            nn.Conv2d(128, 128, 3, padding=1), nn.BatchNorm2d(128), nn.ReLU(),\n            nn.MaxPool2d(2),                 # 16-\u003e8\n            nn.Conv2d(128, 256, 3, padding=1), nn.BatchNorm2d(256), nn.ReLU(),\n        )\n        self.head = nn.Sequential(\n            nn.AdaptiveAvgPool2d(1),\n            nn.Flatten(),\n            nn.Linear(256, num_classes)\n        )\n\n    def forward(self, x):\n        return self.head(self.features(x))\n\nmodel = SmallImageCNN()\nx = torch.randn(4, 3, 32, 32)\nout = model(x)\nprint(f\u0027Input: {tuple(x.shape)} -\u003e Output: {tuple(out.shape)}\u0027)\nprint(f\u0027Params: {sum(p.numel() for p in model.parameters()):,}\u0027)"},{"type":"heading","level":2,"content":"3D Convolution — Video and Volumetric Data"},{"type":"text","content":"nn.Conv3d takes input (N, C, D, H, W) where D is depth (time frames for video, z-slices for medical imaging). It applies a 3D kernel that slides over all three spatial/temporal axes simultaneously, learning spatio-temporal features. C3D (Tran et al., 2015) used 3×3×3 kernels throughout for action recognition. I3D inflated ImageNet-pretrained 2D conv weights into 3D by repeating them along the temporal axis. For medical imaging (CT, MRI), 3D conv captures inter-slice relationships that 2D slice-by-slice processing misses."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass VideoClipCNN(nn.Module):\n    \"\"\"Minimal 3D CNN for short video clip classification.\"\"\"\n    def __init__(self, num_classes=101):\n        super().__init__()\n        # Input: (N, 3, T, H, W) e.g. (N, 3, 16, 112, 112)\n        self.conv1 = nn.Conv3d(3,  64, kernel_size=(3,3,3), padding=1)\n        self.conv2 = nn.Conv3d(64, 128, kernel_size=(3,3,3), padding=1)\n        self.conv3 = nn.Conv3d(128, 256, kernel_size=(3,3,3), padding=1)\n        self.pool  = nn.AdaptiveAvgPool3d(1)\n        self.fc    = nn.Linear(256, num_classes)\n\n    def forward(self, x):\n        x = F.relu(self.conv1(x))\n        x = F.max_pool3d(x, kernel_size=(1,2,2))  # only pool spatial\n        x = F.relu(self.conv2(x))\n        x = F.max_pool3d(x, kernel_size=(2,2,2))\n        x = F.relu(self.conv3(x))\n        x = self.pool(x).squeeze(-1).squeeze(-1).squeeze(-1)\n        return self.fc(x)\n\nmodel = VideoClipCNN()\nx = torch.randn(2, 3, 16, 112, 112)  # 2 clips, 16 frames, 112x112\nout = model(x)\nprint(f\u0027Input : {tuple(x.shape)}\u0027)\nprint(f\u0027Output: {tuple(out.shape)}\u0027)\nprint(f\u0027Params: {sum(p.numel() for p in model.parameters()):,}\u0027)"},{"type":"heading","level":2,"content":"Pseudo-3D Convolution — Factorising for Efficiency"},{"type":"text","content":"Full 3D conv has k³ parameters per filter position. Pseudo-3D (P3D, Qiu et al. 2017) factorises a 3×3×3 conv into a spatial 3×3 (2D, no temporal mixing) followed by a temporal 1×1×3 (1D along time, no spatial mixing). This reduces parameters from k³×C_in×C_out to (k²+k)×C_in×C_out ≈ 3.4× fewer for k=3, with comparable accuracy on action recognition benchmarks. (2+1)D conv (R(2+1)D, Tran et al. 2018) adds a nonlinearity between the two factors, further improving expressivity. These factored designs make 3D-conv-based video understanding practical on standard GPU budgets."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport time\n\nclass FullConv3D(nn.Module):\n    def __init__(self, C): super().__init__(); self.conv = nn.Conv3d(C, C, 3, padding=1)\n    def forward(self, x): return self.conv(x)\n\nclass Pseudo3D(nn.Module):\n    \"\"\"Spatial 2D conv + temporal 1D conv.\"\"\"\n    def __init__(self, C):\n        super().__init__()\n        self.spatial  = nn.Conv3d(C, C, (1,3,3), padding=(0,1,1))\n        self.temporal = nn.Conv3d(C, C, (3,1,1), padding=(1,0,0))\n    def forward(self, x):\n        return self.temporal(self.spatial(x))\n\nC, T, H, W = 64, 8, 28, 28\nx = torch.randn(2, C, T, H, W)\n\nfor name, model in [(\u0027Full 3D\u0027, FullConv3D(C)), (\u0027Pseudo-3D\u0027, Pseudo3D(C))]:\n    params = sum(p.numel() for p in model.parameters())\n    t0 = time.time()\n    for _ in range(10): _ = model(x)\n    elapsed = (time.time() - t0) / 10 * 1000\n    print(f\u0027{name:\u003c12}: params={params:,}  time={elapsed:.1f}ms\u0027)"},{"type":"callout","variant":"tip","title":"Conv2D + LSTM vs Conv3D for Video","content":"Conv2D+LSTM (ConvLSTM) processes each frame with 2D conv and propagates temporal state through LSTM cells. This is better for long videos where temporal dependencies span many frames. Conv3D is better for short clips (8–32 frames) where local spatio-temporal patterns matter (e.g., detecting a hand gesture). For very long videos, consider ViT-based approaches with temporal attention, which have global receptive fields from the first layer."},{"type":"heading","level":2,"content":"When to Use Each Dimensionality"},{"type":"text","content":"The choice of conv dimensionality should match where local structure exists in the data. 1D is best for ordered sequences with local temporal/positional patterns and no inherent 2D structure. 2D is the default for any grid-like data with two spatial axes. 3D is appropriate when a third dimension (time or depth) has local correlations with the spatial dimensions simultaneously, not just sequentially. Using 3D conv on data with sparse temporal structure (e.g., long videos with mostly static scenes) wastes parameters; per-frame 2D conv is more efficient. Using 1D conv on images would miss 2D spatial structure entirely."},{"type":"table","headers":["Dimension","Input Shape","Kernel Shape","Stride Dims","Params (vs 2D)","Main Applications"],"rows":[["Conv1D","(N, C, L)","(C_out, C_in, k)","L only","k/k² = 1/k","Time series, audio, text, 1D signals"],["Conv2D","(N, C, H, W)","(C_out, C_in, k, k)","H, W","1× (baseline)","Images, spatial feature maps"],["Conv3D","(N, C, D, H, W)","(C_out, C_in, k, k, k)","D, H, W","k× more","Video clips, CT/MRI volumes"],["Pseudo-3D","(N, C, T, H, W)","1×k×k then k×1×1","H,W then T","≈1/3 of 3D","Efficient video understanding"],["Depthwise 2D","(N, C, H, W)","C kernels of (1,k,k)","H, W","1/C_out","Mobile, channel-independent features"]]},{"type":"list","ordered":false,"items":["nn.Conv1d input must be (N, C, L) — reshape (N, L, C) inputs with .permute(0,2,1) before passing.","nn.Conv3d is memory-intensive: a 3D feature map (N,256,16,14,14) uses 3.2 GB at float32 batch=8.","For medical imaging, nnU-Net auto-configures 2D vs 3D conv based on dataset anisotropy (z-spacing).","WaveNet used causal dilated Conv1D (masked to prevent future leakage) for autoregressive audio synthesis.","TextCNN (Kim 2014): three Conv1D with kernels [3,4,5], global max pool per kernel, concat → MLP."]},{"type":"heading","level":2,"content":"Memory and Throughput Considerations"},{"type":"text","content":"3D convolutions are memory-intensive because activations grow with D×H×W. A single layer with C=256, T=16, H=56, W=56 uses 256×16×56×56×4 bytes ≈ 1.6 GB at float32 for one sample. Gradient checkpointing (recomputing activations during backward pass) trades compute for memory — essential for training deep video networks. Mixed-precision (float16) halves activation memory with minimal accuracy loss. For inference on edge devices, reduce T (clip length) before C (channel width) since temporal dimension reduction costs fewer parameters."},{"type":"text","content":"Batch size selection also differs by conv type: 1D conv networks can use large batches (e.g., 256) since sequence inputs are compact; 3D video conv networks often require batch size 2–8 even on high-end GPUs due to activation memory. Gradient accumulation over multiple small batches simulates larger effective batch sizes without exceeding GPU memory limits."},{"type":"list","ordered":false,"items":["Profile with torch.profiler to identify whether 3D conv is compute-bound or memory-bandwidth-bound.","For 3D conv on video, consider temporal striding (stride=(2,1,1)) to reduce time dimension cheaply.","Conv1d is equivalent to Conv2d with height=1 — you can implement 1D conv using 2D primitives if needed.","TemporalShift Module (TSM): shifts a fraction of channels along the time axis — zero-parameter temporal modelling built on 2D conv."]},{"type":"divider"}]"
---
# 1D, 2D, and 3D Convolutions — Applications for Each

Convolution generalises naturally across dimensionalities: 1D slides a kernel along a single axis (time or sequence length), 2D slides over a spatial plane (height × width), and 3D slides over a volume (depth × height × width or time × height × width). Choosing the right dimensionality is not arbitrary — it encodes a structural assumption about where local correlations exist in the data, and matching that assumption to the true data geometry is the first architectural decision for any CNN design.

## 1D Convolution — Sequences, Audio, and Time Series

nn.Conv1d takes input of shape (N, C, L) — batch, channels, length — and produces output (N, C_out, L_out). The kernel slides along the L dimension only. Applications: time-series classification (ECG, accelerometer), audio waveform modelling (WaveNet stacks dilated 1D convs to achieve receptive fields of thousands of samples), text classification (TextCNN applies multiple kernel sizes like 3, 4, 5 then max-pools), and position mixing in hybrid models. 1D conv is much faster than RNNs for fixed-context tasks and fully parallelisable during training. WaveNet achieved state-of-the-art text-to-speech by stacking 30 dilated 1D conv layers with dilation rates [1,2,4,...,512] repeated.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class ECGClassifier(nn.Module):
    """1D CNN for time-series (ECG) classification."""
    def __init__(self, n_classes=5):
        super().__init__()
        self.conv1 = nn.Conv1d(1, 32, kernel_size=7, padding=3)   # (N,32,L)
        self.conv2 = nn.Conv1d(32, 64, kernel_size=5, padding=2)  # (N,64,L)
        self.conv3 = nn.Conv1d(64, 128, kernel_size=3, padding=1) # (N,128,L)
        self.pool  = nn.AdaptiveAvgPool1d(1)                       # (N,128,1)
        self.fc    = nn.Linear(128, n_classes)

    def forward(self, x):
        x = F.relu(self.conv1(x))
        x = F.max_pool1d(x, 2)          # halve sequence length
        x = F.relu(self.conv2(x))
        x = F.max_pool1d(x, 2)
        x = F.relu(self.conv3(x))
        x = self.pool(x).squeeze(-1)    # global avg pool -> (N,128)
        return self.fc(x)

model = ECGClassifier()
x = torch.randn(8, 1, 256)  # 8 ECG traces, single lead, 256 timesteps
out = model(x)
print(f'Input:  {tuple(x.shape)}')
print(f'Output: {tuple(out.shape)}')
params = sum(p.numel() for p in model.parameters())
print(f'Total params: {params:,}')
```

## 2D Convolution — Images and Spatial Feature Maps

nn.Conv2d takes input (N, C, H, W) and is the standard building block for image tasks. It slides the kernel over two spatial dimensions simultaneously, learning translation-equivariant feature detectors. Virtually all image classification, detection, and segmentation networks (VGG, ResNet, EfficientNet, YOLO, Mask R-CNN) are built on 2D conv. The key design choices are: how many channels (width), how deep to go (depth), where to downsample (stride or pool), and what kernel sizes to use. The trend since 2015 has been toward all-3×3 kernels (VGG insight: two 3×3 convs have the same RF as one 5×5 but fewer parameters), skip connections (ResNet), and depthwise separable convs (MobileNet).

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class SmallImageCNN(nn.Module):
    """Compact 2D CNN for CIFAR-10 (32x32 input)."""
    def __init__(self, num_classes=10):
        super().__init__()
        self.features = nn.Sequential(
            nn.Conv2d(3, 32, 3, padding=1), nn.BatchNorm2d(32), nn.ReLU(),
            nn.Conv2d(32, 64, 3, padding=1), nn.BatchNorm2d(64), nn.ReLU(),
            nn.MaxPool2d(2),                 # 32->16
            nn.Conv2d(64, 128, 3, padding=1), nn.BatchNorm2d(128), nn.ReLU(),
            nn.Conv2d(128, 128, 3, padding=1), nn.BatchNorm2d(128), nn.ReLU(),
            nn.MaxPool2d(2),                 # 16->8
            nn.Conv2d(128, 256, 3, padding=1), nn.BatchNorm2d(256), nn.ReLU(),
        )
        self.head = nn.Sequential(
            nn.AdaptiveAvgPool2d(1),
            nn.Flatten(),
            nn.Linear(256, num_classes)
        )

    def forward(self, x):
        return self.head(self.features(x))

model = SmallImageCNN()
x = torch.randn(4, 3, 32, 32)
out = model(x)
print(f'Input: {tuple(x.shape)} -> Output: {tuple(out.shape)}')
print(f'Params: {sum(p.numel() for p in model.parameters()):,}')
```

## 3D Convolution — Video and Volumetric Data

nn.Conv3d takes input (N, C, D, H, W) where D is depth (time frames for video, z-slices for medical imaging). It applies a 3D kernel that slides over all three spatial/temporal axes simultaneously, learning spatio-temporal features. C3D (Tran et al., 2015) used 3×3×3 kernels throughout for action recognition. I3D inflated ImageNet-pretrained 2D conv weights into 3D by repeating them along the temporal axis. For medical imaging (CT, MRI), 3D conv captures inter-slice relationships that 2D slice-by-slice processing misses.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class VideoClipCNN(nn.Module):
    """Minimal 3D CNN for short video clip classification."""
    def __init__(self, num_classes=101):
        super().__init__()
        # Input: (N, 3, T, H, W) e.g. (N, 3, 16, 112, 112)
        self.conv1 = nn.Conv3d(3,  64, kernel_size=(3,3,3), padding=1)
        self.conv2 = nn.Conv3d(64, 128, kernel_size=(3,3,3), padding=1)
        self.conv3 = nn.Conv3d(128, 256, kernel_size=(3,3,3), padding=1)
        self.pool  = nn.AdaptiveAvgPool3d(1)
        self.fc    = nn.Linear(256, num_classes)

    def forward(self, x):
        x = F.relu(self.conv1(x))
        x = F.max_pool3d(x, kernel_size=(1,2,2))  # only pool spatial
        x = F.relu(self.conv2(x))
        x = F.max_pool3d(x, kernel_size=(2,2,2))
        x = F.relu(self.conv3(x))
        x = self.pool(x).squeeze(-1).squeeze(-1).squeeze(-1)
        return self.fc(x)

model = VideoClipCNN()
x = torch.randn(2, 3, 16, 112, 112)  # 2 clips, 16 frames, 112x112
out = model(x)
print(f'Input : {tuple(x.shape)}')
print(f'Output: {tuple(out.shape)}')
print(f'Params: {sum(p.numel() for p in model.parameters()):,}')
```

## Pseudo-3D Convolution — Factorising for Efficiency

Full 3D conv has k³ parameters per filter position. Pseudo-3D (P3D, Qiu et al. 2017) factorises a 3×3×3 conv into a spatial 3×3 (2D, no temporal mixing) followed by a temporal 1×1×3 (1D along time, no spatial mixing). This reduces parameters from k³×C_in×C_out to (k²+k)×C_in×C_out ≈ 3.4× fewer for k=3, with comparable accuracy on action recognition benchmarks. (2+1)D conv (R(2+1)D, Tran et al. 2018) adds a nonlinearity between the two factors, further improving expressivity. These factored designs make 3D-conv-based video understanding practical on standard GPU budgets.

```python
import torch
import torch.nn as nn
import time

class FullConv3D(nn.Module):
    def __init__(self, C): super().__init__(); self.conv = nn.Conv3d(C, C, 3, padding=1)
    def forward(self, x): return self.conv(x)

class Pseudo3D(nn.Module):
    """Spatial 2D conv + temporal 1D conv."""
    def __init__(self, C):
        super().__init__()
        self.spatial  = nn.Conv3d(C, C, (1,3,3), padding=(0,1,1))
        self.temporal = nn.Conv3d(C, C, (3,1,1), padding=(1,0,0))
    def forward(self, x):
        return self.temporal(self.spatial(x))

C, T, H, W = 64, 8, 28, 28
x = torch.randn(2, C, T, H, W)

for name, model in [('Full 3D', FullConv3D(C)), ('Pseudo-3D', Pseudo3D(C))]:
    params = sum(p.numel() for p in model.parameters())
    t0 = time.time()
    for _ in range(10): _ = model(x)
    elapsed = (time.time() - t0) / 10 * 1000
    print(f'{name:<12}: params={params:,}  time={elapsed:.1f}ms')
```

> **Conv2D + LSTM vs Conv3D for Video**: Conv2D+LSTM (ConvLSTM) processes each frame with 2D conv and propagates temporal state through LSTM cells. This is better for long videos where temporal dependencies span many frames. Conv3D is better for short clips (8–32 frames) where local spatio-temporal patterns matter (e.g., detecting a hand gesture). For very long videos, consider ViT-based approaches with temporal attention, which have global receptive fields from the first layer.

## When to Use Each Dimensionality

The choice of conv dimensionality should match where local structure exists in the data. 1D is best for ordered sequences with local temporal/positional patterns and no inherent 2D structure. 2D is the default for any grid-like data with two spatial axes. 3D is appropriate when a third dimension (time or depth) has local correlations with the spatial dimensions simultaneously, not just sequentially. Using 3D conv on data with sparse temporal structure (e.g., long videos with mostly static scenes) wastes parameters; per-frame 2D conv is more efficient. Using 1D conv on images would miss 2D spatial structure entirely.

| Dimension | Input Shape | Kernel Shape | Stride Dims | Params (vs 2D) | Main Applications |
| --- | --- | --- | --- | --- | --- |
| Conv1D | (N, C, L) | (C_out, C_in, k) | L only | k/k² = 1/k | Time series, audio, text, 1D signals |
| Conv2D | (N, C, H, W) | (C_out, C_in, k, k) | H, W | 1× (baseline) | Images, spatial feature maps |
| Conv3D | (N, C, D, H, W) | (C_out, C_in, k, k, k) | D, H, W | k× more | Video clips, CT/MRI volumes |
| Pseudo-3D | (N, C, T, H, W) | 1×k×k then k×1×1 | H,W then T | ≈1/3 of 3D | Efficient video understanding |
| Depthwise 2D | (N, C, H, W) | C kernels of (1,k,k) | H, W | 1/C_out | Mobile, channel-independent features |

- nn.Conv1d input must be (N, C, L) — reshape (N, L, C) inputs with .permute(0,2,1) before passing.
- nn.Conv3d is memory-intensive: a 3D feature map (N,256,16,14,14) uses 3.2 GB at float32 batch=8.
- For medical imaging, nnU-Net auto-configures 2D vs 3D conv based on dataset anisotropy (z-spacing).
- WaveNet used causal dilated Conv1D (masked to prevent future leakage) for autoregressive audio synthesis.
- TextCNN (Kim 2014): three Conv1D with kernels [3,4,5], global max pool per kernel, concat → MLP.

## Memory and Throughput Considerations

3D convolutions are memory-intensive because activations grow with D×H×W. A single layer with C=256, T=16, H=56, W=56 uses 256×16×56×56×4 bytes ≈ 1.6 GB at float32 for one sample. Gradient checkpointing (recomputing activations during backward pass) trades compute for memory — essential for training deep video networks. Mixed-precision (float16) halves activation memory with minimal accuracy loss. For inference on edge devices, reduce T (clip length) before C (channel width) since temporal dimension reduction costs fewer parameters.

Batch size selection also differs by conv type: 1D conv networks can use large batches (e.g., 256) since sequence inputs are compact; 3D video conv networks often require batch size 2–8 even on high-end GPUs due to activation memory. Gradient accumulation over multiple small batches simulates larger effective batch sizes without exceeding GPU memory limits.

- Profile with torch.profiler to identify whether 3D conv is compute-bound or memory-bandwidth-bound.
- For 3D conv on video, consider temporal striding (stride=(2,1,1)) to reduce time dimension cheaply.
- Conv1d is equivalent to Conv2d with height=1 — you can implement 1D conv using 2D primitives if needed.
- TemporalShift Module (TSM): shifts a fraction of channels along the time axis — zero-parameter temporal modelling built on 2D conv.

---

