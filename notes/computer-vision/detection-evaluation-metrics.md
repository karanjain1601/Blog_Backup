---
title: "Detection Evaluation: COCO mAP and Metrics"
slug: "detection-evaluation-metrics"
description: "COCO evaluation protocol — mAP@50, mAP@50:95, AP for small/medium/large objects, AR@100, and how to use pycocotools to evaluate a custom detector."
tags: ["computer-vision"]
topic: "computer-vision"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"h2","content":"Overview"},{"type":"text","content":"COCO (Common Objects in Context) defines the standard evaluation protocol for modern object detection. The primary metric is AP50:95 — the mean average precision averaged across 10 IoU thresholds from 0.5 to 0.95. This stricter protocol rewards detectors that localise tightly, not just detectors that find objects approximately."},{"type":"text","content":"Beyond the headline number, COCO reports AP broken down by object scale (small \u003c32², medium 32–96², large \u003e96²), maximum recall at 1/10/100 detections per image, and per-category AP. These diagnostics reveal whether a model fails on tiny objects, crowds, or specific semantic categories."},{"type":"h2","content":"Precision-Recall Curve"},{"type":"text","content":"For a single class at a fixed IoU threshold, evaluation sorts all predictions across all images by confidence (descending). Each prediction is matched to an unmatched ground-truth box — if IoU ≥ threshold it is a true positive, otherwise a false positive. Running P and R are computed cumulatively, tracing the P-R curve."},{"type":"code","lang":"python","content":"import numpy as np\n\ndef precision_recall_curve(scores, tp_flags, n_gt):\n    \"\"\"\n    scores:   (N,) confidence scores\n    tp_flags: (N,) 1 if TP, 0 if FP (sorted by score desc)\n    n_gt:     total ground-truth count for this class\n    \"\"\"\n    order = np.argsort(-scores)\n    tp = tp_flags[order]\n    fp = 1 - tp\n    cum_tp = np.cumsum(tp)\n    cum_fp = np.cumsum(fp)\n    precision = cum_tp / (cum_tp + cum_fp).clip(min=1e-8)\n    recall = cum_tp / max(n_gt, 1)\n    return precision, recall"},{"type":"text","content":"A good detector traces a P-R curve that hugs the top-right corner — high precision even at high recall. Area under this curve (Average Precision) summarises the entire precision-recall trade-off in a single number, independent of any operating point threshold chosen at inference time."},{"type":"h2","content":"mAP@50 vs mAP@50:95"},{"type":"text","content":"mAP@50 (Pascal VOC metric) declares a detection correct if IoU with any ground-truth box exceeds 0.5. A box covering roughly the right area qualifies. mAP@50:95 repeats this at 10 thresholds (0.50, 0.55, …, 0.95) and averages — a box must localise tightly to score well at 0.75 or 0.95."},{"type":"code","lang":"python","content":"import numpy as np\n\ndef compute_ap_101(precision, recall):\n    \"\"\"101-point interpolated AP (COCO style).\"\"\"\n    recall_thresholds = np.linspace(0, 1, 101)\n    ap = 0.0\n    for thr in recall_thresholds:\n        p_at_r = precision[recall \u003e= thr]\n        ap += (p_at_r.max() if p_at_r.size \u003e 0 else 0.0)\n    return ap / 101\n\ndef map_50_95(per_iou_aps):\n    \"\"\"per_iou_aps: list of 10 AP values at IoU 0.5..0.95\"\"\"\n    return float(np.mean(per_iou_aps))"},{"type":"callout","calloutType":"warning","content":"AP50 (Pascal VOC style) is much easier to game than AP50:95 — a model can score 60% AP50 but only 40% AP50:95. Use COCO\u0027s primary metric (AP50:95) for fair comparison."},{"type":"h2","content":"Small / Medium / Large Object AP"},{"type":"text","content":"COCO segments AP by object area: APs (area \u003c 32²=1024 px²), APm (1024–9216 px²), APl (\u003e9216 px²). Small object AP is consistently the hardest metric — detectors struggle because features are low-resolution and context is limited. Improvements on APs usually come from higher input resolution or better FPN design."},{"type":"table","headers":["Metric","IoU threshold","Object size","What it measures"],"rows":[["AP (primary)","0.50:0.05:0.95","All","Overall localisation quality"],["AP50","0.50","All","Coarse detection (VOC style)"],["AP75","0.75","All","Strict localisation"],["APs","0.50:0.95","\u003c 32×32 px","Small object performance"],["APm","0.50:0.95","32–96 px","Medium object performance"],["APl","0.50:0.95","\u003e 96×96 px","Large object performance"],["AR100","0.50:0.95","All","Max recall at 100 dets/img"]]},{"type":"text","content":"AR (Average Recall) at 100 detections per image measures the upper bound on recall given a fixed detection budget. A high AR100 with low AP indicates the model finds objects but ranks them poorly — the confidence calibration or NMS threshold needs tuning."},{"type":"h2","content":"Using pycocotools"},{"type":"text","content":"pycocotools is the official COCO evaluation library. It expects predictions in COCO result format: a JSON array of objects with image_id, category_id, bbox ([x,y,w,h] format), and score. The library handles matching, IoU computation, and all 12 standard metrics in a single evaluate() + summarize() call."},{"type":"code","lang":"python","content":"from pycocotools.coco import COCO\nfrom pycocotools.cocoeval import COCOeval\nimport json\n\n# Load ground truth\ncoco_gt = COCO(\u0027annotations/instances_val2017.json\u0027)\n\n# Load predictions (list of dicts with image_id, category_id, bbox, score)\nwith open(\u0027predictions.json\u0027) as f:\n    pred_list = json.load(f)\n\ncoco_dt = coco_gt.loadRes(pred_list)\neval = COCOeval(coco_gt, coco_dt, iouType=\u0027bbox\u0027)\neval.evaluate()\neval.accumulate()\neval.summarize()  # prints all 12 metrics"},{"type":"text","content":"To evaluate on a subset of categories or images, set eval.params.catIds and eval.params.imgIds before calling evaluate(). Per-category AP requires iterating over categories and setting params.catIds = [cat_id] for each, then reading eval.stats[0] (AP50:95 for that category)."},{"type":"code","lang":"python","content":"from pycocotools.coco import COCO\nfrom pycocotools.cocoeval import COCOeval\n\ndef per_category_ap(coco_gt, coco_dt):\n    results = {}\n    for cat in coco_gt.loadCats(coco_gt.getCatIds()):\n        ev = COCOeval(coco_gt, coco_dt, iouType=\u0027bbox\u0027)\n        ev.params.catIds = [cat[\u0027id\u0027]]\n        ev.evaluate()\n        ev.accumulate()\n        ev.summarize()\n        results[cat[\u0027name\u0027]] = round(float(ev.stats[0]), 4)\n    return results"},{"type":"h2","content":"Key Takeaways"},{"type":"text","content":"Always report AP50:95 as the primary metric for COCO comparisons. AP50 alone overstates model quality. When debugging, APs is the first place to look for headroom — most SOTA models still lag significantly on small objects compared to medium and large ones."},{"type":"text","content":"Confidence calibration matters: a miscalibrated model that ranks FPs above TPs degrades AP without affecting classification accuracy. Temperature scaling or Platt scaling on detector confidence scores can improve AP by 1–3 points without retraining the backbone."},{"type":"text","content":"When comparing custom domain results to COCO benchmarks, note that COCO has 80 categories with heavy long-tail distribution. A model trained on 5 balanced categories may report inflated AP because rare hard negatives are absent. Always contextualise metrics against the evaluation set difficulty."},{"type":"text","content":"AR100 is underutilised in practice but valuable for two-stage pipelines. If your region proposal network is the bottleneck, maximise AR100 of proposals before worrying about the detection head. A proposal AR100 below 90% caps final detector AP regardless of head quality."},{"type":"text","content":"pycocotools supports segmentation (iouType=\u0027segm\u0027) and keypoint (iouType=\u0027keypoints\u0027) evaluation with the same API. Instance segmentation models are evaluated on mask IoU, not box IoU — a common source of confusion when adapting box detectors to segmentation tasks."}]"
---
# Detection Evaluation: COCO mAP and Metrics

COCO (Common Objects in Context) defines the standard evaluation protocol for modern object detection. The primary metric is AP50:95 — the mean average precision averaged across 10 IoU thresholds from 0.5 to 0.95. This stricter protocol rewards detectors that localise tightly, not just detectors that find objects approximately.

Beyond the headline number, COCO reports AP broken down by object scale (small <32², medium 32–96², large >96²), maximum recall at 1/10/100 detections per image, and per-category AP. These diagnostics reveal whether a model fails on tiny objects, crowds, or specific semantic categories.

For a single class at a fixed IoU threshold, evaluation sorts all predictions across all images by confidence (descending). Each prediction is matched to an unmatched ground-truth box — if IoU ≥ threshold it is a true positive, otherwise a false positive. Running P and R are computed cumulatively, tracing the P-R curve.

```
import numpy as np

def precision_recall_curve(scores, tp_flags, n_gt):
    """
    scores:   (N,) confidence scores
    tp_flags: (N,) 1 if TP, 0 if FP (sorted by score desc)
    n_gt:     total ground-truth count for this class
    """
    order = np.argsort(-scores)
    tp = tp_flags[order]
    fp = 1 - tp
    cum_tp = np.cumsum(tp)
    cum_fp = np.cumsum(fp)
    precision = cum_tp / (cum_tp + cum_fp).clip(min=1e-8)
    recall = cum_tp / max(n_gt, 1)
    return precision, recall
```

A good detector traces a P-R curve that hugs the top-right corner — high precision even at high recall. Area under this curve (Average Precision) summarises the entire precision-recall trade-off in a single number, independent of any operating point threshold chosen at inference time.

mAP@50 (Pascal VOC metric) declares a detection correct if IoU with any ground-truth box exceeds 0.5. A box covering roughly the right area qualifies. mAP@50:95 repeats this at 10 thresholds (0.50, 0.55, …, 0.95) and averages — a box must localise tightly to score well at 0.75 or 0.95.

```
import numpy as np

def compute_ap_101(precision, recall):
    """101-point interpolated AP (COCO style)."""
    recall_thresholds = np.linspace(0, 1, 101)
    ap = 0.0
    for thr in recall_thresholds:
        p_at_r = precision[recall >= thr]
        ap += (p_at_r.max() if p_at_r.size > 0 else 0.0)
    return ap / 101

def map_50_95(per_iou_aps):
    """per_iou_aps: list of 10 AP values at IoU 0.5..0.95"""
    return float(np.mean(per_iou_aps))
```

> ****: AP50 (Pascal VOC style) is much easier to game than AP50:95 — a model can score 60% AP50 but only 40% AP50:95. Use COCO's primary metric (AP50:95) for fair comparison.

COCO segments AP by object area: APs (area < 32²=1024 px²), APm (1024–9216 px²), APl (>9216 px²). Small object AP is consistently the hardest metric — detectors struggle because features are low-resolution and context is limited. Improvements on APs usually come from higher input resolution or better FPN design.

| Metric | IoU threshold | Object size | What it measures |
| --- | --- | --- | --- |
| AP (primary) | 0.50:0.05:0.95 | All | Overall localisation quality |
| AP50 | 0.50 | All | Coarse detection (VOC style) |
| AP75 | 0.75 | All | Strict localisation |
| APs | 0.50:0.95 | < 32×32 px | Small object performance |
| APm | 0.50:0.95 | 32–96 px | Medium object performance |
| APl | 0.50:0.95 | > 96×96 px | Large object performance |
| AR100 | 0.50:0.95 | All | Max recall at 100 dets/img |

AR (Average Recall) at 100 detections per image measures the upper bound on recall given a fixed detection budget. A high AR100 with low AP indicates the model finds objects but ranks them poorly — the confidence calibration or NMS threshold needs tuning.

pycocotools is the official COCO evaluation library. It expects predictions in COCO result format: a JSON array of objects with image_id, category_id, bbox ([x,y,w,h] format), and score. The library handles matching, IoU computation, and all 12 standard metrics in a single evaluate() + summarize() call.

```
from pycocotools.coco import COCO
from pycocotools.cocoeval import COCOeval
import json

# Load ground truth
coco_gt = COCO('annotations/instances_val2017.json')

# Load predictions (list of dicts with image_id, category_id, bbox, score)
with open('predictions.json') as f:
    pred_list = json.load(f)

coco_dt = coco_gt.loadRes(pred_list)
eval = COCOeval(coco_gt, coco_dt, iouType='bbox')
eval.evaluate()
eval.accumulate()
eval.summarize()  # prints all 12 metrics
```

To evaluate on a subset of categories or images, set eval.params.catIds and eval.params.imgIds before calling evaluate(). Per-category AP requires iterating over categories and setting params.catIds = [cat_id] for each, then reading eval.stats[0] (AP50:95 for that category).

```
from pycocotools.coco import COCO
from pycocotools.cocoeval import COCOeval

def per_category_ap(coco_gt, coco_dt):
    results = {}
    for cat in coco_gt.loadCats(coco_gt.getCatIds()):
        ev = COCOeval(coco_gt, coco_dt, iouType='bbox')
        ev.params.catIds = [cat['id']]
        ev.evaluate()
        ev.accumulate()
        ev.summarize()
        results[cat['name']] = round(float(ev.stats[0]), 4)
    return results
```

Always report AP50:95 as the primary metric for COCO comparisons. AP50 alone overstates model quality. When debugging, APs is the first place to look for headroom — most SOTA models still lag significantly on small objects compared to medium and large ones.

Confidence calibration matters: a miscalibrated model that ranks FPs above TPs degrades AP without affecting classification accuracy. Temperature scaling or Platt scaling on detector confidence scores can improve AP by 1–3 points without retraining the backbone.

When comparing custom domain results to COCO benchmarks, note that COCO has 80 categories with heavy long-tail distribution. A model trained on 5 balanced categories may report inflated AP because rare hard negatives are absent. Always contextualise metrics against the evaluation set difficulty.

AR100 is underutilised in practice but valuable for two-stage pipelines. If your region proposal network is the bottleneck, maximise AR100 of proposals before worrying about the detection head. A proposal AR100 below 90% caps final detector AP regardless of head quality.

pycocotools supports segmentation (iouType='segm') and keypoint (iouType='keypoints') evaluation with the same API. Instance segmentation models are evaluated on mask IoU, not box IoU — a common source of confusion when adapting box detectors to segmentation tasks.

