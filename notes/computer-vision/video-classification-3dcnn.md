---
title: "Video Classification with 3D CNNs: C3D, I3D, and SlowFast"
slug: "video-classification-3dcnn"
description: ""
tags: [""]
topic: ""
status: ""
updated: ""
blocks_json: "[{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Video classification assigns a semantic label — walking, cooking, playing basketball — to an untrimmed or trimmed video clip. Unlike image classification, the model must aggregate evidence across time: a single frame rarely disambiguates between similar-looking activities. Temporal modeling is therefore the central architectural challenge, and different designs encode fundamentally different inductive biases about motion."},{"type":"text","content":"Early approaches applied 2D CNNs frame-by-frame and pooled predictions, discarding temporal structure entirely. More principled methods model time explicitly: two-stream networks separate RGB and optical flow pathways; 3D CNNs treat video as a spatiotemporal volume; transformer-based methods attend across frame tokens. Dataset scale — Kinetics (400K clips) — proved as important as architecture choice."},{"type":"heading","level":2,"content":"Temporal Modeling Approaches"},{"type":"text","content":"The simplest temporal baseline is late fusion: run a ResNet on each sampled frame, pool logits over time, and classify. Despite its simplicity, late fusion with a strong 2D backbone is competitive on many benchmarks. Single-frame accuracy on Kinetics-400 can reach around 73%, surprisingly close to early 3D models, suggesting 2D models capture contextual scene cues beyond pure temporal motion."},{"type":"text","content":"3D convolutions extend the 2D kernel with a temporal dimension: a 3×3×3 kernel processes a T×H×W spatiotemporal volume jointly. This captures motion patterns directly without explicit optical flow. The cost is cubic in kernel size: a temporal kernel of 3 triples parameter count. Factorized designs like (2+1)D — separate spatial then temporal convolutions — partially address this computational overhead."},{"type":"heading","level":2,"content":"C3D and 3D Convolutions"},{"type":"text","content":"C3D (Tran et al., 2015) was among the first large-scale 3D CNN models, trained on Sports-1M with 3×3×3 convolutions throughout 8 layers. It extracted fc6 activations as 4096-dimensional video descriptors. Despite its 78M parameters and lower accuracy compared to later models, C3D demonstrated that 3D convolutions can learn generic spatiotemporal features transferable across recognition tasks."},{"type":"code","lang":"python","content":"import torch.nn as nn\n\n# 3D conv block: processes T x H x W volumes jointly\n# kernel_size=(3,3,3) has 3x more params than 2D of same spatial size\nconv3d = nn.Conv3d(C_in, C_out,\n                   kernel_size=(3, 3, 3),\n                   stride=(1, 1, 1),\n                   padding=(1, 1, 1),\n                   bias=False)\n\n# Factorized (2+1)D alternative — same accuracy, fewer FLOPs:\nconv_s = nn.Conv3d(C_in,  C_out, (1, 3, 3), padding=(0, 1, 1))\nconv_t = nn.Conv3d(C_out, C_out, (3, 1, 1), padding=(1, 0, 0))"},{"type":"text","content":"C3D\u0027s limitations are significant: 78M parameters, 38 GFLOPs per clip, and fixed 16-frame 112×112 input. It was pretrained on noisily labelled Sports-1M. Later work found depth and width with smaller 3D kernels generalize better than C3D\u0027s design. The shift to Kinetics as the standard benchmark also exposed C3D\u0027s limited spatial resolution and its sensitivity to input clip length."},{"type":"heading","level":2,"content":"Two-Stream and I3D"},{"type":"text","content":"Two-stream networks (Simonyan \u0026 Zisserman, 2014) compute optical flow offline and train two separate CNNs: a spatial stream on RGB frames and a temporal stream on stacked optical flow fields (10 horizontal + 10 vertical channels). Streams are fused at prediction time by averaging softmax scores. The temporal stream\u0027s flow input encodes motion explicitly, complementing the RGB appearance stream."},{"type":"code","lang":"python","content":"def inflate_conv2d_to_3d(conv2d, T=1):\n    \"\"\"Inflate 2D weights to 3D by repeating along the time axis.\"\"\"\n    w2d = conv2d.weight.data           # (C_out, C_in, kH, kW)\n    w3d = w2d.unsqueeze(2)             # (C_out, C_in, 1, kH, kW)\n    w3d = w3d.repeat(1, 1, T, 1, 1)   # (C_out, C_in, T, kH, kW)\n    w3d = w3d / T                      # preserve activation scale\n    kH, kW = conv2d.kernel_size\n    pH, pW = conv2d.padding\n    conv3d = nn.Conv3d(\n        conv2d.in_channels, conv2d.out_channels,\n        (T, kH, kW), padding=(T//2, pH, pW), bias=False\n    )\n    conv3d.weight.data.copy_(w3d)\n    return conv3d"},{"type":"code","lang":"python","content":"def two_stream_inference(spatial_net, temporal_net,\n                         frames, flows, alpha=1.0):\n    # frames: (B, 3, H, W) — single RGB frame or mean-pooled\n    # flows:  (B, 20, H, W) — 10 horizontal + 10 vertical channels\n    rgb_logits  = spatial_net(frames.mean(2))   # mean pool over T\n    flow_logits = temporal_net(flows)\n    rgb_prob    = torch.softmax(rgb_logits,  dim=1)\n    flow_prob   = torch.softmax(flow_logits, dim=1)\n    fused = rgb_prob + alpha * flow_prob          # late fusion\n    return fused.argmax(dim=1)"},{"type":"text","content":"I3D training follows three stages: inflate ImageNet-pretrained weights into 3D, pretrain on Kinetics-400 or 600, then fine-tune on the target dataset. The inflated initialization dramatically accelerates convergence versus random initialization. Two-stream I3D achieves 75.7% on Kinetics-400, a major milestone that set the standard for subsequent video classification models through 2018 and 2019."},{"type":"heading","level":2,"content":"SlowFast Network"},{"type":"text","content":"SlowFast (Feichtenbofer et al., 2019) uses two pathways: a Slow pathway at 8 fps with full channel width, and a Fast pathway at 32 fps with only 1/8 the channels. The Fast pathway captures fine-grained temporal motion cheaply; the Slow pathway focuses on rich semantic features. Lateral connections at each stage fuse temporal information from Fast into Slow, enriching semantic representations with motion cues."},{"type":"code","lang":"python","content":"def slowfast_forward(frames, slow_rate=8, fast_rate=2):\n    # frames: (B, 3, T_full, H, W) — dense temporal sampling\n    slow_frames = frames[:, :, ::slow_rate]   # (B, 3,  8, H, W)\n    fast_frames = frames[:, :, ::fast_rate]   # (B, 3, 32, H, W)\n    slow_feats, laterals = slow_pathway(slow_frames)\n    fast_feats           = fast_pathway(fast_frames)\n    # Lateral connections: fuse motion info from fast into slow\n    for i in range(len(slow_feats)):\n        slow_feats[i] = slow_feats[i] + lateral_conv[i](fast_feats[i])\n    pooled = torch.cat([slow_feats[-1], fast_feats[-1]], dim=1)\n    return classifier_head(pooled)"},{"type":"text","content":"SlowFast avoids optical flow entirely: the Fast pathway learns motion-sensitive features directly from dense RGB frames. At inference, both pathways run simultaneously and their global average-pooled features are concatenated before the classifier head. SlowFast with a ResNet-101 backbone reaches 79% on Kinetics-400, surpassing I3D by over 3% without any optical flow computation at inference time."},{"type":"callout","variant":"tip","content":"SlowFast\u0027s insight: humans process video at two timescales — slow (semantic understanding) and fast (motion). The slow pathway uses 8 frames at full resolution; the fast pathway uses 32 frames at low channel count. Lateral connections let slow receive motion cues from fast."},{"type":"table","headers":["Model","Input","Kinetics-400 Top-1 %","Params (M)","FLOPs (G)","Pretrain"],"rows":[["C3D","16×112²","67.2","78","38","Sports-1M"],["I3D","64×224²","72.1","12","108","ImageNet"],["Two-Stream I3D","RGB+Flow","75.7","25","216","ImageNet"],["SlowFast R50","8+32×224²","77.0","34","65","None"],["SlowFast R101","8+32×224²","79.0","53","213","None"]]},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"3D convolutions are powerful but expensive: 3D ResNets require careful factorization to stay tractable. The (2+1)D decomposition — first a 2D spatial conv then a 1D temporal conv — matches full 3D accuracy while using fewer FLOPs. SlowFast goes further, factorizing temporal sampling rather than kernel shape by operating at two different frame rates in parallel within a shared architecture."},{"type":"text","content":"Optical flow as explicit input has largely been superseded by architectures that learn motion implicitly: SlowFast, TimeSformer, and Video Swin all operate on raw RGB only. Implicit motion learning avoids the overhead of flow estimation — which can cost more than the classifier itself — and lets the model learn task-relevant motion features rather than general-purpose flow displacement fields."},{"type":"text","content":"Dataset scale and label quality matter as much as architecture: Kinetics-400 enabled the ImageNet moment for video understanding. Models pretrained on larger sets — Kinetics-600, Kinetics-700, or JFT — gain 1 to 4% on downstream tasks. Self-supervised pretraining on unlabeled video using masked autoencoding now matches supervised Kinetics pretraining for many fine-grained video recognition benchmarks."}]"
---
# Video Classification with 3D CNNs: C3D, I3D, and SlowFast

## Overview

Video classification assigns a semantic label — walking, cooking, playing basketball — to an untrimmed or trimmed video clip. Unlike image classification, the model must aggregate evidence across time: a single frame rarely disambiguates between similar-looking activities. Temporal modeling is therefore the central architectural challenge, and different designs encode fundamentally different inductive biases about motion.

Early approaches applied 2D CNNs frame-by-frame and pooled predictions, discarding temporal structure entirely. More principled methods model time explicitly: two-stream networks separate RGB and optical flow pathways; 3D CNNs treat video as a spatiotemporal volume; transformer-based methods attend across frame tokens. Dataset scale — Kinetics (400K clips) — proved as important as architecture choice.

## Temporal Modeling Approaches

The simplest temporal baseline is late fusion: run a ResNet on each sampled frame, pool logits over time, and classify. Despite its simplicity, late fusion with a strong 2D backbone is competitive on many benchmarks. Single-frame accuracy on Kinetics-400 can reach around 73%, surprisingly close to early 3D models, suggesting 2D models capture contextual scene cues beyond pure temporal motion.

3D convolutions extend the 2D kernel with a temporal dimension: a 3×3×3 kernel processes a T×H×W spatiotemporal volume jointly. This captures motion patterns directly without explicit optical flow. The cost is cubic in kernel size: a temporal kernel of 3 triples parameter count. Factorized designs like (2+1)D — separate spatial then temporal convolutions — partially address this computational overhead.

## C3D and 3D Convolutions

C3D (Tran et al., 2015) was among the first large-scale 3D CNN models, trained on Sports-1M with 3×3×3 convolutions throughout 8 layers. It extracted fc6 activations as 4096-dimensional video descriptors. Despite its 78M parameters and lower accuracy compared to later models, C3D demonstrated that 3D convolutions can learn generic spatiotemporal features transferable across recognition tasks.

```
import torch.nn as nn

# 3D conv block: processes T x H x W volumes jointly
# kernel_size=(3,3,3) has 3x more params than 2D of same spatial size
conv3d = nn.Conv3d(C_in, C_out,
                   kernel_size=(3, 3, 3),
                   stride=(1, 1, 1),
                   padding=(1, 1, 1),
                   bias=False)

# Factorized (2+1)D alternative — same accuracy, fewer FLOPs:
conv_s = nn.Conv3d(C_in,  C_out, (1, 3, 3), padding=(0, 1, 1))
conv_t = nn.Conv3d(C_out, C_out, (3, 1, 1), padding=(1, 0, 0))
```

C3D's limitations are significant: 78M parameters, 38 GFLOPs per clip, and fixed 16-frame 112×112 input. It was pretrained on noisily labelled Sports-1M. Later work found depth and width with smaller 3D kernels generalize better than C3D's design. The shift to Kinetics as the standard benchmark also exposed C3D's limited spatial resolution and its sensitivity to input clip length.

## Two-Stream and I3D

Two-stream networks (Simonyan & Zisserman, 2014) compute optical flow offline and train two separate CNNs: a spatial stream on RGB frames and a temporal stream on stacked optical flow fields (10 horizontal + 10 vertical channels). Streams are fused at prediction time by averaging softmax scores. The temporal stream's flow input encodes motion explicitly, complementing the RGB appearance stream.

```
def inflate_conv2d_to_3d(conv2d, T=1):
    """Inflate 2D weights to 3D by repeating along the time axis."""
    w2d = conv2d.weight.data           # (C_out, C_in, kH, kW)
    w3d = w2d.unsqueeze(2)             # (C_out, C_in, 1, kH, kW)
    w3d = w3d.repeat(1, 1, T, 1, 1)   # (C_out, C_in, T, kH, kW)
    w3d = w3d / T                      # preserve activation scale
    kH, kW = conv2d.kernel_size
    pH, pW = conv2d.padding
    conv3d = nn.Conv3d(
        conv2d.in_channels, conv2d.out_channels,
        (T, kH, kW), padding=(T//2, pH, pW), bias=False
    )
    conv3d.weight.data.copy_(w3d)
    return conv3d
```

```
def two_stream_inference(spatial_net, temporal_net,
                         frames, flows, alpha=1.0):
    # frames: (B, 3, H, W) — single RGB frame or mean-pooled
    # flows:  (B, 20, H, W) — 10 horizontal + 10 vertical channels
    rgb_logits  = spatial_net(frames.mean(2))   # mean pool over T
    flow_logits = temporal_net(flows)
    rgb_prob    = torch.softmax(rgb_logits,  dim=1)
    flow_prob   = torch.softmax(flow_logits, dim=1)
    fused = rgb_prob + alpha * flow_prob          # late fusion
    return fused.argmax(dim=1)
```

I3D training follows three stages: inflate ImageNet-pretrained weights into 3D, pretrain on Kinetics-400 or 600, then fine-tune on the target dataset. The inflated initialization dramatically accelerates convergence versus random initialization. Two-stream I3D achieves 75.7% on Kinetics-400, a major milestone that set the standard for subsequent video classification models through 2018 and 2019.

## SlowFast Network

SlowFast (Feichtenbofer et al., 2019) uses two pathways: a Slow pathway at 8 fps with full channel width, and a Fast pathway at 32 fps with only 1/8 the channels. The Fast pathway captures fine-grained temporal motion cheaply; the Slow pathway focuses on rich semantic features. Lateral connections at each stage fuse temporal information from Fast into Slow, enriching semantic representations with motion cues.

```
def slowfast_forward(frames, slow_rate=8, fast_rate=2):
    # frames: (B, 3, T_full, H, W) — dense temporal sampling
    slow_frames = frames[:, :, ::slow_rate]   # (B, 3,  8, H, W)
    fast_frames = frames[:, :, ::fast_rate]   # (B, 3, 32, H, W)
    slow_feats, laterals = slow_pathway(slow_frames)
    fast_feats           = fast_pathway(fast_frames)
    # Lateral connections: fuse motion info from fast into slow
    for i in range(len(slow_feats)):
        slow_feats[i] = slow_feats[i] + lateral_conv[i](fast_feats[i])
    pooled = torch.cat([slow_feats[-1], fast_feats[-1]], dim=1)
    return classifier_head(pooled)
```

SlowFast avoids optical flow entirely: the Fast pathway learns motion-sensitive features directly from dense RGB frames. At inference, both pathways run simultaneously and their global average-pooled features are concatenated before the classifier head. SlowFast with a ResNet-101 backbone reaches 79% on Kinetics-400, surpassing I3D by over 3% without any optical flow computation at inference time.

> **tip**: SlowFast's insight: humans process video at two timescales — slow (semantic understanding) and fast (motion). The slow pathway uses 8 frames at full resolution; the fast pathway uses 32 frames at low channel count. Lateral connections let slow receive motion cues from fast.

| Model | Input | Kinetics-400 Top-1 % | Params (M) | FLOPs (G) | Pretrain |
| --- | --- | --- | --- | --- | --- |
| C3D | 16×112² | 67.2 | 78 | 38 | Sports-1M |
| I3D | 64×224² | 72.1 | 12 | 108 | ImageNet |
| Two-Stream I3D | RGB+Flow | 75.7 | 25 | 216 | ImageNet |
| SlowFast R50 | 8+32×224² | 77.0 | 34 | 65 | None |
| SlowFast R101 | 8+32×224² | 79.0 | 53 | 213 | None |

## Key Takeaways

3D convolutions are powerful but expensive: 3D ResNets require careful factorization to stay tractable. The (2+1)D decomposition — first a 2D spatial conv then a 1D temporal conv — matches full 3D accuracy while using fewer FLOPs. SlowFast goes further, factorizing temporal sampling rather than kernel shape by operating at two different frame rates in parallel within a shared architecture.

Optical flow as explicit input has largely been superseded by architectures that learn motion implicitly: SlowFast, TimeSformer, and Video Swin all operate on raw RGB only. Implicit motion learning avoids the overhead of flow estimation — which can cost more than the classifier itself — and lets the model learn task-relevant motion features rather than general-purpose flow displacement fields.

Dataset scale and label quality matter as much as architecture: Kinetics-400 enabled the ImageNet moment for video understanding. Models pretrained on larger sets — Kinetics-600, Kinetics-700, or JFT — gain 1 to 4% on downstream tasks. Self-supervised pretraining on unlabeled video using masked autoencoding now matches supervised Kinetics pretraining for many fine-grained video recognition benchmarks.

