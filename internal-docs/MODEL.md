# Model documentation

## Status in this repository

**The app ships an ensemble of two bundled models** (see "Ensemble (shipped)"):
`ai-image-detector.onnx` (35.2 MB) and `commfor-224.onnx` (Community Forensics ViT-S 224,
MIT, 43.5 MB), both with fp16-stored weights and fp32 math. If the second file is missing
or fails to load, the first runs alone with its own calibration.

**The primary classifier model is bundled.** `app/src/main/assets/models/ai-image-detector.onnx`
is committed to the repository: the `Dafilab/ai-image-detector` model
below, exported to ONNX (export steps in "Replacing the model file"). It loads and runs on real
devices — debug logs show output like
`Classifier raw output=[[-3.787038, 2.1529553]] -> P(ai)=0.0026`, i.e. the graph
accepts the `pixel_values` input and emits two raw logits. If the file is ever
missing from a build, `AIImageClassifierProvider` honestly reports the
`AI_CLASSIFIER` signal as unavailable rather than fabricating a score.

Accuracy has been measured, and scores are calibrated and bands set from data (see
"Measured accuracy"). `ModelConfig.BASE_CONFIDENCE`, which weighs the classifier
against the other signals, is still a fixed value.

**`Dafilab/ai-image-detector` is a gated repo on Hugging Face** — confirmed by
actually running the conversion: a plain download gets a `401 GatedRepoError`, even
though the model itself is public and Apache-2.0 licensed. You must be logged in
*and* have clicked through the access request on the model page before downloading
works (see step 1 in "Replacing the model file"). Its `config.json` is also not in
`timm`'s hub-config format (`timm.create_model("hf_hub:...")` fails with
`KeyError: 'architecture'`) — the repo instead publishes a raw training checkpoint,
`pytorch_model.pth` (71MB, renamed at some point from `model_epoch_8_acc_0.9859.pth`
— that "acc_0.9859" is the model author's own training/validation accuracy, not an
independently verified number; still worth running `tools/evaluate.py` yourself).
`tools/convert_model.py` downloads that checkpoint directly, builds a bare
`efficientnet_b4` architecture, and loads the checkpoint's weights into it, handling
the couple of common checkpoint-dict shapes a training script might have saved
(bare state dict, or wrapped under a `state_dict`/`model_state_dict` key).

## The target model

| Field | Value |
|---|---|
| Name | `Dafilab/ai-image-detector` |
| Source | https://huggingface.co/Dafilab/ai-image-detector |
| Architecture | EfficientNet-B4 (via `timm`) |
| License | Apache-2.0 (permits commercial use) |
| Task | Binary classification: human-made vs. AI-generated image |
| Native input size | 380×380 RGB |

### Why this model

The project brief requires a classifier that (a) permits commercial use, (b) is
mobile-viable or convertible to ONNX/TFLite, (c) has a clearly documented license,
and (d) doesn't require a hosted inference service. Two candidates were evaluated:

- **`Organika/sdxl-detector`** / **`umm-maybe/AI-image-detector`** — well-known,
  reasonably accurate community detectors, but licensed **CC-BY-NC** (non-commercial).
  Disqualified outright by the commercial-use requirement.
- **`Dafilab/ai-image-detector`** (chosen) — Apache-2.0, EfficientNet-B4. Meaningfully
  smaller and faster than transformer-based alternatives (e.g. a SwinV2-Base export
  of `haywoodsloan/ai-image-detector-deploy`, also Apache-2.0 but ~4× the parameter
  count and slower on-device), while still being a real, general-purpose AI-image
  classifier rather than a narrow single-generator detector.

No independent accuracy benchmark of this specific model was run as part of this
project (see "Known limitations" below and `tools/evaluate.py`).

### Expected input

- 380×380 RGB, resized (not center-cropped) from the normalized image.
- Pixel values scaled to `[0, 1]`, then normalized with the standard ImageNet
  statistics `timm` models default to:
  - mean = `[0.485, 0.456, 0.406]`
  - std = `[0.229, 0.224, 0.225]`
- Layout: `NCHW`, i.e. tensor shape `[1, 3, 380, 380]`.

These exact values live in one place in the code:
`app/src/main/kotlin/com/genned/app/data/detection/classifier/ModelConfig.kt`, and
are duplicated in `tools/evaluate.py` for the offline evaluation harness — keep both
in sync if you change them.

### Output interpretation

The ONNX export emits the classifier head's **raw logits** (the output tensor is
named `logits`; timm's `efficientnet_b4` has no softmax layer), so
`ModelConfig.interpretOutput` applies the softmax itself:
- a 2-class output `[ai_logit, human_logit]` → `P(ai) = sigmoid(ai_logit - human_logit)`, or
- a single raw logit → `P(ai) = sigmoid(logit)`.

An earlier version "normalized" with `ai / (ai + human)`, which is not a softmax:
whenever both logits were negative — an entirely ordinary output — a `total <= 0`
guard forced exactly `0.5`, so confident predictions were displayed as a flat 50%.
Found on-device with the real bundled model; `ModelConfigTest` now pins the exact
failing input.

**This label order is now confirmed**, not guessed: the real `config.json` on
`Dafilab/ai-image-detector` publishes `"label_mapping": {"0": "ai", "1": "human"}`
directly, i.e. output index 0 = P(ai). An earlier version of this file/code assumed
the reverse (`[human, ai]`), which would have silently inverted every result — caught
before the model was bundled, precisely because this doc insisted on confirming it
rather than trusting the initial guess. The bundled export runs with
`ModelConfig.INPUT_NAME = "pixel_values"` and a 2-logit output. If you replace the
model:
1. Open the new export in [Netron](https://netron.app) and confirm the input tensor
   name and output shape.
2. Update `ModelConfig.kt` if the input name differs, or if a future model version's
   `config.json` changes `label_mapping`.

### Model size

The full-precision export is 70.1 MB. The app ships it with fp16-stored weights
(`tools/fp16_weights.py`: weights stored as fp16 and cast back to fp32 at load, so
all math stays fp32), which is 35.2 MB. The logit gap moves by at most 0.022
(mean 0.007) on real dataset images, which is negligible after calibration
(slope 0.23). Dynamic int8 quantization broke this model (logit gaps off by up to
35), so it is not used.

### Known limitations

- **Moderate accuracy, overconfident raw scores.** See "Measured accuracy": AUC
  0.91 / 0.80 on two public datasets, with about a third of real images in the
  second one scored as AI. Its raw probabilities are far too extreme to show
  as-is.
- **Training data cutoff.** Like all AI-image detectors, this model's training data
  has a cutoff; it will be systematically weaker against generators released after
  that point (a fundamental limitation of every classifier-based approach, not
  specific to this model).
- **Vulnerable to adversarial pressure.** Compression, screenshotting, resizing, and
  intentional adversarial perturbation can all degrade classifier accuracy in either
  direction (false positive or false negative).
- **Binary, single-signal.** It does not identify *which* generator produced an
  image, and (per this app's design) its output is never treated as proof on its
  own — see `internal-docs/ARCHITECTURE.md`'s evidence-aggregation model.

## Measured accuracy

The `Model eval` GitHub Actions workflow (`.github/workflows/model-eval.yml`,
manual trigger only: Actions → Model eval → Run workflow) benchmarks the bundled
`.onnx` against public labeled datasets. It runs on GitHub's runners because they
have the open internet access (Hugging Face) that a sandboxed dev environment may not.

- `tools/fetch_eval_data.py` streams a seeded, balanced sample (default 250 real +
  250 AI per dataset, AI spread across generators) and writes the original file
  bytes into `real/` and `ai/<generator>/`. Labels are never guessed: ambiguous
  label columns fail loudly with the dataset's features printed.
- `tools/evaluate.py` scores every image under 3 conditions × 2 preprocessing
  modes. Conditions: `original`; `jpeg75`; and `social`, which caps the long edge at
  1080 and applies JPEG q75, like an Instagram re-upload. Every condition then gets
  the app's own normalization: long edge ≤2048 and JPEG q92, same as `ImageLoader`.
  Preprocessing modes: `squash`, the app's current straight resize to 380×380, and
  `center_crop`.
  It reports AUC, accuracy/FPR/FNR at 0.5, the share of real/AI images landing
  in each app band (LOW/UNCERTAIN/HIGH), calibration (ECE + reliability table) and
  per-generator results.
- `tools/eval_report.py` merges the per-run JSON into the job summary and the
  `model-eval-results` artifact. Only numbers leave the runner, never images.

Datasets: `Rajarshi-Roy-research/Defactify_Image_Dataset` (MS-COCO real photos;
SD 2.1, SDXL, SD3, DALL-E 3, Midjourney v6) and
`julienlucas/midjourney-dalle-sd-nanobananapro-dataset`. Caveats:
- If the model was trained on either dataset, its numbers there are inflated.
- Defactify's `Label_B` id → generator-name order follows the dataset card's
  listing order and isn't independently verified. Only `0 = real` is checked,
  against `Label_A`.
- Neither dataset covers what the overlay actually captures, which is a
  phone-screen crop of an Instagram post. `social` only approximates it.

### Baseline: first run (2026-09-25, [run 36171690452](https://github.com/as791/genned/actions/runs/36171690452))

250 real + 250 AI images per dataset, raw (uncalibrated) scores, app preprocessing
(`squash`). "Real shown HIGH" / "AI shown LOW" use the app's bands at the time
(LOW <30%, HIGH ≥70%).

| Dataset | Condition | AUC | Accuracy @0.5 | Real→AI (FPR) | AI missed (FNR) | Real shown HIGH | AI shown LOW | ECE | Scores >99% or <1% |
|---|---|---|---|---|---|---|---|---|---|
| Defactify | original | 0.914 | 83.0% | 10.0% | 24.0% | 8.0% | 22.0% | 0.132 | 64.0% |
| Defactify | social | 0.915 | 82.8% | 10.0% | 24.4% | 7.6% | 21.6% | 0.127 | 64.6% |
| MJ/DALL·E/SD/NBP | original | 0.795 | 72.0% | 36.4% | 19.6% | 33.6% | 15.6% | 0.222 | 60.0% |
| MJ/DALL·E/SD/NBP | social | 0.770 | 69.8% | 40.8% | 19.6% | 38.8% | 16.8% | 0.247 | 58.4% |

Findings:
- **Overconfident.** 60–74% of scores are above 99% or below 1%. Scores above 90%
  are actually AI 93% (Defactify) / 72% (other set) of the time, and scores below
  10% are still AI 18% of the time.
- **Real photos are often flagged.** On the second set about a third of real
  images land in HIGH.
- **Compression barely matters.** `jpeg75`/`social` are within about 3 AUC
  points of `original`. The Instagram re-upload isn't the main problem.
- **Center crop is mixed.** Defactify AUC goes 0.914 → 0.964 and FPR 10% → 5.2%.
  The other set is unchanged or slightly worse (0.795 → 0.794 original,
  0.748 → 0.722 jpeg75).
- **Per generator** (detected at 0.5, original): Midjourney v6 86%, SDXL 82%,
  SD 2.1 80%, SD3 76%, **DALL·E 3 56%**.

### Calibration and preprocessing (shipped, [run 36185656205](https://github.com/as791/genned/actions/runs/36185656205))

- **Preprocessing: two views averaged.** The app runs the model on the whole
  image squashed to 380×380 *and* on an aspect-preserving center crop, then
  averages the two logit gaps. AUC: Defactify 0.952 vs 0.915 (squash only), the
  harder set 0.773 vs 0.771. The adoption rule was "at least as good as squash on
  both datasets". Cost: 2 inferences per image.
- **Calibration:** `P(ai) = sigmoid(0.2252 · (ai − human) + 0.0494)` (Platt scaling
  on 3,000 per-image scores, all datasets and conditions pooled). Scores above 99%
  or below 1% drop from 58–71% of images to about 1%. ECE drops from 0.125/0.247 to
  0.102/0.081 (pooled fit). A fit on one dataset alone transfers only partly to the
  other (ECE 0.161/0.205), so treat the percentages as approximate.
- **Bands** (`EvidenceWeights`): **HIGH ≥ 90%, LOW < 25%**, UNCERTAIN in between
  (LOW later moved to < 15% for the ensemble, see "Ensemble (shipped)").
  Worst case over every dataset × condition: **2.8% of real images shown HIGH**
  (was up to 38.8% with the old 70% band) and **8.0% of AI images shown LOW**.
  Accepted cost: many images now read UNCERTAIN. That's the honest answer for a
  detector with AUC 0.77 on the harder set, and only a better model (Phase 1 model
  comparison) can shrink the UNCERTAIN band.
- Example: the on-device output `[[4.50, -3.50]]` that used to read 99.97% now reads
  86% (UNCERTAIN).
- `tools/evaluate.py --preprocess avg --calibration app` reproduces the app as
  shipped. The `Model eval` report includes it as the "app as shipped" rows.

**Verified** ([run 36187349202](https://github.com/as791/genned/actions/runs/36187349202),
app exactly as shipped):

| Dataset | AUC | Real shown HIGH | AI shown LOW | ECE | Scores >99% or <1% |
|---|---|---|---|---|---|
| Defactify (original / jpeg75 / social) | 0.951–0.952 | 0.0% | 6.4% | 0.102 | 1.0% |
| MJ/DALL·E/SD/NBP (original / jpeg75 / social) | 0.744–0.803 | 2.4–2.8% | 3.6–8.0% | 0.088–0.093 | 0.0% |

AUC is identical to the uncalibrated two-view scores, as it must be, since
calibration only rescales scores and doesn't reorder them. The false-HIGH target
(≤5%) holds in every condition.

### Candidate detectors: first comparison ([run 36186295441](https://github.com/as791/genned/actions/runs/36186295441))

Same images and conditions. Each candidate uses its own preprocessing, and its
scores are raw.

| Model | Defactify AUC | MJ/DALL·E/SD/NBP AUC | Real passed @0.5 | AI caught @0.5 (harder set) |
|---|---|---|---|---|
| Bundled (as shipped) | 0.951 | 0.744–0.803 | 94% / 56–60% | 74–84% |
| Community Forensics ViT-S 224 (MIT) | 0.959–0.960 | 0.624–0.708 | 99% | 10–15% |
| Community Forensics ViT-S 384 (MIT) | 0.941 | 0.520–0.589 | 99.6% | 9–14% |

Community Forensics almost never flags a real image, but it misses most AI
images in the harder set. It's not a replacement on its own. Its errors do
complement the bundled model's (for example, it catches 76% of DALL·E 3 vs 56%),
which is what the ensemble analysis tests. The SigLIP and dima806 candidates
didn't run in this pass because of a tooling bug that has since been fixed (a
`'hum'` label crashed the script).

### Video: the Reels path ([run 36187968201](https://github.com/as791/genned/actions/runs/36187968201))

This is the app's exact pipeline: 5 frames per video, two views per frame,
calibrated, and the per-frame probabilities averaged. 60 real + 60 AI videos per
dataset.

| Dataset | AUC | Real shown HIGH | AI shown LOW | Mean score, real videos | AI caught @0.5 |
|---|---|---|---|---|---|
| [DF26](https://huggingface.co/datasets/DF26/DF26) (2026 talking heads: Veo 3.1, Kling 3.0, Wan 2.6, Grok Imagine, HunyuanVideo 1.5, LTX 2.3…) | **0.646** | **28.3%** | 0% | 0.83 | 100% |
| [DeepAction](https://huggingface.co/datasets/faridlab/deepaction_v1) (actions: Veo, RunwayML, CogVideoX, AnimateDiff, VideoPoet, SD) | 0.797 | 3.3% | 0% | 0.65 | 98% |

**The image model reads real video frames as AI-like.** Compression, motion blur
and talking-head framing all push real videos up. The image calibration doesn't
carry over to video, so about 1 in 4 real talking-head clips showed HIGH.

### Video: all models + video calibration ([run 36190406439](https://github.com/as791/genned/actions/runs/36190406439))

100 real + 100 AI videos per dataset, the same 5 sampled frames for every model.
Candidates use raw scores.

| Model | AUC DeepAction | AUC DF26 | Real videos shown HIGH (DA / DF26) | AI caught at ≤5% false alarms (worst dataset) |
|---|---|---|---|---|
| Bundled (image-calibrated, before this fix) | 0.789 | 0.651 | 2% / 26% | 21% |
| Community Forensics ViT-S 224 (MIT) | **0.970** | **0.743** | 0% / 0% | 33% |
| Community Forensics ViT-S 384 (MIT) | 0.944 | 0.730 | 0% / 2% | 19% |
| Ateeqq SigLIP | 0.645 | 0.691 | 43% / 99% | 18% |
| dima806 ViT | 0.496 | 0.543 | 33% / 27% | 5% |

The best video ensemble is commfor-224 + commfor-384 (mean): 38% of AI caught at
≤5% false alarms, and 39% with SigLIP added.

**Shipped video calibration.** `VideoSignalAggregator` now averages the frames'
logit gaps (inverting the image calibration) and applies
`P(ai) = sigmoid(0.2071 · meanGap − 1.3977)`. This was fit on the bundled
model's per-video mean frame gap. The calibration error (ECE) goes from
0.36 / 0.49 raw to 0.14 / 0.20 when fit on the other dataset only, and to
0.09 pooled. At the global bands (HIGH ≥ 90%, LOW < 25%), the worst case is
**0% of real videos shown HIGH** and 3% of AI videos shown LOW. The honest
consequence is that with this model a video almost never reads HIGH. That
takes near-certain frames (mean image score about 0.98+), and no benchmark
video, real or AI, got there. Example: a real talking-head clip whose frames
average 0.83 now reads about 50% (UNCERTAIN) instead of HIGH. Actually catching
AI video needs a better video model; see the comparison above.

### Ensemble (shipped, [Ensemble build run 36196623887](https://github.com/as791/genned/actions/runs/36196623887))

The app now combines the bundled model with **Community Forensics ViT-S 224**
([OwensLab/commfor-model-224](https://huggingface.co/OwensLab/commfor-model-224), MIT,
CVPR 2025). The two models make different mistakes: the bundled model catches more
AI photos, while Community Forensics is much stronger on video and rarely flags real
content. Every number below comes from the exact ONNX files the app bundles.

`EnsembleConfig`:
`s = ((gap − μd)/σd + (cf − μc)/σc) / 2` is the mean of both models' standardized
logits, with standardization fit on photo scores. Photos use
`P = sigmoid(3.1935·s + 0.1634)`. Video uses `P = sigmoid(3.4921·mean(s) − 1.8588)`
over the 5 sampled frames. Python mirror: `tools/evaluate.py` `APP_ENSEMBLE`.

| | Bundled alone | Community Forensics alone | **Ensemble** |
|---|---|---|---|
| Photos AUC (Defactify / MJ-DALL·E-SD-NBP) | 0.952 / 0.773 | 0.959 / 0.654 | **0.991 / 0.778** |
| Photos: AI caught at 5% false alarms | 73.2% / 29.7% | 83.3% / 22.8% | **94.8% / 33.9%** |
| Video AUC (DeepAction / DF26) | 0.793 / 0.651 | 0.970 / 0.743 | 0.958 / **0.746** |
| Video: AI caught at 5% false alarms | 41% / 21% | 70% / 33% | **82%** / 30% |
| **Worst case over photos and video** | 21% | 22.8% | **30%** |

- **Bands.** HIGH stays at ≥ 90%. In the worst case, 2.8% of real photos and 2.0%
  of real videos show HIGH (target ≤ 5%). LOW moved from < 25% to **< 15%**: at
  25%, 17.6% of AI photos and 17% of AI videos read LOW. At 15% that is 10.0% and
  9.0% (target ≤ 10%). That value is the calibration's own recommendation for
  both photos and video.
- **Parity** (40 images).
  - Community Forensics, authors' PyTorch pipeline vs the app's preprocessing plus
    ONNX: max logit difference 0.0001. That needed torchvision's exact geometry:
    Resize truncates the long side, CenterCrop rounds half-to-even.
  - fp16 vs fp32 weights: 0.022 for the bundled model, 0.014 for Community
    Forensics.
  - Both files load in the app's ONNX Runtime 1.19 (IR 8, opset 17).
- **Cost.** 3 model runs per check: 2 views for the bundled model, 1 for Community
  Forensics. The models grow from 70.1 MB to 78.7 MB in total (+8.6 MB).
- **Still limited on talking-head video.** DF26 AUC is 0.746, and some generators
  (LTX, Hunyuan) fool both models.

### Adversarial robustness (Phase 2, #15)

`tools/adv_eval.py` attacks a differentiable copy of the exact app pipeline. The
copy is checked against the shipped files before any number counts:
- the fp16 model files, converted with onnx2torch after
  `fp16_weights.restore_fp32`;
- the app's JPEG q92 and its Pillow resize inside the forward pass, with
  gradients passed straight through;
- parity with ONNX Runtime: 1e-5 for the bundled model and 2e-6 for Community
  Forensics.

Attacks:
- white-box: FGSM, PGD with EOT, and a PGD adapted to the defense;
- transfer from the bundled model alone, i.e. an attacker who knows one of the
  two models;
- black-box Square Attack, 200 queries.

*Evasion* means an AI image shown LOW. *Framing* means a real image shown HIGH.
*Laundered* means the result is re-scored after JPEG q75.

**The shipped ensemble** ([run 36227004230](https://github.com/as791/genned/actions/runs/36227004230)):
60 AI + 60 real attacked images, 300 clean, 30 for Square.

| At 8/255 | No defense (3 model runs) | Consistency check (6 runs) |
|---|---|---|
| Clean AUC / real shown HIGH / AI shown LOW | 0.903 / 0.7% / 11.3% | same |
| Clean real photos abstained, attack harness | 0% | 8.0% |
| **Clean real photos abstained, app pipeline (worst dataset)** | 0% | **16.7%** (Defactify; 1.3% on MJ/DALL·E/SD/NBP) |
| PGD with EOT (attacker ignores the check) | 100% fooled | 0% (all abstained) |
| **Adaptive PGD** (attacker also evades the check) | – | **77% fooled; 100% after laundering** |
| FGSM | 93% | 88% |
| Transfer | 100% | 0% direct, 37% laundered |
| Square (black box) | 80% | 80% |
| Framing | 100% | 68–73% |

At 4/255 the picture is the same. With no defense, 93–100% of attacks succeed. With the
consistency check, the adaptive PGD gets 78% through (98% laundered), and framing 72–78%.

**Verdict:**
- **No inference-time defense is shipped.** The consistency check (feature
  squeezing: JPEG q75 + 3×3 median, abstain above the 95th-percentile
  disagreement) only stops attackers who don't adapt to it. An adaptive
  attacker still gets 77–100% through, and black-box queries aren't slowed.
- Its one real gain is less framing (100% → about 70%). In exchange, on the
  real app pipeline it tells **1 in 6 genuine COCO photos** they "may have
  been altered". That fails the ≤ 10% abstain gate, and it harms exactly the
  people the check is meant to protect.
- Raising its threshold enough to pass the gate would cut the remaining
  protection further.

The earlier single-model run ([36196534662](https://github.com/as791/genned/actions/runs/36196534662),
n = 24) also covered:
- random transforms: cut Square from 83% to 33%, but not white-box attacks;
- randomized smoothing: clean AUC fell to 0.648, so it's ineligible.

**Also found:**
- Community Forensics' logit moves by up to 1.3 when pixels change by under
  1/255, e.g. torch vs Pillow bilinear resize.
- That is why squeezing alone costs clean AUC (0.989 → 0.946 on Defactify), and
  why the consistency check misfires on clean photos.

### Phase 2b: adversarial fine-tuning

Only training-time defenses move adaptive white-box numbers. `tools/adv_finetune.py`
fine-tunes each model on the app's own preprocessing (random original / jpeg75 / social,
then the model's view), keeps BatchNorm statistics frozen, and keeps the epoch with the
best PGD-10 robust accuracy at 4/255 on Defactify validation whose clean AUC is within 0.01
of the starting model's.

**Attempt 1** (2026-09-26, Colab T4; `as791/genned-robust:commfor-robust.pt`):
- Community Forensics only: PGD-AT, half of each batch attacked with PGD-3 at 4/255,
  lr 1e-5, 2 epochs.
- Data: 8,000 train images from Defactify plus MJ/DALL·E/SD/NBP.

| Community Forensics | As shipped | Epoch 1 | Epoch 2 |
|---|---|---|---|
| Clean AUC (Defactify validation) | 0.958 | 0.990 | 0.994 |
| Robust accuracy, PGD-10 at 4/255 | 3.7% | **1.0%** | **1.0%** |

No robustness was gained:
- The clean half of each batch was easy to fit; the attacked half wasn't learned
  in 500 small steps.
- The clean-AUC jump is in-distribution adaptation (train and test splits of
  the same datasets), not better generalization. Not built or shipped.

**Attempt 2** (2026-10-01, Colab T4; overwrote `commfor-robust.pt` on HF):
- TRADES with β = 6, lr 1e-4.
- By mistake it ran attempt 1's cached notebook cells: 2 epochs, Defactify +
  MJ/DALL·E/SD/NBP.

The model **collapsed**:

| Community Forensics | As shipped | Epoch 1 | Epoch 2 |
|---|---|---|---|
| Clean AUC | 0.958 | 0.706 | 0.693 |
| Clean accuracy | 78% | 50% | 51% |
| Robust accuracy at 4/255 | 4.3% | 31.7%* | 0% |

\*A degenerate model scores as "robust" on half the images. The clean loss
settled at ln 2, i.e. a constant 50/50 output. That output zeroes the KL term,
and lr 1e-4 let the model fall into it within 50 steps. Not usable.

**Attempt 3 recipe** (current defaults, kept for future retries):
- **Objective:** TRADES, with β ramping 0 → 3 over 2 epochs and the training ε
  ramping 0 → 4/255 over 1 epoch. PGD-5 with step ε/4.
- **Learning rate:** 2e-5 for Community Forensics, 1e-5 for EfficientNet-B4,
  with 5% warmup, then cosine.
- **Epochs:** 6 and 4.
- **Validation** every half epoch: clean AUC/accuracy, and robust accuracy at
  2/255 and 4/255.
- **Collapse guard:** training stops if clean AUC falls more than 0.05 below
  the start.
- **Eligibility:** a checkpoint is eligible only if clean AUC stays within
  0.01 and clean accuracy within 5 points of the start. If none is eligible,
  nothing is saved or uploaded.
- **Data:** Defactify's train split only, with `--strict-split`. The notebook
  re-clones the repo and checks the recipe version, so stale cells can't run.

**Attempt 3** (2026-10-01, Colab T4; `as791/genned-robust:commfor-robust-v3.pt`):
- the conservative recipe above;
- 6,000 Defactify train images, 6 epochs, about 15 min.

| Community Forensics | Start | Epoch 1.0 | Epoch 2.0 | Epoch 4.0 | Epoch 6.0 |
|---|---|---|---|---|---|
| Clean AUC (Defactify validation, in-distribution) | 0.958 | 0.947 | 0.965 | 0.980 | 0.988 |
| Clean accuracy | 78% | 54% | 88% | 92% | 95% |
| Robust accuracy, PGD-10 at 2/255 | 5.3% | 0% | 0% | 1.0% | 0.7% |
| Robust accuracy, PGD-10 at 4/255 | 4.3% | 0% | 0% | 0% | 0% |

The run was stable: no collapse, and every checkpoint after epoch 1.5 is clean-gate
eligible. **But no robustness was gained.**
- The TRADES KL term stayed near zero (0.01–0.03) while the clean training loss
  stayed high (0.54–0.66).
- So the model met "don't change your answer under attack" by keeping every
  output close to 50/50, where clean and attacked predictions barely differ.
  A 4/255 perturbation then flips them.
- In-batch robust accuracy fell from 50% to 10% over training. This is a softer
  form of attempt 2's collapse.
- The clean-AUC gain is in-distribution, since training and validation are both
  Defactify.
- The EfficientNet step was skipped by the notebook's guard; it needs ≥ 30%
  robust accuracy.

**Conclusion: Phase 2b is stopped.** Three attempts on free Colab budgets didn't give
these detectors any measurable robustness at 4/255. The app keeps the current
ensemble and stays documented as *not robust to deliberate attacks*. Ordinary
compression and resharing (jpeg75 / social) are a different matter: they are part
of the clean benchmarks and are handled.

Robustness would need materially more than this:
- starting from an adversarially pretrained backbone (robust ImageNet ViT/ConvNeXt
  checkpoints);
- a margin-preserving objective (e.g. PGD-AT with a logit-margin term, or MART);
- far more data and GPU time, on the order of tens of GPU-hours.

The tooling stays in place to retry:
- `tools/adv_finetune.py` and the notebook;
- the checkpoint support in Ensemble build and Adversarial eval;
- the gates below.

**How to run it:**
1. Run `notebooks/adversarial_finetune.ipynb` on Colab or Kaggle with an
   `HF_TOKEN` secret (write scope). It uploads `*-robust-v3.pt` to your private
   HF repo.
2. Run **Ensemble build** with `commfor_checkpoint=<repo>:commfor-robust-v3.pt`.
   Add `bundled_checkpoint=<repo>:bundled-robust-v3.pt` if that model was
   trained too. Set `assets_branch=model-assets-robust`.
3. Run **Adversarial eval** with `assets_branch=model-assets-robust`,
   `defenses=["none"]`.

**Ship gates** (robust vs current ensemble). Clean gates use **held-out data only**:
MJ/DALL·E/SD/NBP, DF26 and DeepAction. Defactify is in-distribution after fine-tuning,
so it's reported but not gated.
1. Worst-case AI caught at 5% false alarms over the held-out sets is no more
   than 3 points below the current ensemble's on the same sets.
2. Real shown HIGH ≤ 5% and AI shown LOW ≤ 10% at the recalibrated bands.
3. Video AUCs drop by at most 0.02.
4. Worst-case evasion at 4/255, all attacks, direct and laundered, falls from
   100% to **≤ 50%**, and framing at 4/255 falls too.

8/255 is reported but not gated. If a gate fails, the current models stay.

Caveats: MS-COCO (Defactify's real photos) is a very common training source, so
Defactify numbers may be optimistic. What the second dataset's "real" class
contains (photos only, or also artwork) hasn't been verified.

### Phase 3: accuracy on newer generators and realistic robustness

Phase 2 and 2b showed that per-image white-box attacks beat every affordable defense.
Phase 3 targets the threats that are both realistic and fixable:
- accuracy on generators the models have never seen;
- everyday edits: noise, filters, rescaling, crops, screenshots, re-encoding;
- universal patterns: one pattern, published once, that fools many images;
- transfer from open detectors that aren't in the app.

White-box per-image attacks are still measured and reported, but not gated.

**Tools:**
- `tools/evaluate.py --conditions edits`: 14 everyday edits, seeded per image.
- `--ensemble` scores the app's shipped ensemble exactly.
- `tools/edit_report.py` applies the gates.
- The **Robustness eval** workflow runs one job per dataset.
- `tools/adv_eval.py --attacks uap,transfer-ext` adds the universal-pattern and
  outside-detector attacks.
- `tools/adv_report.py` adds the by-threat table.
- **OpenFake** (`ComplexDataLab/OpenFake`, core config) is the newer-generator
  benchmark.
  - Its test split holds 2025–26 generators: GPT-Image-1.5/2, Midjourney 7,
    Flux.2-klein, Nano Banana Pro, Seedream 5, Z-Image, Recraft, frames from
    Veo 3 / Sora 2, and more. Real images are ImageNet and DOCCI photos.
  - Its train split holds older generators, so training on train and testing on
    test measures generalization to newer ones.
  - License: CC-BY-SA-4.0. Proprietary-generator subsets are non-commercial, so
    they're used for evaluation only.

**Baseline: the shipped ensemble under everyday edits**
([run 37121345188](https://github.com/as791/genned/actions/runs/37121345188),
[run 37121695956](https://github.com/as791/genned/actions/runs/37121695956);
150 AI + 150 real images per dataset):

| Dataset | Clean AUC | AI shown HIGH | AI shown LOW | Real shown HIGH | Edits that fail a gate |
|---|---|---|---|---|---|
| Defactify | 0.989 | 64.0% | 1.3% | 0.0% | noise8, grain, sharpen, webp50, chain_shot |
| MJ/DALL·E/SD/NBP | 0.828 | 30.7% | 4.7% | 2.0% | noise2/4/8, grain, webp50, screenshot, chain_shot |
| OpenFake (2025–26 generators) | 0.863 | 40.0% | 5.3% | 0.7% | grain, sharpen, webp50, screenshot, chain_shot |

Worst cells (over the three datasets):

| Edit | What goes wrong |
|---|---|
| webp50 (WebP quality 50) | **Real photos shown HIGH: 11.3% / 14.7% / 14.0%.** Ordinary re-encoding becomes a false accusation. |
| grain (film grain) | AI shown HIGH falls 15–32 points; AI shown LOW up to 11.3%. The easiest evasion. |
| sharpen | AI shown HIGH −21 points (Defactify); AI shown LOW up to 13.3% (OpenFake). |
| chain_shot (noise → screenshot → repost) | AI shown LOW 16.7% (MJ set), 15.3% (OpenFake). |
| screenshot | AI shown LOW 12.7% (MJ set), 10.0% (OpenFake). |
| noise2/4 (MJ set) | Real shown HIGH 5.3–8.0%. |

Blur, rescaling, cropping, small rotations, colour filters and the filter chain stay
within the gates.

On its own, Community Forensics catches almost none of the newest generators:
Flux.2-klein 0/15, GPT-Image-2 0/5, Seedream 5 0/4, Midjourney 7 2/15.

**Gates for a Phase 3 model** (held-out data only):
1. Worst-case AI caught at 5% false alarms doesn't fall. An accuracy win needs ≥ +3
   points.
2. Real shown HIGH ≤ 5% and AI shown LOW ≤ 10%, unedited and under every edit.
3. Video AUCs drop by at most 0.02.
4. AI shown HIGH under any edit is at most 10 points below unedited.
5. Universal pattern at 8/255 (direct, laundered, re-cropped): evasion and framing
   ≤ 20%.
6. Transfer from open detectors at 8/255 ≤ 30%.
7. Per-image white-box attacks are reported, not gated.

**Training** (`notebooks/robust_finetune_kaggle.ipynb`, `tools/adv_finetune.py
--objective aug+uat`):
- **Everyday-edit augmentation:** 60% of training images get a random edit.
- **Universal adversarial training** at 8/255 (Shafahi et al. 2020): two shared
  perturbations, AI→real and real→AI, ascend the loss the model descends, under
  random crops and rescales.
- **Validation:** clean AUC, AUC under six edits, and robustness to a *fresh*
  universal pattern fit on held-out validation images.
- **Data:** OpenFake train restricted to open-weights generators
  (`--exclude-generators`), plus Defactify train.
- **Safeguards:** the Phase 2b clean gate and collapse guard still apply.

## Replacing the model file

Follow these steps to re-export the model with `tools/convert_model.py` or replace
the bundled file with a different one.

1. Request access to the gated repo: visit
   https://huggingface.co/Dafilab/ai-image-detector while logged into a (free)
   Hugging Face account and click through to agree/request access. Then create a
   read-scoped token at https://huggingface.co/settings/tokens and run
   `huggingface-cli login` locally with it — a plain download otherwise fails with
   `401 GatedRepoError` (see the gated-repo note under "Status in this repository").
2. `pip install -r tools/requirements.txt`
3. `python tools/convert_model.py --output app/src/main/assets/models/ai-image-detector.onnx`
   — read that script's docstring first; it explains the verification steps you
   must do by hand (input/output names, label order) before trusting the export.
4. Run `python tools/evaluate.py --model app/src/main/assets/models/ai-image-detector.onnx --dataset <labeled dataset>`
   and sanity-check accuracy/precision/recall before shipping.
5. Rebuild the app. `SettingsScreen` and `AIImageClassifierProvider` will
   automatically detect the bundled file — no other code change is required.
6. Never commit a model file you have not personally verified the license and
   provenance of.

## Never download a model at runtime

Per the project's engineering rules, `ModelAssets` only ever reads from the app's
own compiled assets (`app/src/main/assets/models/`). Nothing in this codebase
fetches a model from the network at install- or run-time — a model change is a
build-time decision made by a maintainer who has read this document, not something
that happens silently on a user's device.
