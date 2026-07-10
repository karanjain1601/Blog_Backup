---
title: "Mask R-CNN: Instance Segmentation"
slug: "mask-rcnn-instance"
description: "Mask R-CNN extends Faster R-CNN with a parallel mask prediction head — RoI Align, FCN-based mask branch, multi-task training loss, and applications to COCO instance segmentation."
tags: ["computer-vision"]
topic: "computer-vision"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Mask R-CNN extends Faster R-CNN by adding a third parallel branch that predicts a segmentation mask for each detected object. The model uses a ResNet-FPN backbone for multi-scale features, a Region Proposal Network for candidate boxes, and separate heads for class prediction, bounding box regression, and binary mask output. It achieves state-of-the-art instance segmentation on COCO with practical inference speed."},{"type":"callout","variant":"warning","content":"Mask R-CNN predicts masks independently per class — it does NOT use the predicted class to pick the mask at training time. This avoids competition between classes in the mask head."},{"type":"heading","level":2,"content":"RoI Align for Precise Alignment"},{"type":"text","content":"RoI Pooling quantizes region coordinates to integers, creating spatial misalignment that degrades mask accuracy. RoI Align removes quantization by sampling features at exact floating-point positions using bilinear interpolation. A fixed sampling grid per output cell is computed from the feature map without rounding, preserving spatial accuracy that is essential for the downstream 28x28 mask branch."},{"type":"code","language":"python","content":"import torch\nimport torchvision.ops as ops\n\ndef demo_roi_align(feature_map, boxes):\n    \"\"\"RoI Align: bilinear sampling at exact coords, no quantization error.\"\"\"\n    # feature_map: [B, C, H, W]; boxes: [N, 5] (batch_idx, x1, y1, x2, y2)\n    aligned = ops.roi_align(\n        feature_map,\n        boxes,\n        output_size=(14, 14),\n        spatial_scale=1.0 / 16.0,\n        sampling_ratio=2,\n        aligned=True\n    )\n    return aligned  # [N, C, 14, 14]"},{"type":"text","content":"In practice, RoI Align divides each output cell into a 2x2 or 4x4 sub-grid and samples four bilinear interpolation points per sub-cell, then averages within each cell. The improvement over RoI Pooling is most pronounced for mask quality — Mask R-CNN\u0027s paper reports a 3-point mask AP gain from switching to RoI Align, especially for small or thin objects such as poles and wires."},{"type":"heading","level":2,"content":"Mask Head Architecture"},{"type":"text","content":"The mask head is a small fully convolutional network applied independently to each RoI feature. It consists of four 3x3 convolutional layers with 256 channels and ReLU activations, followed by a transposed convolution to upsample from 14x14 to 28x28, and a 1x1 conv with sigmoid activation. One 28x28 binary mask is predicted per class without class competition in the head."},{"type":"code","language":"python","content":"import torch.nn as nn\n\nclass MaskHead(nn.Module):\n    \"\"\"4x conv3x3 -\u003e deconv -\u003e 1x1; output: [N, num_classes, 28, 28].\"\"\"\n    def __init__(self, num_classes=80):\n        super().__init__()\n        self.convs = nn.Sequential(*[\n            nn.Sequential(nn.Conv2d(256, 256, 3, padding=1), nn.ReLU())\n            for _ in range(4)])\n        self.deconv = nn.ConvTranspose2d(256, 256, 2, stride=2)\n        self.out = nn.Conv2d(256, num_classes, 1)\n    def forward(self, x):\n        x = self.convs(x)\n        x = nn.functional.relu(self.deconv(x))\n        return self.out(x)"},{"type":"text","content":"The 28x28 resolution balances spatial detail against compute cost. At inference, the top-scoring class selects which of the C predicted masks to use; the chosen mask is resized back to the bounding box dimensions using bilinear interpolation and pasted into the full image canvas. Mask prediction and classification remain fully decoupled throughout training and inference, preventing cross-class gradient interference."},{"type":"heading","level":2,"content":"Multi-task Training Loss"},{"type":"text","content":"Mask R-CNN optimizes three losses jointly: cross-entropy classification loss, smooth-L1 bounding box regression loss, and binary cross-entropy mask loss. The total loss is their unweighted sum. Only positive RoIs — those matched to a ground-truth object by IoU threshold — contribute to the mask loss. Negative RoIs contribute only to classification and box regression losses."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef mask_loss(pred_masks, gt_masks, gt_labels, pos_idx):\n    \"\"\"BCE mask loss on GT class channel only, averaged over positive RoIs.\"\"\"\n    pos_pred = pred_masks[pos_idx]       # [P, C, 28, 28]\n    pos_gt   = gt_masks[pos_idx]         # [P, 28, 28] binary float\n    pos_cls  = gt_labels[pos_idx]        # [P] GT class indices\n    # Select predicted mask at the ground-truth class channel\n    sel = pos_cls.view(-1, 1, 1, 1).expand(-1, 1, 28, 28)\n    chosen = pos_pred.gather(1, sel).squeeze(1)  # [P, 28, 28]\n    return F.binary_cross_entropy_with_logits(chosen, pos_gt.float())"},{"type":"text","content":"The binary cross-entropy mask loss is averaged over all pixels in the 28x28 prediction for each positive RoI. Crucially, the loss is computed only on the mask channel corresponding to the ground-truth class, not the predicted class. This design choice prevents gradient interference between class masks, allowing each channel to specialize without competing with others during backpropagation."},{"type":"heading","level":2,"content":"Running Mask R-CNN with torchvision"},{"type":"text","content":"The torchvision library ships Mask R-CNN with a ResNet-50-FPN backbone pretrained on COCO, available via a single model factory call. The pretrained model achieves 37.9 box AP and 34.6 mask AP on COCO minival. For inference, images are passed as a list of tensors; the model returns boxes, labels, scores, and binary masks at 28x28 resolution already resized to each detected box."},{"type":"code","language":"python","content":"import torch\nfrom torchvision.models.detection import maskrcnn_resnet50_fpn, MaskRCNN_ResNet50_FPN_Weights\nimport torchvision.transforms.functional as TF\n\nmodel = maskrcnn_resnet50_fpn(weights=MaskRCNN_ResNet50_FPN_Weights.DEFAULT)\nmodel.eval()\n\nimg_tensor = TF.to_tensor(image_pil).unsqueeze(0)\nwith torch.no_grad():\n    preds = model(img_tensor)[0]\n\nmasks  = preds[\"masks\"][:, 0] \u003e 0.5\nscores = preds[\"scores\"]\nlabels = preds[\"labels\"]\nprint(f\"{(scores \u003e 0.9).sum()} high-confidence detections\")"},{"type":"text","content":"For custom dataset fine-tuning, replace the box predictor and mask predictor heads with new ones matching the number of target classes. Freeze backbone layers during initial training then unfreeze for fine-tuning. The default anchor generator and NMS thresholds work well for most datasets, but adjusting the minimum score threshold at inference significantly affects the number of returned instances."},{"type":"table","headers":["Model","AP (box)","AP (mask)","Backbone","FPS","Year"],"rows":[["Mask R-CNN","38.2","34.7","ResNet-50-FPN","8.8","2017"],["PANet","42.0","37.5","ResNet-50-FPN","4.7","2018"],["HTC","44.9","38.4","ResNet-50-FPN","2.3","2019"],["SOLOv2","39.7","35.5","ResNet-50-FPN","18.0","2020"],["QueryInst","44.5","39.7","ResNet-50-FPN","10.0","2021"]]},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"Mask R-CNN\u0027s key insight is that instance segmentation can be decomposed into detection and segmentation as parallel tasks sharing a backbone. The FPN backbone provides multi-scale features enabling detection across scales. This two-stage approach — first detect then segment — produces high-quality masks by focusing the mask head on already-localized regions rather than full images."},{"type":"text","content":"RoI Align is a critical contribution — the shift from quantized RoI Pooling to bilinear-interpolated sampling may seem minor but yields significant mask quality improvements. Spatial misalignment of even one pixel at the feature level translates to visible artifacts in the upsampled 28x28 mask, especially for small or thin objects such as poles, wires, or pedestrian limbs."},{"type":"text","content":"Multi-task training with a joint loss is crucial for performance. The mask head benefits from the object localization signal provided by the box head, and the box head improves from additional supervision. Jointly training all three tasks produces better shared representations than any single-task model, showing that complementary vision objectives regularize features effectively."},{"type":"text","content":"Mask R-CNN remains a strong baseline for instance segmentation despite being published in 2017. Subsequent advances like PANet, HTC, SOLOv2, and QueryInst improve AP by 5 to 15 points but share its core design principles. Understanding Mask R-CNN is essential for reading modern instance segmentation literature and adapting models to domain-specific applications."}]"
---
# Mask R-CNN: Instance Segmentation

## Overview

Mask R-CNN extends Faster R-CNN by adding a third parallel branch that predicts a segmentation mask for each detected object. The model uses a ResNet-FPN backbone for multi-scale features, a Region Proposal Network for candidate boxes, and separate heads for class prediction, bounding box regression, and binary mask output. It achieves state-of-the-art instance segmentation on COCO with practical inference speed.

> **warning**: Mask R-CNN predicts masks independently per class — it does NOT use the predicted class to pick the mask at training time. This avoids competition between classes in the mask head.

## RoI Align for Precise Alignment

RoI Pooling quantizes region coordinates to integers, creating spatial misalignment that degrades mask accuracy. RoI Align removes quantization by sampling features at exact floating-point positions using bilinear interpolation. A fixed sampling grid per output cell is computed from the feature map without rounding, preserving spatial accuracy that is essential for the downstream 28x28 mask branch.

```python
import torch
import torchvision.ops as ops

def demo_roi_align(feature_map, boxes):
    """RoI Align: bilinear sampling at exact coords, no quantization error."""
    # feature_map: [B, C, H, W]; boxes: [N, 5] (batch_idx, x1, y1, x2, y2)
    aligned = ops.roi_align(
        feature_map,
        boxes,
        output_size=(14, 14),
        spatial_scale=1.0 / 16.0,
        sampling_ratio=2,
        aligned=True
    )
    return aligned  # [N, C, 14, 14]
```

In practice, RoI Align divides each output cell into a 2x2 or 4x4 sub-grid and samples four bilinear interpolation points per sub-cell, then averages within each cell. The improvement over RoI Pooling is most pronounced for mask quality — Mask R-CNN's paper reports a 3-point mask AP gain from switching to RoI Align, especially for small or thin objects such as poles and wires.

## Mask Head Architecture

The mask head is a small fully convolutional network applied independently to each RoI feature. It consists of four 3x3 convolutional layers with 256 channels and ReLU activations, followed by a transposed convolution to upsample from 14x14 to 28x28, and a 1x1 conv with sigmoid activation. One 28x28 binary mask is predicted per class without class competition in the head.

```python
import torch.nn as nn

class MaskHead(nn.Module):
    """4x conv3x3 -> deconv -> 1x1; output: [N, num_classes, 28, 28]."""
    def __init__(self, num_classes=80):
        super().__init__()
        self.convs = nn.Sequential(*[
            nn.Sequential(nn.Conv2d(256, 256, 3, padding=1), nn.ReLU())
            for _ in range(4)])
        self.deconv = nn.ConvTranspose2d(256, 256, 2, stride=2)
        self.out = nn.Conv2d(256, num_classes, 1)
    def forward(self, x):
        x = self.convs(x)
        x = nn.functional.relu(self.deconv(x))
        return self.out(x)
```

The 28x28 resolution balances spatial detail against compute cost. At inference, the top-scoring class selects which of the C predicted masks to use; the chosen mask is resized back to the bounding box dimensions using bilinear interpolation and pasted into the full image canvas. Mask prediction and classification remain fully decoupled throughout training and inference, preventing cross-class gradient interference.

## Multi-task Training Loss

Mask R-CNN optimizes three losses jointly: cross-entropy classification loss, smooth-L1 bounding box regression loss, and binary cross-entropy mask loss. The total loss is their unweighted sum. Only positive RoIs — those matched to a ground-truth object by IoU threshold — contribute to the mask loss. Negative RoIs contribute only to classification and box regression losses.

```python
import torch
import torch.nn.functional as F

def mask_loss(pred_masks, gt_masks, gt_labels, pos_idx):
    """BCE mask loss on GT class channel only, averaged over positive RoIs."""
    pos_pred = pred_masks[pos_idx]       # [P, C, 28, 28]
    pos_gt   = gt_masks[pos_idx]         # [P, 28, 28] binary float
    pos_cls  = gt_labels[pos_idx]        # [P] GT class indices
    # Select predicted mask at the ground-truth class channel
    sel = pos_cls.view(-1, 1, 1, 1).expand(-1, 1, 28, 28)
    chosen = pos_pred.gather(1, sel).squeeze(1)  # [P, 28, 28]
    return F.binary_cross_entropy_with_logits(chosen, pos_gt.float())
```

The binary cross-entropy mask loss is averaged over all pixels in the 28x28 prediction for each positive RoI. Crucially, the loss is computed only on the mask channel corresponding to the ground-truth class, not the predicted class. This design choice prevents gradient interference between class masks, allowing each channel to specialize without competing with others during backpropagation.

## Running Mask R-CNN with torchvision

The torchvision library ships Mask R-CNN with a ResNet-50-FPN backbone pretrained on COCO, available via a single model factory call. The pretrained model achieves 37.9 box AP and 34.6 mask AP on COCO minival. For inference, images are passed as a list of tensors; the model returns boxes, labels, scores, and binary masks at 28x28 resolution already resized to each detected box.

```python
import torch
from torchvision.models.detection import maskrcnn_resnet50_fpn, MaskRCNN_ResNet50_FPN_Weights
import torchvision.transforms.functional as TF

model = maskrcnn_resnet50_fpn(weights=MaskRCNN_ResNet50_FPN_Weights.DEFAULT)
model.eval()

img_tensor = TF.to_tensor(image_pil).unsqueeze(0)
with torch.no_grad():
    preds = model(img_tensor)[0]

masks  = preds["masks"][:, 0] > 0.5
scores = preds["scores"]
labels = preds["labels"]
print(f"{(scores > 0.9).sum()} high-confidence detections")
```

For custom dataset fine-tuning, replace the box predictor and mask predictor heads with new ones matching the number of target classes. Freeze backbone layers during initial training then unfreeze for fine-tuning. The default anchor generator and NMS thresholds work well for most datasets, but adjusting the minimum score threshold at inference significantly affects the number of returned instances.

| Model | AP (box) | AP (mask) | Backbone | FPS | Year |
| --- | --- | --- | --- | --- | --- |
| Mask R-CNN | 38.2 | 34.7 | ResNet-50-FPN | 8.8 | 2017 |
| PANet | 42.0 | 37.5 | ResNet-50-FPN | 4.7 | 2018 |
| HTC | 44.9 | 38.4 | ResNet-50-FPN | 2.3 | 2019 |
| SOLOv2 | 39.7 | 35.5 | ResNet-50-FPN | 18.0 | 2020 |
| QueryInst | 44.5 | 39.7 | ResNet-50-FPN | 10.0 | 2021 |

## Key Takeaways

Mask R-CNN's key insight is that instance segmentation can be decomposed into detection and segmentation as parallel tasks sharing a backbone. The FPN backbone provides multi-scale features enabling detection across scales. This two-stage approach — first detect then segment — produces high-quality masks by focusing the mask head on already-localized regions rather than full images.

RoI Align is a critical contribution — the shift from quantized RoI Pooling to bilinear-interpolated sampling may seem minor but yields significant mask quality improvements. Spatial misalignment of even one pixel at the feature level translates to visible artifacts in the upsampled 28x28 mask, especially for small or thin objects such as poles, wires, or pedestrian limbs.

Multi-task training with a joint loss is crucial for performance. The mask head benefits from the object localization signal provided by the box head, and the box head improves from additional supervision. Jointly training all three tasks produces better shared representations than any single-task model, showing that complementary vision objectives regularize features effectively.

Mask R-CNN remains a strong baseline for instance segmentation despite being published in 2017. Subsequent advances like PANet, HTC, SOLOv2, and QueryInst improve AP by 5 to 15 points but share its core design principles. Understanding Mask R-CNN is essential for reading modern instance segmentation literature and adapting models to domain-specific applications.

