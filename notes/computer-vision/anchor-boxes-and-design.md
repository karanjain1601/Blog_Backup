---
title: "Anchor Boxes in Object Detection"
slug: "anchor-boxes-and-design"
description: "Anchor-based detection — anchor design (scales, ratios), anchor assignment (IoU thresholding), regression targets, and the motivation for moving to anchor-free approaches."
tags: ["computer-vision"]
topic: "computer-vision"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Anchor boxes are pre-defined reference rectangles tiled across the feature map. Each spatial location generates a fixed set of anchors with varying scales and aspect ratios. During training, anchors are assigned to ground-truth boxes based on IoU overlap, creating positive samples for boxes the network should predict and negative samples for background regions."},{"type":"text","content":"Anchor design encodes prior knowledge about expected object sizes in the dataset. A typical configuration uses 3 scales (small, medium, large) and 3 aspect ratios (0.5, 1.0, 2.0), producing 9 anchors per location. Given a feature map of size H×W, this yields H×W×9 total anchors — often hundreds of thousands for a single image, requiring efficient batch processing."},{"type":"heading","level":2,"content":"Anchor Generation"},{"type":"text","content":"Anchors are generated relative to each feature map cell, then projected to the input image coordinate space. For a stride-16 feature map, each cell covers a 16×16 pixel region in the original image. Anchor scales are applied to this stride (e.g., 32², 64², 128² pixels), so anchors at each location cover different absolute sizes in the image."},{"type":"text","content":"Feature Pyramid Networks (FPN) address multi-scale detection by generating anchors at multiple pyramid levels. Larger anchors appear at coarser feature levels with larger receptive fields, and smaller anchors at finer levels. This allows a single detector to handle objects spanning several orders of magnitude in size without needing excessively large anchor sets at one level."},{"type":"code","language":"python","content":"import numpy as np\n\ndef generate_anchors(stride, scales, ratios, feat_h, feat_w):\n    anchors = []\n    for y in range(feat_h):\n        for x in range(feat_w):\n            cx = (x + 0.5) * stride\n            cy = (y + 0.5) * stride\n            for s in scales:\n                for r in ratios:\n                    w = s * np.sqrt(1.0 / r)\n                    h = s * np.sqrt(r)\n                    anchors.append([cx-w/2, cy-h/2, cx+w/2, cy+h/2])\n    return np.array(anchors)  # [H*W*num_scales*num_ratios, 4]"},{"type":"heading","level":2,"content":"Anchor Assignment via IoU"},{"type":"text","content":"Anchor assignment determines which anchors participate in training. The assignment rule is IoU-based: anchors with IoU \u003e= 0.7 with any GT box are positive; anchors with IoU \u003c 0.3 with all GT boxes are negative; anchors in between are ignored. Each GT box is also assigned to its highest-IoU anchor to ensure every object has at least one positive training sample."},{"type":"text","content":"Positive anchors learn to predict the GT box they are assigned to. Negative anchors learn to predict background. In practice, positive anchors are rare — for Faster R-CNN, roughly 25% of each mini-batch consists of positive anchors, with the rest randomly sampled negatives. This sampling prevents the gradient from being dominated by the abundant easy negatives."},{"type":"code","language":"python","content":"import numpy as np\n\ndef assign_anchors(anchors, gt_boxes, pos_thr=0.7, neg_thr=0.3):\n    # Returns labels: 1=positive, 0=negative, -1=ignore\n    iou_mat = compute_iou_matrix(anchors, gt_boxes)  # [N_anc, N_gt]\n    max_iou = iou_mat.max(axis=1)\n    assigned_gt = iou_mat.argmax(axis=1)\n\n    labels = np.full(len(anchors), -1)\n    labels[max_iou \u003e= pos_thr] = 1\n    labels[max_iou \u003c neg_thr] = 0\n    # Force-assign the best anchor per GT to ensure coverage\n    best_anc_per_gt = iou_mat.argmax(axis=0)\n    labels[best_anc_per_gt] = 1\n    return labels, assigned_gt"},{"type":"heading","level":2,"content":"Regression Targets"},{"type":"text","content":"Detection heads predict offsets relative to the assigned anchor, not absolute coordinates. Regression targets (delta_x, delta_y, delta_w, delta_h) are normalized by the anchor\u0027s dimensions, making the learning scale-invariant. A network predicting delta_w near 0 means the predicted width equals the anchor width, so predictions initialize near anchor geometry."},{"type":"text","content":"The encoding formula is: dx = (gt_cx - anc_cx) / anc_w, dy = (gt_cy - anc_cy) / anc_h, dw = log(gt_w / anc_w), dh = log(gt_h / anc_h). The log transform prevents negative predictions and stabilizes gradients for large size differences. Smooth L1 loss (Huber) is used instead of MSE to reduce sensitivity to large outliers early in training."},{"type":"code","language":"python","content":"import numpy as np\n\ndef encode_targets(anchors_cxcywh, gt_cxcywh):\n    # Encode GT boxes as deltas relative to matched anchors\n    anc_cx, anc_cy = anchors_cxcywh[:,0], anchors_cxcywh[:,1]\n    anc_w,  anc_h  = anchors_cxcywh[:,2], anchors_cxcywh[:,3]\n    gt_cx,  gt_cy  = gt_cxcywh[:,0], gt_cxcywh[:,1]\n    gt_w,   gt_h   = gt_cxcywh[:,2], gt_cxcywh[:,3]\n\n    dx = (gt_cx - anc_cx) / anc_w\n    dy = (gt_cy - anc_cy) / anc_h\n    dw = np.log(gt_w / anc_w)\n    dh = np.log(gt_h / anc_h)\n    return np.stack([dx, dy, dw, dh], axis=1)"},{"type":"code","language":"python","content":"import numpy as np\n\ndef decode_predictions(anchors_cxcywh, deltas):\n    # Decode predicted deltas back to absolute xyxy boxes\n    anc_cx, anc_cy = anchors_cxcywh[:,0], anchors_cxcywh[:,1]\n    anc_w,  anc_h  = anchors_cxcywh[:,2], anchors_cxcywh[:,3]\n\n    pred_cx = deltas[:,0] * anc_w + anc_cx\n    pred_cy = deltas[:,1] * anc_h + anc_cy\n    pred_w  = np.exp(deltas[:,2]) * anc_w\n    pred_h  = np.exp(deltas[:,3]) * anc_h\n\n    x1 = pred_cx - pred_w / 2\n    y1 = pred_cy - pred_h / 2\n    x2 = pred_cx + pred_w / 2\n    y2 = pred_cy + pred_h / 2\n    return np.stack([x1, y1, x2, y2], axis=1)"},{"type":"heading","level":2,"content":"Limitations of Anchors"},{"type":"text","content":"Anchor-based detectors require careful hyper-parameter tuning. Anchor scales and ratios must be chosen to cover the dataset\u0027s object size distribution — anchors that do not cover GT sizes well lead to poor positive assignment and degraded recall. This makes anchor design dataset-specific: anchors optimal for COCO may be suboptimal for satellite imagery or medical imaging."},{"type":"text","content":"Dense anchor grids introduce severe class imbalance — in a typical FPN detector, fewer than 1% of anchors are positive. This requires either hard negative mining, OHEM (online hard example mining), or focal loss to prevent easy negatives from overwhelming the training signal. Anchor-free detectors like FCOS and CenterNet bypass this issue entirely with different assignment strategies."},{"type":"callout","variant":"info","content":"Anchor design requires careful tuning for each dataset\u0027s object size distribution — this brittleness is why anchor-free detectors (FCOS, DETR) have gained popularity."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"Anchor boxes remain the foundation of many production detectors. Understanding anchor generation, IoU-based assignment, and delta-encoding is essential for debugging training failures, adapting detectors to custom datasets, and extending existing architectures. Anchor-free approaches trade this complexity for different design choices around center-point or pixel-wise prediction."},{"type":"table","headers":["Detector","Anchors/Location","Scales","Ratios","Positive IoU Threshold"],"rows":[["Faster R-CNN","9","3","3","0.7"],["SSD","4-6","4-6","1,2,3","0.5"],["RetinaNet","9","3","3","0.5"],["YOLOv3","3","3 (per level)","1 (clustered)","0.5"],["FCOS","0 (anchor-free)","—","—","N/A"]]},{"type":"text","content":"When adapting an anchor-based detector to a new domain, use k-means clustering on GT box dimensions to find optimal anchor scales and ratios. The YOLOv5 autoanchor script automates this. Alternatively, consider migrating to an anchor-free architecture if the object size distribution is highly varied or difficult to parameterize with a fixed anchor set."},{"type":"text","content":"Regression target normalization — dividing by anchor dimensions, log-transform for sizes — is critical for training stability. Without it, raw pixel coordinates span wildly different ranges, making it hard for the network to learn uniform representations across object scales. Most modern frameworks encode these normalizations into the loss function or data collation pipeline."}]"
---
# Anchor Boxes in Object Detection

## Overview

Anchor boxes are pre-defined reference rectangles tiled across the feature map. Each spatial location generates a fixed set of anchors with varying scales and aspect ratios. During training, anchors are assigned to ground-truth boxes based on IoU overlap, creating positive samples for boxes the network should predict and negative samples for background regions.

Anchor design encodes prior knowledge about expected object sizes in the dataset. A typical configuration uses 3 scales (small, medium, large) and 3 aspect ratios (0.5, 1.0, 2.0), producing 9 anchors per location. Given a feature map of size H×W, this yields H×W×9 total anchors — often hundreds of thousands for a single image, requiring efficient batch processing.

## Anchor Generation

Anchors are generated relative to each feature map cell, then projected to the input image coordinate space. For a stride-16 feature map, each cell covers a 16×16 pixel region in the original image. Anchor scales are applied to this stride (e.g., 32², 64², 128² pixels), so anchors at each location cover different absolute sizes in the image.

Feature Pyramid Networks (FPN) address multi-scale detection by generating anchors at multiple pyramid levels. Larger anchors appear at coarser feature levels with larger receptive fields, and smaller anchors at finer levels. This allows a single detector to handle objects spanning several orders of magnitude in size without needing excessively large anchor sets at one level.

```python
import numpy as np

def generate_anchors(stride, scales, ratios, feat_h, feat_w):
    anchors = []
    for y in range(feat_h):
        for x in range(feat_w):
            cx = (x + 0.5) * stride
            cy = (y + 0.5) * stride
            for s in scales:
                for r in ratios:
                    w = s * np.sqrt(1.0 / r)
                    h = s * np.sqrt(r)
                    anchors.append([cx-w/2, cy-h/2, cx+w/2, cy+h/2])
    return np.array(anchors)  # [H*W*num_scales*num_ratios, 4]
```

## Anchor Assignment via IoU

Anchor assignment determines which anchors participate in training. The assignment rule is IoU-based: anchors with IoU >= 0.7 with any GT box are positive; anchors with IoU < 0.3 with all GT boxes are negative; anchors in between are ignored. Each GT box is also assigned to its highest-IoU anchor to ensure every object has at least one positive training sample.

Positive anchors learn to predict the GT box they are assigned to. Negative anchors learn to predict background. In practice, positive anchors are rare — for Faster R-CNN, roughly 25% of each mini-batch consists of positive anchors, with the rest randomly sampled negatives. This sampling prevents the gradient from being dominated by the abundant easy negatives.

```python
import numpy as np

def assign_anchors(anchors, gt_boxes, pos_thr=0.7, neg_thr=0.3):
    # Returns labels: 1=positive, 0=negative, -1=ignore
    iou_mat = compute_iou_matrix(anchors, gt_boxes)  # [N_anc, N_gt]
    max_iou = iou_mat.max(axis=1)
    assigned_gt = iou_mat.argmax(axis=1)

    labels = np.full(len(anchors), -1)
    labels[max_iou >= pos_thr] = 1
    labels[max_iou < neg_thr] = 0
    # Force-assign the best anchor per GT to ensure coverage
    best_anc_per_gt = iou_mat.argmax(axis=0)
    labels[best_anc_per_gt] = 1
    return labels, assigned_gt
```

## Regression Targets

Detection heads predict offsets relative to the assigned anchor, not absolute coordinates. Regression targets (delta_x, delta_y, delta_w, delta_h) are normalized by the anchor's dimensions, making the learning scale-invariant. A network predicting delta_w near 0 means the predicted width equals the anchor width, so predictions initialize near anchor geometry.

The encoding formula is: dx = (gt_cx - anc_cx) / anc_w, dy = (gt_cy - anc_cy) / anc_h, dw = log(gt_w / anc_w), dh = log(gt_h / anc_h). The log transform prevents negative predictions and stabilizes gradients for large size differences. Smooth L1 loss (Huber) is used instead of MSE to reduce sensitivity to large outliers early in training.

```python
import numpy as np

def encode_targets(anchors_cxcywh, gt_cxcywh):
    # Encode GT boxes as deltas relative to matched anchors
    anc_cx, anc_cy = anchors_cxcywh[:,0], anchors_cxcywh[:,1]
    anc_w,  anc_h  = anchors_cxcywh[:,2], anchors_cxcywh[:,3]
    gt_cx,  gt_cy  = gt_cxcywh[:,0], gt_cxcywh[:,1]
    gt_w,   gt_h   = gt_cxcywh[:,2], gt_cxcywh[:,3]

    dx = (gt_cx - anc_cx) / anc_w
    dy = (gt_cy - anc_cy) / anc_h
    dw = np.log(gt_w / anc_w)
    dh = np.log(gt_h / anc_h)
    return np.stack([dx, dy, dw, dh], axis=1)
```

```python
import numpy as np

def decode_predictions(anchors_cxcywh, deltas):
    # Decode predicted deltas back to absolute xyxy boxes
    anc_cx, anc_cy = anchors_cxcywh[:,0], anchors_cxcywh[:,1]
    anc_w,  anc_h  = anchors_cxcywh[:,2], anchors_cxcywh[:,3]

    pred_cx = deltas[:,0] * anc_w + anc_cx
    pred_cy = deltas[:,1] * anc_h + anc_cy
    pred_w  = np.exp(deltas[:,2]) * anc_w
    pred_h  = np.exp(deltas[:,3]) * anc_h

    x1 = pred_cx - pred_w / 2
    y1 = pred_cy - pred_h / 2
    x2 = pred_cx + pred_w / 2
    y2 = pred_cy + pred_h / 2
    return np.stack([x1, y1, x2, y2], axis=1)
```

## Limitations of Anchors

Anchor-based detectors require careful hyper-parameter tuning. Anchor scales and ratios must be chosen to cover the dataset's object size distribution — anchors that do not cover GT sizes well lead to poor positive assignment and degraded recall. This makes anchor design dataset-specific: anchors optimal for COCO may be suboptimal for satellite imagery or medical imaging.

Dense anchor grids introduce severe class imbalance — in a typical FPN detector, fewer than 1% of anchors are positive. This requires either hard negative mining, OHEM (online hard example mining), or focal loss to prevent easy negatives from overwhelming the training signal. Anchor-free detectors like FCOS and CenterNet bypass this issue entirely with different assignment strategies.

> **info**: Anchor design requires careful tuning for each dataset's object size distribution — this brittleness is why anchor-free detectors (FCOS, DETR) have gained popularity.

## Key Takeaways

Anchor boxes remain the foundation of many production detectors. Understanding anchor generation, IoU-based assignment, and delta-encoding is essential for debugging training failures, adapting detectors to custom datasets, and extending existing architectures. Anchor-free approaches trade this complexity for different design choices around center-point or pixel-wise prediction.

| Detector | Anchors/Location | Scales | Ratios | Positive IoU Threshold |
| --- | --- | --- | --- | --- |
| Faster R-CNN | 9 | 3 | 3 | 0.7 |
| SSD | 4-6 | 4-6 | 1,2,3 | 0.5 |
| RetinaNet | 9 | 3 | 3 | 0.5 |
| YOLOv3 | 3 | 3 (per level) | 1 (clustered) | 0.5 |
| FCOS | 0 (anchor-free) | — | — | N/A |

When adapting an anchor-based detector to a new domain, use k-means clustering on GT box dimensions to find optimal anchor scales and ratios. The YOLOv5 autoanchor script automates this. Alternatively, consider migrating to an anchor-free architecture if the object size distribution is highly varied or difficult to parameterize with a fixed anchor set.

Regression target normalization — dividing by anchor dimensions, log-transform for sizes — is critical for training stability. Without it, raw pixel coordinates span wildly different ranges, making it hard for the network to learn uniform representations across object scales. Most modern frameworks encode these normalizations into the loss function or data collation pipeline.

