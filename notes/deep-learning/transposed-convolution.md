---
title: "Transposed Convolution — Upsampling and Checkerboard Artifacts"
slug: "transposed-convolution"
description: "Understand transposed convolution as learnable upsampling, diagnose and fix checkerboard artifacts, and compare pixel shuffle and bilinear resize alternatives."
tags: ["deep-learning", "cnns"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Encoder-decoder architectures — U-Net for segmentation, DCGAN and StyleGAN generators, super-resolution networks — need to increase spatial resolution in the decoder. Transposed convolution (also called deconvolution or fractionally-strided convolution) is the learnable alternative to fixed upsampling like bilinear or nearest-neighbour interpolation. However, transposed conv is notorious for producing checkerboard artifacts — periodic amplitude patterns caused by uneven kernel overlap. Understanding why this happens and how to avoid it is essential for anyone building generative or dense-prediction models."},{"type":"heading","level":2,"content":"Transposed Convolution Mechanics"},{"type":"text","content":"A transposed conv with stride s inserts s-1 zeros between each input element along each spatial axis, then applies a standard convolution. This is the transpose of the forward convolution operator in its matrix form. If forward conv is y = Cx, transposed conv computes x̂ = Cᵀy. The output size is: H_out = (H_in - 1)·s - 2p + k. For H_in=4, k=4, s=2, p=1: H_out = (4-1)·2 - 2 + 4 = 8 — exactly doubling. This is the standard configuration in DCGAN and U-Net decoders. The learnable weights give the network freedom to learn the best upsampling filter for the task, unlike fixed bilinear interpolation."},{"type":"code","language":"python","content":"import numpy as np\n\ndef transposed_conv1d_scratch(x, kernel, stride=2):\n    \"\"\"1D transposed conv: insert zeros then convolve (no padding).\"\"\"\n    # Step 1: insert (stride-1) zeros between elements\n    x_up = np.zeros((x.shape[0] - 1) * stride + x.shape[0] -\n                    (x.shape[0] - 1) * (stride - 1))\n    # Simpler: use np repeat trick\n    expanded = np.zeros((x.shape[0] - 1) * stride + 1)\n    expanded[::stride] = x\n    # Step 2: convolve (cross-correlate) with kernel (no flip for CNN)\n    k = len(kernel)\n    out_len = len(expanded) + k - 1\n    output = np.zeros(out_len)\n    for i in range(len(expanded)):\n        output[i:i+k] += expanded[i] * kernel\n    return output\n\nx = np.array([1.0, 2.0, 3.0, 4.0])\nkernel = np.array([1.0, 2.0, 1.0])\nout = transposed_conv1d_scratch(x, kernel, stride=2)\nprint(f\u0027Input length:  {len(x)}\u0027)\nprint(f\u0027Kernel length: {len(kernel)}\u0027)\nprint(f\u0027Output length: {len(out)}  (expected: (4-1)*2+1 + 3-1 = 9)\u0027)\nprint(f\u0027Output values: {out}\u0027)\nprint(\u0027Zero insertion doubles spacing; kernel blends adjacent elements.\u0027)"},{"type":"heading","level":2,"content":"Checkerboard Artifacts and Their Cause"},{"type":"text","content":"Checkerboard artifacts arise when kernel_size is not divisible by stride. With k=3, s=2: some output pixels receive contributions from 2 input pixels while others receive from only 1 — a systematic amplitude imbalance that repeats with period s. The result is a spatially periodic intensity pattern visible in GAN-generated images and segmentation masks. Odena et al. (2016) documented this in \u0027Deconvolution and Checkerboard Artifacts\u0027 and showed that any k not divisible by s produces overlap imbalance. Odd k=4 with s=2 is divisible; k=3 with s=2 is not."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport numpy as np\n\ndef overlap_pattern(k, s, size=8):\n    \"\"\"Count how many input pixels contribute to each output position.\"\"\"\n    # Use a ones input to count overlaps\n    x = torch.ones(1, 1, size, size)\n    conv_t = nn.ConvTranspose2d(1, 1, k, stride=s, padding=0, bias=False)\n    nn.init.ones_(conv_t.weight)\n    with torch.no_grad():\n        out = conv_t(x)\n    return out[0, 0].numpy()\n\nprint(\u0027Overlap counts — k=4 s=2 (divisible, uniform):\u0027)\now = overlap_pattern(4, 2, size=4)\nprint(ow[:8, :8].astype(int))\n\nprint(\u0027\\nOverlap counts — k=3 s=2 (NOT divisible, checkerboard):\u0027)\now = overlap_pattern(3, 2, size=4)\nprint(ow[:8, :8].astype(int))\n\nprint(\u0027\\nFix: resize then conv (no transposed conv at all):\u0027)\ndef upsample_resize_conv(x_in, C_in, C_out):\n    x_up = F.interpolate(x_in, scale_factor=2, mode=\u0027bilinear\u0027, align_corners=False)\n    conv = nn.Conv2d(C_in, C_out, 3, padding=1)\n    return conv(x_up)\n\nprint(\u0027Bilinear + conv = uniform overlap by construction.\u0027)"},{"type":"heading","level":2,"content":"U-Net Decoder — Transposed Conv vs Bilinear+Conv"},{"type":"text","content":"The original U-Net used transposed conv in the decoder. Modern segmentation models often replace it with bilinear upsampling followed by a 3×3 conv, which avoids checkerboard artifacts with minimal accuracy loss. The tradeoff: transposed conv is fully learnable (can learn non-symmetric upsampling), while bilinear+conv fixes the upsampling to bilinear but lets the conv refine features. For tasks where fine-grained detail matters (e.g., cell boundary segmentation), transposed conv with careful initialisation (bilinear init) can outperform fixed bilinear upsampling. In practice, the choice is often hardware-and-latency-driven."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass UNetDecoder(nn.Module):\n    \"\"\"Compare transposed conv vs bilinear+conv decoder blocks.\"\"\"\n    def __init__(self, C_in, C_out, mode=\u0027transpose\u0027):\n        super().__init__()\n        self.mode = mode\n        if mode == \u0027transpose\u0027:\n            self.up = nn.ConvTranspose2d(C_in, C_out, kernel_size=2, stride=2)\n        else:  # bilinear + conv\n            self.up   = nn.Upsample(scale_factor=2, mode=\u0027bilinear\u0027, align_corners=False)\n            self.conv = nn.Conv2d(C_in, C_out, 3, padding=1)\n        self.refine = nn.Sequential(\n            nn.Conv2d(C_out * 2, C_out, 3, padding=1),  # after skip concat\n            nn.BatchNorm2d(C_out), nn.ReLU(inplace=True)\n        )\n\n    def forward(self, x, skip):\n        x = self.up(x) if self.mode == \u0027transpose\u0027 else self.conv(self.up(x))\n        x = torch.cat([x, skip], dim=1)\n        return self.refine(x)\n\nfor mode in [\u0027transpose\u0027, \u0027bilinear\u0027]:\n    dec = UNetDecoder(256, 128, mode=mode)\n    x = torch.randn(2, 256, 14, 14)\n    skip = torch.randn(2, 128, 28, 28)\n    out = dec(x, skip)\n    p = sum(q.numel() for q in dec.parameters())\n    print(f\u0027{mode:\u003c12}: output={tuple(out.shape)}, params={p:,}\u0027)"},{"type":"heading","level":2,"content":"Pixel Shuffle — Sub-Pixel Convolution"},{"type":"text","content":"Pixel shuffle (sub-pixel convolution, Shi et al. 2016) is an elegant alternative for super-resolution. Instead of inserting zeros and filtering, it applies a standard conv in the low-resolution space to produce C×r²×H×W features, then rearranges (shuffles) the r² channels into a spatial r×r grid: output is C×(H·r)×(W·r). The computation happens entirely at low resolution — far cheaper than operating at high resolution — and the upsampling is fully learned. ESPCN used this for real-time video super-resolution. The key property: no checkerboard artifacts when the preceding conv is initialised correctly (ICNR initialisation)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass PixelShuffleUpsample(nn.Module):\n    \"\"\"Sub-pixel convolution for 2x upsampling.\"\"\"\n    def __init__(self, C_in, C_out, scale_factor=2):\n        super().__init__()\n        # Conv produces C_out * r^2 channels at low resolution\n        self.conv = nn.Conv2d(C_in, C_out * scale_factor**2, kernel_size=3, padding=1)\n        self.ps   = nn.PixelShuffle(scale_factor)  # rearranges to spatial\n        self._init_weights(C_out, scale_factor)\n\n    def _init_weights(self, C_out, r):\n        \"\"\"ICNR init: tile C_out filters to avoid checkerboard at init.\"\"\"\n        kernel = self.conv.weight.data.clone()[:C_out]\n        for i in range(r * r):\n            self.conv.weight.data[i*C_out:(i+1)*C_out] = kernel\n\n    def forward(self, x):\n        return self.ps(self.conv(x))\n\n# Compare transposed conv vs pixel shuffle\nC_in, C_out, r = 64, 32, 2\ntransp = nn.ConvTranspose2d(C_in, C_out, kernel_size=2, stride=2, bias=False)\npixshu = PixelShuffleUpsample(C_in, C_out, scale_factor=r)\n\nx = torch.randn(2, C_in, 14, 14)\nprint(f\u0027Transposed conv output: {tuple(transp(x).shape)}\u0027)\nprint(f\u0027Pixel shuffle output:   {tuple(pixshu(x).shape)}\u0027)\nprint(f\u0027Transposed params: {sum(p.numel() for p in transp.parameters()):,}\u0027)\nprint(f\u0027PixelShuffle params: {sum(p.numel() for p in pixshu.parameters()):,}\u0027)"},{"type":"callout","variant":"warning","title":"Always Check Kernel Divisibility","content":"The single most common cause of checkerboard artifacts in GAN generators is using kernel_size=3 with stride=2 in ConvTranspose2d. The fix is either: (1) use kernel_size=4 with stride=2 (divisible), (2) replace with Upsample(scale_factor=2) + Conv2d(3x3), or (3) use PixelShuffle. If your GAN outputs have a faint grid pattern, this is almost certainly the culprit. Check every ConvTranspose2d in your decoder: is k % s == 0?"},{"type":"heading","level":2,"content":"Upsampling Methods Comparison"},{"type":"text","content":"Each upsampling method carries different tradeoffs in learnability, artifact risk, memory, and computational cost. Nearest-neighbour is fastest but produces blocky outputs with sharp transitions. Bilinear is smoother but also fixed. Transposed conv is fully learnable but artifact-prone. Pixel shuffle learns upsampling at low resolution — the most compute-efficient learnable option. In practice, segmentation models (like DeepLabV3+) use bilinear upsampling throughout the decoder for simplicity, while super-resolution models exclusively use pixel shuffle."},{"type":"table","headers":["Method","Learnable","Checkerboard Risk","Memory Use","Main Use Case","Artifact Fix"],"rows":[["Nearest neighbour","No","None","Low","Simple baselines, quick prototyping","N/A"],["Bilinear upsample","No","None","Low","Segmentation decoders (DeepLab)","N/A"],["Transposed conv","Yes","High (if k%s≠0)","Medium","U-Net, DCGAN, VAE decoders","Use k%s==0 or switch method"],["Bilinear + Conv","Partial (conv)","None","Medium","Modern segmentation decoders","N/A — inherently safe"],["Pixel Shuffle","Yes","Low (with ICNR init)","Low (works at LR)","Super-resolution (ESPCN, ESRGAN)","ICNR initialisation"]]},{"type":"list","ordered":false,"items":["output_padding in ConvTranspose2d adds extra rows/cols to resolve ambiguity when stride \u003e 1.","ICNR (Initialisation via Convolutional Neural network Rearrangement) init for pixel shuffle avoids early-training checkerboard.","Progressive growing GANs (ProGAN) add transposed conv layers gradually during training to stabilise.","In segmentation, ASPP (Atrous Spatial Pyramid Pooling) avoids transposed conv entirely by using dilated convs.","nn.Upsample with align_corners=True vs False gives different results — False is recommended for most tasks."]},{"type":"heading","level":2,"content":"Practical Decoder Design Patterns"},{"type":"text","content":"Modern encoder-decoder architectures have converged on a few reliable decoder patterns. FPN (Feature Pyramid Network) uses top-down lateral connections with nearest-neighbour upsampling + 1×1 conv for channel matching, then 3×3 conv for smoothing. This avoids transposed conv entirely and is robust to checkerboard artifacts. U-Net variants for medical imaging often keep transposed conv because high-frequency detail preservation is critical and artifact-free bilinear upsampling discards some learned sharpness."},{"type":"text","content":"For GAN generators, the community has largely moved away from transposed conv in favour of resize+conv (StyleGAN2 uses modulated conv) or pixel shuffle (ESRGAN). The checkerboard artifact is particularly visible in GAN outputs because the discriminator is specifically trained to distinguish real from generated images — any systematic pattern is immediately penalised. Stable Diffusion\u0027s VAE decoder uses nearest-neighbour upsampling followed by ResNet blocks, avoiding transposed conv completely."},{"type":"list","ordered":false,"items":["SegFormer decoder: simple MLP + bilinear upsample — no transposed conv, state-of-the-art segmentation.","ESRGAN generator: pixel shuffle (RRDB blocks) for super-resolution with no checkerboard artifacts.","output_padding parameter in ConvTranspose2d is needed when input size is ambiguous given stride.","ConvTranspose1d and ConvTranspose3d follow the same mechanics — same checkerboard risk applies."]},{"type":"divider"}]"
---
# Transposed Convolution — Upsampling and Checkerboard Artifacts

Encoder-decoder architectures — U-Net for segmentation, DCGAN and StyleGAN generators, super-resolution networks — need to increase spatial resolution in the decoder. Transposed convolution (also called deconvolution or fractionally-strided convolution) is the learnable alternative to fixed upsampling like bilinear or nearest-neighbour interpolation. However, transposed conv is notorious for producing checkerboard artifacts — periodic amplitude patterns caused by uneven kernel overlap. Understanding why this happens and how to avoid it is essential for anyone building generative or dense-prediction models.

## Transposed Convolution Mechanics

A transposed conv with stride s inserts s-1 zeros between each input element along each spatial axis, then applies a standard convolution. This is the transpose of the forward convolution operator in its matrix form. If forward conv is y = Cx, transposed conv computes x̂ = Cᵀy. The output size is: H_out = (H_in - 1)·s - 2p + k. For H_in=4, k=4, s=2, p=1: H_out = (4-1)·2 - 2 + 4 = 8 — exactly doubling. This is the standard configuration in DCGAN and U-Net decoders. The learnable weights give the network freedom to learn the best upsampling filter for the task, unlike fixed bilinear interpolation.

```python
import numpy as np

def transposed_conv1d_scratch(x, kernel, stride=2):
    """1D transposed conv: insert zeros then convolve (no padding)."""
    # Step 1: insert (stride-1) zeros between elements
    x_up = np.zeros((x.shape[0] - 1) * stride + x.shape[0] -
                    (x.shape[0] - 1) * (stride - 1))
    # Simpler: use np repeat trick
    expanded = np.zeros((x.shape[0] - 1) * stride + 1)
    expanded[::stride] = x
    # Step 2: convolve (cross-correlate) with kernel (no flip for CNN)
    k = len(kernel)
    out_len = len(expanded) + k - 1
    output = np.zeros(out_len)
    for i in range(len(expanded)):
        output[i:i+k] += expanded[i] * kernel
    return output

x = np.array([1.0, 2.0, 3.0, 4.0])
kernel = np.array([1.0, 2.0, 1.0])
out = transposed_conv1d_scratch(x, kernel, stride=2)
print(f'Input length:  {len(x)}')
print(f'Kernel length: {len(kernel)}')
print(f'Output length: {len(out)}  (expected: (4-1)*2+1 + 3-1 = 9)')
print(f'Output values: {out}')
print('Zero insertion doubles spacing; kernel blends adjacent elements.')
```

## Checkerboard Artifacts and Their Cause

Checkerboard artifacts arise when kernel_size is not divisible by stride. With k=3, s=2: some output pixels receive contributions from 2 input pixels while others receive from only 1 — a systematic amplitude imbalance that repeats with period s. The result is a spatially periodic intensity pattern visible in GAN-generated images and segmentation masks. Odena et al. (2016) documented this in 'Deconvolution and Checkerboard Artifacts' and showed that any k not divisible by s produces overlap imbalance. Odd k=4 with s=2 is divisible; k=3 with s=2 is not.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import numpy as np

def overlap_pattern(k, s, size=8):
    """Count how many input pixels contribute to each output position."""
    # Use a ones input to count overlaps
    x = torch.ones(1, 1, size, size)
    conv_t = nn.ConvTranspose2d(1, 1, k, stride=s, padding=0, bias=False)
    nn.init.ones_(conv_t.weight)
    with torch.no_grad():
        out = conv_t(x)
    return out[0, 0].numpy()

print('Overlap counts — k=4 s=2 (divisible, uniform):')
ow = overlap_pattern(4, 2, size=4)
print(ow[:8, :8].astype(int))

print('\nOverlap counts — k=3 s=2 (NOT divisible, checkerboard):')
ow = overlap_pattern(3, 2, size=4)
print(ow[:8, :8].astype(int))

print('\nFix: resize then conv (no transposed conv at all):')
def upsample_resize_conv(x_in, C_in, C_out):
    x_up = F.interpolate(x_in, scale_factor=2, mode='bilinear', align_corners=False)
    conv = nn.Conv2d(C_in, C_out, 3, padding=1)
    return conv(x_up)

print('Bilinear + conv = uniform overlap by construction.')
```

## U-Net Decoder — Transposed Conv vs Bilinear+Conv

The original U-Net used transposed conv in the decoder. Modern segmentation models often replace it with bilinear upsampling followed by a 3×3 conv, which avoids checkerboard artifacts with minimal accuracy loss. The tradeoff: transposed conv is fully learnable (can learn non-symmetric upsampling), while bilinear+conv fixes the upsampling to bilinear but lets the conv refine features. For tasks where fine-grained detail matters (e.g., cell boundary segmentation), transposed conv with careful initialisation (bilinear init) can outperform fixed bilinear upsampling. In practice, the choice is often hardware-and-latency-driven.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class UNetDecoder(nn.Module):
    """Compare transposed conv vs bilinear+conv decoder blocks."""
    def __init__(self, C_in, C_out, mode='transpose'):
        super().__init__()
        self.mode = mode
        if mode == 'transpose':
            self.up = nn.ConvTranspose2d(C_in, C_out, kernel_size=2, stride=2)
        else:  # bilinear + conv
            self.up   = nn.Upsample(scale_factor=2, mode='bilinear', align_corners=False)
            self.conv = nn.Conv2d(C_in, C_out, 3, padding=1)
        self.refine = nn.Sequential(
            nn.Conv2d(C_out * 2, C_out, 3, padding=1),  # after skip concat
            nn.BatchNorm2d(C_out), nn.ReLU(inplace=True)
        )

    def forward(self, x, skip):
        x = self.up(x) if self.mode == 'transpose' else self.conv(self.up(x))
        x = torch.cat([x, skip], dim=1)
        return self.refine(x)

for mode in ['transpose', 'bilinear']:
    dec = UNetDecoder(256, 128, mode=mode)
    x = torch.randn(2, 256, 14, 14)
    skip = torch.randn(2, 128, 28, 28)
    out = dec(x, skip)
    p = sum(q.numel() for q in dec.parameters())
    print(f'{mode:<12}: output={tuple(out.shape)}, params={p:,}')
```

## Pixel Shuffle — Sub-Pixel Convolution

Pixel shuffle (sub-pixel convolution, Shi et al. 2016) is an elegant alternative for super-resolution. Instead of inserting zeros and filtering, it applies a standard conv in the low-resolution space to produce C×r²×H×W features, then rearranges (shuffles) the r² channels into a spatial r×r grid: output is C×(H·r)×(W·r). The computation happens entirely at low resolution — far cheaper than operating at high resolution — and the upsampling is fully learned. ESPCN used this for real-time video super-resolution. The key property: no checkerboard artifacts when the preceding conv is initialised correctly (ICNR initialisation).

```python
import torch
import torch.nn as nn

class PixelShuffleUpsample(nn.Module):
    """Sub-pixel convolution for 2x upsampling."""
    def __init__(self, C_in, C_out, scale_factor=2):
        super().__init__()
        # Conv produces C_out * r^2 channels at low resolution
        self.conv = nn.Conv2d(C_in, C_out * scale_factor**2, kernel_size=3, padding=1)
        self.ps   = nn.PixelShuffle(scale_factor)  # rearranges to spatial
        self._init_weights(C_out, scale_factor)

    def _init_weights(self, C_out, r):
        """ICNR init: tile C_out filters to avoid checkerboard at init."""
        kernel = self.conv.weight.data.clone()[:C_out]
        for i in range(r * r):
            self.conv.weight.data[i*C_out:(i+1)*C_out] = kernel

    def forward(self, x):
        return self.ps(self.conv(x))

# Compare transposed conv vs pixel shuffle
C_in, C_out, r = 64, 32, 2
transp = nn.ConvTranspose2d(C_in, C_out, kernel_size=2, stride=2, bias=False)
pixshu = PixelShuffleUpsample(C_in, C_out, scale_factor=r)

x = torch.randn(2, C_in, 14, 14)
print(f'Transposed conv output: {tuple(transp(x).shape)}')
print(f'Pixel shuffle output:   {tuple(pixshu(x).shape)}')
print(f'Transposed params: {sum(p.numel() for p in transp.parameters()):,}')
print(f'PixelShuffle params: {sum(p.numel() for p in pixshu.parameters()):,}')
```

> **Always Check Kernel Divisibility**: The single most common cause of checkerboard artifacts in GAN generators is using kernel_size=3 with stride=2 in ConvTranspose2d. The fix is either: (1) use kernel_size=4 with stride=2 (divisible), (2) replace with Upsample(scale_factor=2) + Conv2d(3x3), or (3) use PixelShuffle. If your GAN outputs have a faint grid pattern, this is almost certainly the culprit. Check every ConvTranspose2d in your decoder: is k % s == 0?

## Upsampling Methods Comparison

Each upsampling method carries different tradeoffs in learnability, artifact risk, memory, and computational cost. Nearest-neighbour is fastest but produces blocky outputs with sharp transitions. Bilinear is smoother but also fixed. Transposed conv is fully learnable but artifact-prone. Pixel shuffle learns upsampling at low resolution — the most compute-efficient learnable option. In practice, segmentation models (like DeepLabV3+) use bilinear upsampling throughout the decoder for simplicity, while super-resolution models exclusively use pixel shuffle.

| Method | Learnable | Checkerboard Risk | Memory Use | Main Use Case | Artifact Fix |
| --- | --- | --- | --- | --- | --- |
| Nearest neighbour | No | None | Low | Simple baselines, quick prototyping | N/A |
| Bilinear upsample | No | None | Low | Segmentation decoders (DeepLab) | N/A |
| Transposed conv | Yes | High (if k%s≠0) | Medium | U-Net, DCGAN, VAE decoders | Use k%s==0 or switch method |
| Bilinear + Conv | Partial (conv) | None | Medium | Modern segmentation decoders | N/A — inherently safe |
| Pixel Shuffle | Yes | Low (with ICNR init) | Low (works at LR) | Super-resolution (ESPCN, ESRGAN) | ICNR initialisation |

- output_padding in ConvTranspose2d adds extra rows/cols to resolve ambiguity when stride > 1.
- ICNR (Initialisation via Convolutional Neural network Rearrangement) init for pixel shuffle avoids early-training checkerboard.
- Progressive growing GANs (ProGAN) add transposed conv layers gradually during training to stabilise.
- In segmentation, ASPP (Atrous Spatial Pyramid Pooling) avoids transposed conv entirely by using dilated convs.
- nn.Upsample with align_corners=True vs False gives different results — False is recommended for most tasks.

## Practical Decoder Design Patterns

Modern encoder-decoder architectures have converged on a few reliable decoder patterns. FPN (Feature Pyramid Network) uses top-down lateral connections with nearest-neighbour upsampling + 1×1 conv for channel matching, then 3×3 conv for smoothing. This avoids transposed conv entirely and is robust to checkerboard artifacts. U-Net variants for medical imaging often keep transposed conv because high-frequency detail preservation is critical and artifact-free bilinear upsampling discards some learned sharpness.

For GAN generators, the community has largely moved away from transposed conv in favour of resize+conv (StyleGAN2 uses modulated conv) or pixel shuffle (ESRGAN). The checkerboard artifact is particularly visible in GAN outputs because the discriminator is specifically trained to distinguish real from generated images — any systematic pattern is immediately penalised. Stable Diffusion's VAE decoder uses nearest-neighbour upsampling followed by ResNet blocks, avoiding transposed conv completely.

- SegFormer decoder: simple MLP + bilinear upsample — no transposed conv, state-of-the-art segmentation.
- ESRGAN generator: pixel shuffle (RRDB blocks) for super-resolution with no checkerboard artifacts.
- output_padding parameter in ConvTranspose2d is needed when input size is ambiguous given stride.
- ConvTranspose1d and ConvTranspose3d follow the same mechanics — same checkerboard risk applies.

---

