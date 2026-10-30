# Homework: 2D Object Detection — SOTA Evaluation or Open-Source Model Analysis

## Objective

The goal of this homework is to develop a technical understanding of modern 2D object detection. Ref our tutorial as the starting point: [link]

Choose **ONE** track based on your available computing resources:

- **Track A — Experimental Track:** If you have access to a GPU, run and evaluate modern object detection models. Training/fine-tuning is encouraged but not required; meaningful inference and cross-dataset evaluation are acceptable.
- **Track B — Code & Architecture Analysis Track:** If you do not have sufficient GPU resources, perform a detailed technical analysis of real open-source detector implementations.

Track B is **NOT** a simple literature survey. You must inspect actual source code and connect the implementation to the papers and model architecture.

AI tools are allowed and encouraged, but your submission must demonstrate real technical investigation and understanding.

---

## Track A — Experimental Model Evaluation

Choose this track if you have access to a GPU, cloud GPU, or other suitable accelerator.

### Requirements

#### 1. Models

Evaluate at least **3 model configurations** from at least **2 different detector families**.

Examples:

- Faster R-CNN / Mask R-CNN
- RetinaNet / FCOS
- YOLOv8 / YOLO11
- DETR / Deformable DETR / RT-DETR
- Grounding DINO / OWLv2 / YOLO-World

Three sizes of the same model do not count as three detector families.

#### 2. Datasets

Evaluate on at least **2 datasets or domains**.

Recommended datasets include:

- COCO
- KITTI
- nuImages
- nuScenes
- Waymo

A recommended experiment is:

> COCO-pretrained detector → autonomous-driving dataset without retraining

This allows you to study domain shift and generalization.

If datasets use different class definitions, clearly document your label/taxonomy mapping.

#### 3. Metrics

Report appropriate metrics such as:

- mAP@[0.50:0.95]
- AP50 / AP75
- AP small / medium / large
- per-class AP
- AR
- inference latency / FPS
- GPU memory, if measurable

#### 4. Reproducibility

For each major experiment, report:

- model and checkpoint
- dataset and split
- input resolution
- confidence/NMS thresholds
- hardware
- framework/version
- exact command or configuration

Screenshots alone are not sufficient.

#### 5. Technical Analysis

Perform at least **two** of the following:

- **Cross-dataset generalization:** Which classes or object scales degrade most?
- **Architecture comparison:** e.g., YOLO vs. RT-DETR or Faster R-CNN vs. FCOS.
- **Closed-set vs. open-vocabulary:** e.g., YOLO vs. Grounding DINO/YOLO-World.
- **Speed–accuracy tradeoff:** Compare latency, memory, and accuracy.
- **Fine-tuning:** Compare pretrained/zero-shot performance with fine-tuned performance.

---

## Track B — Open-Source Code & Architecture Analysis

Choose this track if you do not have sufficient GPU resources.

This track requires a code-level technical survey, not just paper summaries.

### Requirements

#### 1. Models

Analyze at least **4 models** from at least **3 detector families**.

A good selection might include:

- Faster R-CNN
- FCOS or RetinaNet
- YOLOv8/YOLO11
- DETR/RT-DETR
- Grounding DINO/YOLO-World

Depth is more important than analyzing many models.

#### 2. Study Real Open-Source Implementations

Use official or established repositories such as: official author repositories

For each model, identify:

- paper
- repository
- framework
- main model-definition file/class
- backbone implementation
- neck implementation
- detection head
- loss implementation
- inference/post-processing implementation

Include actual file paths, class names, and important function names.

#### 3. Trace the Model Pipeline

For each model, trace the actual implementation:

```
Image → Backbone → Multi-scale Features → Neck → Detection Head → Loss/Prediction → Post-processing → Final Detections
```

Create your own architecture diagram based on the source code you inspected, not simply a copied paper figure.

#### 4. Analyze the Key Technical Components

Explain and compare:

**Architecture**

- backbone
- FPN/PAN/other neck
- detection head
- anchor-based vs. anchor-free vs. query-based

**Training**

- target assignment
- classification loss
- box regression loss
- focal loss
- IoU/GIoU/CIoU
- Distribution Focal Loss
- Hungarian matching, where applicable

**Inference**

- confidence thresholding
- box decoding
- NMS or NMS-free inference
- top-K selection
- resizing boxes to original coordinates

For open-vocabulary detectors, also trace:

```
Text prompt → text encoder → vision-language interaction → detection score
```

#### 5. Target Assignment Comparison

Compare at least **3** target-assignment strategies, such as:

- anchor/IoU matching
- center sampling
- task-aligned assignment
- Hungarian matching
- query matching

Explain why this is an important difference among detector families.

#### 6. Code-Level Comparison Table

Include a comparison table containing items such as:

| Property | Faster R-CNN | FCOS | YOLO11 | RT-DETR |
|---|---|---|---|---|
| Backbone | | | | |
| Neck | | | | |
| Anchor-based? | | | | |
| Target assignment | | | | |
| Classification loss | | | | |
| Box loss | | | | |
| Object queries? | | | | |
| NMS? | | | | |
| Main source file/class | | | | |

#### 7. One Required Deep Dive

Choose **ONE**:

- **Anchor-based → Anchor-free:** How did target assignment and prediction change?
- **YOLO → DETR:** Why does YOLO typically use NMS while DETR can be NMS-free?
- **DETR → Deformable/RT-DETR:** What changes improve convergence and efficiency?
- **Closed-set → Open-vocabulary:** How is a fixed classification head replaced by text-conditioned detection?

Your explanation must reference actual source code.

#### 8. Source-Code Evidence

Include at least **8 specific code references**, for example:

> Repository → file → class/function → what the code does → why it matters.

Do not simply provide GitHub links or screenshots.

---

## References

For either track, use at least **8 credible technical references**, including:

- at least **4** original research papers
- at least **2** official repositories/framework documentation sources

Foundational papers are acceptable when discussing architectural evolution, but include recent models where appropriate.

## AI Tool Usage

ChatGPT, Claude, Codex, and other AI tools are allowed and encouraged.

Good uses of AI include:

- understanding unfamiliar source code
- locating model components
- comparing a paper with its implementation
- debugging experiments
- generating scripts to inspect tensor shapes
- analyzing unexpected results
- challenging your technical explanation

You are responsible for verifying AI-generated explanations against the actual paper, code, and experimental results.

## Submission

Submit one PDF as either:

- a 6–10 page technical report, or
- a 15–25 slide technical presentation.

### Track A should include:

- Models and datasets
- Experimental setup and hardware
- Commands/configurations
- Quantitative results
- At least two technical analyses
- Failure analysis
- Conclusions
- References

Also submit/link your experiment code, configuration, or command log.

### Track B should include:

- Detector evolution/taxonomy
- Selected papers and repositories
- Code-derived architecture diagrams
- Backbone/neck/head analysis
- Loss and target-assignment analysis
- Inference/post-processing analysis
- Code-level comparison table
- One deep-dive topic
- At least 8 specific source-code references
- Conclusions
- References

## Minimum Quality Requirement

**Track A:** You must provide evidence that you actually ran the experiments. Copied benchmark numbers or detection screenshots alone are not sufficient.

**Track B:** You must provide evidence that you actually inspected the source code. AI-generated paper summaries, copied architecture diagrams, benchmark tables, or lists of GitHub links are not sufficient.

I am not grading based on who has the most powerful GPU.

For Track A, the key question is:

> Can you design, reproduce, and critically analyze a meaningful object-detection experiment?

For Track B:

> Can you read a modern deep-learning codebase and connect the implementation to the ideas described in the paper?

Both tracks require real technical understanding.
