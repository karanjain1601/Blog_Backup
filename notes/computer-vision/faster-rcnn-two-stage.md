---
title: "Faster R-CNN: Two-Stage Object Detection"
slug: "faster-rcnn-two-stage"
description: "The Faster R-CNN architecture — Region Proposal Network (RPN), RoI Align, two-stage pipeline, and how to use torchvision's pretrained detection models."
tags: ["computer-vision"]
topic: "computer-vision"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Faster R-CNN is the canonical two-stage object detector, introducing the Region Proposal Network (RPN) to replace the slow selective search algorithm used in R-CNN and Fast R-CNN. The shared convolutional backbone extracts features used by both the RPN and the detection head, dramatically reducing inference time compared to predecessors while maintaining high accuracy."},{"type":"text","content":"The two-stage pipeline separates localization into coarse region proposal (RPN) and fine-grained classification plus refinement (detection head). This decoupling lets the model focus compute on promising regions rather than evaluating every spatial location at every scale. Faster R-CNN achieved roughly 5 FPS on a GPU in 2015, which was state-of-the-art at the time."},{"type":"heading","level":2,"content":"Region Proposal Network (RPN)"},{"type":"text","content":"The RPN slides a small network over the feature map, at each location classifying anchors as object vs. background and regressing box offsets. It outputs objectness scores and bounding box deltas for each anchor. The top-k proposals ranked by objectness after NMS are passed to the detection head — typically 2000 during training and 1000 at inference."},{"type":"text","content":"The RPN shares the backbone with the detection head — this is the key insight of Faster R-CNN. Both networks are trained jointly. The RPN loss combines binary cross-entropy for objectness classification and Smooth L1 for box regression, summed over all positive and sampled negative anchors in the mini-batch. Positive anchors use IoU \u003e= 0.7 with any GT box."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass RPN(nn.Module):\n    def __init__(self, in_channels, num_anchors=9):\n        super().__init__()\n        self.conv = nn.Conv2d(in_channels, 256, 3, padding=1)\n        self.cls  = nn.Conv2d(256, num_anchors * 2, 1)\n        self.reg  = nn.Conv2d(256, num_anchors * 4, 1)\n\n    def forward(self, feat):\n        x = torch.relu(self.conv(feat))\n        cls_logits  = self.cls(x)   # [B, 2*A, H, W]\n        bbox_deltas = self.reg(x)   # [B, 4*A, H, W]\n        return cls_logits, bbox_deltas"},{"type":"heading","level":2,"content":"RoI Pooling vs RoI Align"},{"type":"text","content":"RoI Pooling extracts fixed-size feature maps from variable-size proposals by quantizing proposal boundaries to the nearest feature map cell. This double quantization — once when projecting the proposal to the feature map, again when dividing into grid cells — introduces misalignment errors that hurt accuracy on tasks requiring precise localization like instance segmentation."},{"type":"text","content":"RoI Align eliminates quantization by using bilinear interpolation to sample exactly at fractional feature map coordinates. Each grid cell samples 4 points using bilinear weights. This preserves spatial alignment between input image regions and extracted features, which is critical for instance segmentation and also measurably improves box detection mAP in practice."},{"type":"code","language":"python","content":"import torch\nfrom torchvision.ops import roi_align\n\n# features: [B, C, H, W]; proposals: [K, 5] (batch_idx, x1, y1, x2, y2)\nfeatures = torch.randn(2, 256, 32, 32)\nproposals = torch.tensor([\n    [0, 10.0, 20.0, 50.0, 80.0],\n    [1,  5.0,  5.0, 60.0, 60.0]\n])\n\n# spatial_scale maps image coords to feature map coords (1/stride)\npooled = roi_align(features, proposals, output_size=(7, 7),\n                   spatial_scale=1.0/32, sampling_ratio=2)\nprint(pooled.shape)  # [2, 256, 7, 7]"},{"type":"callout","variant":"info","content":"RoI Align fixed the quantization error in RoI Pooling by using bilinear interpolation — this improved Mask R-CNN\u0027s instance segmentation quality significantly."},{"type":"heading","level":2,"content":"Two-Stage Detection Head"},{"type":"text","content":"The second stage takes RoI-aligned features of shape [K, C, 7, 7] for the top-K proposals, flattens them, and passes them through two fully connected layers. The output branches into a classification head (K+1 softmax over object classes plus background) and a regression head (4 times K box offsets for class-specific refinement of the coarse RPN proposals)."},{"type":"text","content":"Cascade R-CNN extends this idea by stacking multiple detection heads with progressively higher IoU thresholds (0.5, 0.6, 0.7). Each stage refines the proposals from the previous stage. This improves precision at high IoU thresholds without sacrificing recall, outperforming standard Faster R-CNN on COCO especially at strict IoU thresholds like AP75."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass DetectionHead(nn.Module):\n    def __init__(self, in_dim, num_classes):\n        super().__init__()\n        self.fc1 = nn.Linear(in_dim, 1024)\n        self.fc2 = nn.Linear(1024, 1024)\n        self.cls_score = nn.Linear(1024, num_classes + 1)\n        self.bbox_pred = nn.Linear(1024, num_classes * 4)\n\n    def forward(self, roi_feats):\n        x = torch.relu(self.fc1(roi_feats.flatten(1)))\n        x = torch.relu(self.fc2(x))\n        return self.cls_score(x), self.bbox_pred(x)"},{"type":"heading","level":2,"content":"Training the Full Pipeline"},{"type":"text","content":"Faster R-CNN is trained end-to-end by summing four losses: RPN classification (objectness), RPN regression (box offsets), detection head classification (class scores), and detection head regression (refined box offsets). The backbone and RPN share gradients from both stages. PyTorch\u0027s torchvision implementation handles this with a GeneralizedRCNN wrapper class."},{"type":"text","content":"Mini-batch construction samples 256 anchors for the RPN stage (up to 128 positive) and 512 RoIs for the detection stage (up to 25% positive). During training, ground-truth boxes are added to the RoI pool to ensure the detection head always sees positive examples even if the RPN misses some objects early in training — a technique called GT box sampling."},{"type":"text","content":"Data augmentation for detection includes horizontal flipping, random cropping, multi-scale training, and color jitter. The backbone is typically initialized from ImageNet pre-trained weights, and the learning rate for the backbone is often set lower than detection-specific layers to prevent destroying learned representations during the early stages of fine-tuning."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"Faster R-CNN established the template that most subsequent two-stage detectors follow: shared backbone plus proposal network plus RoI feature extraction plus classification and regression head. Understanding this architecture clarifies the design choices in later models like Mask R-CNN, Cascade R-CNN, and Sparse R-CNN, which all build on the same fundamental structure."},{"type":"table","headers":["Model","Proposal Method","Speed (FPS)","mAP (VOC/COCO)","Year"],"rows":[["R-CNN","Selective Search","~0.02","58.5 (VOC)","2014"],["Fast R-CNN","Selective Search","~2","70.0 (VOC)","2015"],["Faster R-CNN","RPN","~5","73.2 (VOC)","2015"],["Cascade R-CNN","RPN (cascaded)","~7","42.8 (COCO)","2018"],["Sparse R-CNN","Learned queries","~22","45.0 (COCO)","2021"]]},{"type":"code","language":"python","content":"import torch\nfrom torchvision.models.detection import fasterrcnn_resnet50_fpn\nfrom torchvision.transforms.functional import to_tensor\nfrom PIL import Image\n\nmodel = fasterrcnn_resnet50_fpn(pretrained=True)\nmodel.eval()\n\nimg = to_tensor(Image.open(\u0027image.jpg\u0027))  # [3, H, W] float32\nwith torch.no_grad():\n    preds = model([img])[0]\n\nprint(preds[\u0027boxes\u0027].shape)   # [N, 4] xyxy\nprint(preds[\u0027labels\u0027].shape)  # [N]\nprint(preds[\u0027scores\u0027].shape)  # [N]"},{"type":"text","content":"For fine-tuning on a custom dataset, replace the classification and regression heads by specifying num_classes in the torchvision constructor. Keep the backbone and FPN frozen for the first few epochs to stabilize training, then unfreeze for end-to-end fine-tuning. Use a batch size of 1-2 images with multiple crops per image to maintain effective mini-batch diversity."}]"
---
# Faster R-CNN: Two-Stage Object Detection

## Overview

Faster R-CNN is the canonical two-stage object detector, introducing the Region Proposal Network (RPN) to replace the slow selective search algorithm used in R-CNN and Fast R-CNN. The shared convolutional backbone extracts features used by both the RPN and the detection head, dramatically reducing inference time compared to predecessors while maintaining high accuracy.

The two-stage pipeline separates localization into coarse region proposal (RPN) and fine-grained classification plus refinement (detection head). This decoupling lets the model focus compute on promising regions rather than evaluating every spatial location at every scale. Faster R-CNN achieved roughly 5 FPS on a GPU in 2015, which was state-of-the-art at the time.

## Region Proposal Network (RPN)

The RPN slides a small network over the feature map, at each location classifying anchors as object vs. background and regressing box offsets. It outputs objectness scores and bounding box deltas for each anchor. The top-k proposals ranked by objectness after NMS are passed to the detection head — typically 2000 during training and 1000 at inference.

The RPN shares the backbone with the detection head — this is the key insight of Faster R-CNN. Both networks are trained jointly. The RPN loss combines binary cross-entropy for objectness classification and Smooth L1 for box regression, summed over all positive and sampled negative anchors in the mini-batch. Positive anchors use IoU >= 0.7 with any GT box.

```python
import torch
import torch.nn as nn

class RPN(nn.Module):
    def __init__(self, in_channels, num_anchors=9):
        super().__init__()
        self.conv = nn.Conv2d(in_channels, 256, 3, padding=1)
        self.cls  = nn.Conv2d(256, num_anchors * 2, 1)
        self.reg  = nn.Conv2d(256, num_anchors * 4, 1)

    def forward(self, feat):
        x = torch.relu(self.conv(feat))
        cls_logits  = self.cls(x)   # [B, 2*A, H, W]
        bbox_deltas = self.reg(x)   # [B, 4*A, H, W]
        return cls_logits, bbox_deltas
```

## RoI Pooling vs RoI Align

RoI Pooling extracts fixed-size feature maps from variable-size proposals by quantizing proposal boundaries to the nearest feature map cell. This double quantization — once when projecting the proposal to the feature map, again when dividing into grid cells — introduces misalignment errors that hurt accuracy on tasks requiring precise localization like instance segmentation.

RoI Align eliminates quantization by using bilinear interpolation to sample exactly at fractional feature map coordinates. Each grid cell samples 4 points using bilinear weights. This preserves spatial alignment between input image regions and extracted features, which is critical for instance segmentation and also measurably improves box detection mAP in practice.

```python
import torch
from torchvision.ops import roi_align

# features: [B, C, H, W]; proposals: [K, 5] (batch_idx, x1, y1, x2, y2)
features = torch.randn(2, 256, 32, 32)
proposals = torch.tensor([
    [0, 10.0, 20.0, 50.0, 80.0],
    [1,  5.0,  5.0, 60.0, 60.0]
])

# spatial_scale maps image coords to feature map coords (1/stride)
pooled = roi_align(features, proposals, output_size=(7, 7),
                   spatial_scale=1.0/32, sampling_ratio=2)
print(pooled.shape)  # [2, 256, 7, 7]
```

> **info**: RoI Align fixed the quantization error in RoI Pooling by using bilinear interpolation — this improved Mask R-CNN's instance segmentation quality significantly.

## Two-Stage Detection Head

The second stage takes RoI-aligned features of shape [K, C, 7, 7] for the top-K proposals, flattens them, and passes them through two fully connected layers. The output branches into a classification head (K+1 softmax over object classes plus background) and a regression head (4 times K box offsets for class-specific refinement of the coarse RPN proposals).

Cascade R-CNN extends this idea by stacking multiple detection heads with progressively higher IoU thresholds (0.5, 0.6, 0.7). Each stage refines the proposals from the previous stage. This improves precision at high IoU thresholds without sacrificing recall, outperforming standard Faster R-CNN on COCO especially at strict IoU thresholds like AP75.

```python
import torch
import torch.nn as nn

class DetectionHead(nn.Module):
    def __init__(self, in_dim, num_classes):
        super().__init__()
        self.fc1 = nn.Linear(in_dim, 1024)
        self.fc2 = nn.Linear(1024, 1024)
        self.cls_score = nn.Linear(1024, num_classes + 1)
        self.bbox_pred = nn.Linear(1024, num_classes * 4)

    def forward(self, roi_feats):
        x = torch.relu(self.fc1(roi_feats.flatten(1)))
        x = torch.relu(self.fc2(x))
        return self.cls_score(x), self.bbox_pred(x)
```

## Training the Full Pipeline

Faster R-CNN is trained end-to-end by summing four losses: RPN classification (objectness), RPN regression (box offsets), detection head classification (class scores), and detection head regression (refined box offsets). The backbone and RPN share gradients from both stages. PyTorch's torchvision implementation handles this with a GeneralizedRCNN wrapper class.

Mini-batch construction samples 256 anchors for the RPN stage (up to 128 positive) and 512 RoIs for the detection stage (up to 25% positive). During training, ground-truth boxes are added to the RoI pool to ensure the detection head always sees positive examples even if the RPN misses some objects early in training — a technique called GT box sampling.

Data augmentation for detection includes horizontal flipping, random cropping, multi-scale training, and color jitter. The backbone is typically initialized from ImageNet pre-trained weights, and the learning rate for the backbone is often set lower than detection-specific layers to prevent destroying learned representations during the early stages of fine-tuning.

## Key Takeaways

Faster R-CNN established the template that most subsequent two-stage detectors follow: shared backbone plus proposal network plus RoI feature extraction plus classification and regression head. Understanding this architecture clarifies the design choices in later models like Mask R-CNN, Cascade R-CNN, and Sparse R-CNN, which all build on the same fundamental structure.

| Model | Proposal Method | Speed (FPS) | mAP (VOC/COCO) | Year |
| --- | --- | --- | --- | --- |
| R-CNN | Selective Search | ~0.02 | 58.5 (VOC) | 2014 |
| Fast R-CNN | Selective Search | ~2 | 70.0 (VOC) | 2015 |
| Faster R-CNN | RPN | ~5 | 73.2 (VOC) | 2015 |
| Cascade R-CNN | RPN (cascaded) | ~7 | 42.8 (COCO) | 2018 |
| Sparse R-CNN | Learned queries | ~22 | 45.0 (COCO) | 2021 |

```python
import torch
from torchvision.models.detection import fasterrcnn_resnet50_fpn
from torchvision.transforms.functional import to_tensor
from PIL import Image

model = fasterrcnn_resnet50_fpn(pretrained=True)
model.eval()

img = to_tensor(Image.open('image.jpg'))  # [3, H, W] float32
with torch.no_grad():
    preds = model([img])[0]

print(preds['boxes'].shape)   # [N, 4] xyxy
print(preds['labels'].shape)  # [N]
print(preds['scores'].shape)  # [N]
```

For fine-tuning on a custom dataset, replace the classification and regression heads by specifying num_classes in the torchvision constructor. Keep the backbone and FPN frozen for the first few epochs to stabilize training, then unfreeze for end-to-end fine-tuning. Use a batch size of 1-2 images with multiple crops per image to maintain effective mini-batch diversity.

