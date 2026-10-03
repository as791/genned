#!/usr/bin/env python3
"""Evaluate the bundled AI-image classifier against a labeled dataset.

This is the tool referred to throughout internal-docs/MODEL.md and internal-docs/ARCHITECTURE.md as
the intended source of truth for detector quality — Genned's evidence weights and
classification thresholds should be calibrated from the numbers this script
produces, not guessed. The `model-eval` GitHub Actions workflow
(.github/workflows/model-eval.yml) runs it against public labeled datasets; see
internal-docs/MODEL.md "Measured accuracy".

Usage:
    python tools/evaluate.py \\
        --model app/src/main/assets/models/ai-image-detector.onnx \\
        --dataset /path/to/dataset \\
        --threshold 0.5

    # Several degradation conditions / preprocessing modes in one pass, with a
    # JSON result per combination (consumed by tools/eval_report.py):
    python tools/evaluate.py --model ... --dataset ... \\
        --conditions original,jpeg75,social --preprocess squash,center_crop \\
        --json-dir results/

Expected dataset layout (binary classification, folder name = ground truth):

    dataset/
      ai/                # known AI-generated images, optionally grouped
        sdxl/img001.png  # by generator (subfolder name = generator)
        img002.png       # (or directly in ai/ -> generator "ai")
      real/              # known non-AI (camera/human-made) images
        img001.jpg

Conditions (applied to each image before preprocessing):
    original  the file as-is
    jpeg75    re-encoded once as JPEG quality 75
    social    what a post seen through Instagram goes through: long edge
              downscaled to <=1080, then JPEG q75 (platform re-upload)

Everyday edits (EDIT_CONDITIONS): what people do to an image before reposting it, or
what simple "beat AI detectors" tools do. They need no knowledge of the model:
    noise2 / noise4 / noise8   Gaussian pixel noise, sigma 2 / 4 / 8 (of 255)
    grain        monochrome film grain (sigma 6, softened)
    blur         Gaussian blur, radius 1.5
    sharpen      unsharp mask (radius 2, 150%)
    filter       Instagram-style colour filter: saturation x1.3, contrast x1.15,
                 brightness x1.05
    rescale      downscale to half size, then upscale back (bicubic)
    crop80       keep 80% of width and height (off-centre)
    rotate3      rotate 3 degrees, cropped back to a rectangle without borders
    webp50       re-encoded as WebP quality 50
    screenshot   shown on a 1080-wide phone screen with status and navigation bars,
                 saved as PNG (a screenshot that is then shared)
    chain_filter filter -> rescale -> social
    chain_shot   noise4 -> screenshot -> social
Random edits are seeded per image, so every run sees the same pixels.

Every condition then goes through the app's own normalization, exactly as
ImageLoader does before the classifier ever sees the image: long edge capped at
2048, re-encoded as JPEG quality 92.

Preprocessing modes (image -> 380x380 model input):
    squash       resize straight to 380x380, ignoring aspect ratio - what the app
                 does today (AIImageClassifierProvider.preprocess)
    center_crop  resize the short side to 380, then center-crop 380x380
    avg          mean of the squash and center_crop logit differences (2 inferences)

Scores are raw model probabilities unless --calibration SLOPE,INTERCEPT is given,
in which case P(ai) = sigmoid(SLOPE * (ai_logit - human_logit) + INTERCEPT) - the
same transform ModelConfig.interpretOutput applies on-device. --scores-csv writes
one row per image and combination (model, dataset, condition, preprocess, image, generator,
is_ai, logit_diff) for tools/calibrate.py and tools/ensemble.py. `image` is the
sample's path inside the fetched dataset folder (e.g. real/00012.jpg), used only to
join models per image; no pixels or source file names.

Resizing uses bilinear filtering to match Android's
Bitmap.createScaledBitmap(..., filter = true). Normalization/channel order MUST
match app/src/main/kotlin/.../classifier/ModelConfig.kt or these numbers will not
reflect what the app actually does on-device.
"""

from __future__ import annotations

import argparse
import csv
import io
import json
import math
import sys
import zlib
from dataclasses import dataclass
from pathlib import Path

import numpy as np
from PIL import Image, ImageEnhance, ImageFilter

try:
    import onnxruntime as ort
except ImportError:  # pragma: no cover - dependency check, not test-covered
    print("onnxruntime is required: pip install -r tools/requirements.txt", file=sys.stderr)
    raise

# Keep these in sync with ModelConfig.kt.
INPUT_SIZE = 380
MEAN = np.array([0.485, 0.456, 0.406], dtype=np.float32)
STD = np.array([0.229, 0.224, 0.225], dtype=np.float32)
INPUT_NAME = "pixel_values"

# Keep these in sync with EvidenceWeights.kt (domain module).
LOW_THRESHOLD = 0.15
HIGH_THRESHOLD = 0.90

# Keep these in sync with ModelConfig.CALIBRATION_SLOPE / CALIBRATION_INTERCEPT and the
# app's two-view ("avg") preprocessing. Pass --calibration app to evaluate the app as shipped.
APP_CALIBRATION = (0.2252, 0.0494)
# Video path (VideoSignalAggregator): mean per-frame logit gap -> this calibration.
# Keep in sync with ModelConfig.VIDEO_CALIBRATION_* (fit on Video eval run 36190406439).
APP_VIDEO_CALIBRATION = (0.2071, -1.3977)
# The shipped ensemble (EnsembleConfig.kt), fit by tools/ensemble_calibrate.py in Ensemble
# build run 36196623887. Keep in sync with EnsembleConfig.
APP_ENSEMBLE = {
    "mean_d": -0.38708, "std_d": 8.00114, "mean_c": -3.96926, "std_c": 4.37424,
    "photo": (3.19350, 0.16339), "video": (3.49213, -1.85881),
}


def load_ensemble_params(path: Path) -> dict:
    """APP_ENSEMBLE-shaped constants from an ensemble-params.json written by
    tools/ensemble_calibrate.py (e.g. for a candidate model set on a model-assets branch)."""
    raw = json.loads(Path(path).read_text())
    st = raw["standardization"]
    return {"mean_d": st["mean_d"], "std_d": st["std_d"], "mean_c": st["mean_c"], "std_c": st["std_c"],
            "photo": (raw["photo"]["slope"], raw["photo"]["intercept"]),
            "video": (raw["video"]["slope"], raw["video"]["intercept"])}


def ensemble_score(primary_gap: float, commfor_logit: float, params: dict | None = None) -> float:
    """EnsembleConfig.combine: mean of both models' standardized logits."""
    e = params or APP_ENSEMBLE
    return ((primary_gap - e["mean_d"]) / e["std_d"] + (commfor_logit - e["mean_c"]) / e["std_c"]) / 2.0

IMAGE_EXTENSIONS = {".jpg", ".jpeg", ".png", ".webp", ".bmp"}
EDIT_CONDITIONS = ("noise2", "noise4", "noise8", "grain", "blur", "sharpen", "filter", "rescale", "crop80",
                   "rotate3", "webp50", "screenshot", "chain_filter", "chain_shot")
CONDITIONS = ("original", "jpeg75", "social") + EDIT_CONDITIONS
PREPROCESS_MODES = ("squash", "center_crop", "avg")
BASE_MODES = ("squash", "center_crop")


@dataclass
class Prediction:
    path: Path
    ground_truth_is_ai: bool
    ai_probability: float
    generator: str = "real"
    logit_diff: float = 0.0


def _jpeg(image: Image.Image, quality: int) -> Image.Image:
    buffer = io.BytesIO()
    image.save(buffer, format="JPEG", quality=quality)
    buffer.seek(0)
    return Image.open(buffer).convert("RGB")


def _encode(image: Image.Image, fmt: str, **kwargs) -> Image.Image:
    buffer = io.BytesIO()
    image.save(buffer, format=fmt, **kwargs)
    buffer.seek(0)
    return Image.open(buffer).convert("RGB")


def _noise(image: Image.Image, sigma: float, rng: np.random.Generator, mono: bool = False) -> Image.Image:
    array = np.asarray(image, dtype=np.float32)
    shape = array.shape[:2] + ((1,) if mono else (3,))
    noisy = array + rng.normal(0.0, sigma, size=shape).astype(np.float32)
    return Image.fromarray(np.clip(np.rint(noisy), 0, 255).astype(np.uint8))


def _grain(image: Image.Image, rng: np.random.Generator) -> Image.Image:
    field = rng.normal(0.0, 6.0, size=(image.height, image.width)).astype(np.float32)
    soft = np.asarray(Image.fromarray(np.clip(field + 128, 0, 255).astype(np.uint8)).filter(
        ImageFilter.GaussianBlur(0.7)), dtype=np.float32) - 128
    array = np.asarray(image, dtype=np.float32) + soft[..., None]
    return Image.fromarray(np.clip(np.rint(array), 0, 255).astype(np.uint8))


def _rotate_crop(image: Image.Image, degrees: float) -> Image.Image:
    """Rotate, then crop the largest centred rectangle with the same aspect ratio and no
    empty corners."""
    w, h = image.size
    a = math.radians(abs(degrees))
    factor = 1.0 / (math.cos(a) + math.sin(a) * max(w / h, h / w))
    rotated = image.rotate(degrees, resample=Image.BICUBIC)
    cw, ch = max(1, int(w * factor)), max(1, int(h * factor))
    left, top = (w - cw) // 2, (h - ch) // 2
    return rotated.crop((left, top, left + cw, top + ch))


def _screenshot(image: Image.Image) -> Image.Image:
    """The image displayed full-width on a 1080 x 2400 phone screen between a status bar
    and app/navigation chrome, captured as PNG."""
    screen_w, top_bar, bottom_bar = 1080, 140, 260
    scale = screen_w / image.width
    shown = image.resize((screen_w, max(1, round(image.height * scale))), Image.BILINEAR)
    shown_h = min(shown.height, 2400 - top_bar - bottom_bar)
    shown = shown.crop((0, 0, screen_w, shown_h))
    canvas = Image.new("RGB", (screen_w, top_bar + shown_h + bottom_bar), (250, 250, 250))
    canvas.paste((20, 20, 20), (0, 0, screen_w, 60))  # status bar
    canvas.paste(shown, (0, top_bar))
    canvas.paste((235, 235, 235), (0, top_bar + shown_h + 120, screen_w, canvas.height))  # nav bar
    return _encode(canvas, "PNG")


def _social(image: Image.Image) -> Image.Image:
    long_edge = max(image.size)
    if long_edge > 1080:
        scale = 1080 / long_edge
        image = image.resize(
            (max(1, round(image.width * scale)), max(1, round(image.height * scale))),
            Image.BILINEAR,
        )
    return _jpeg(image, 75)


def degrade(image: Image.Image, condition: str, seed: int = 0) -> Image.Image:
    """Applies one benchmark condition. `seed` makes the random edits repeatable per image
    (callers pass condition_seed(path))."""
    rng = np.random.default_rng(seed)
    if condition == "original":
        return image
    if condition == "jpeg75":
        return _jpeg(image, 75)
    if condition == "social":
        return _social(image)
    if condition in ("noise2", "noise4", "noise8"):
        return _noise(image, float(condition[5:]), rng)
    if condition == "grain":
        return _grain(image, rng)
    if condition == "blur":
        return image.filter(ImageFilter.GaussianBlur(1.5))
    if condition == "sharpen":
        return image.filter(ImageFilter.UnsharpMask(radius=2, percent=150, threshold=3))
    if condition == "filter":
        image = ImageEnhance.Color(image).enhance(1.3)
        image = ImageEnhance.Contrast(image).enhance(1.15)
        return ImageEnhance.Brightness(image).enhance(1.05)
    if condition == "rescale":
        half = image.resize((max(1, image.width // 2), max(1, image.height // 2)), Image.BILINEAR)
        return half.resize(image.size, Image.BICUBIC)
    if condition == "crop80":
        cw, ch = max(1, round(image.width * 0.8)), max(1, round(image.height * 0.8))
        left = int(rng.integers(0, image.width - cw + 1))
        top = int(rng.integers(0, image.height - ch + 1))
        return image.crop((left, top, left + cw, top + ch))
    if condition == "rotate3":
        return _rotate_crop(image, 3.0 if rng.random() < 0.5 else -3.0)
    if condition == "webp50":
        return _encode(image, "WEBP", quality=50)
    if condition == "screenshot":
        return _screenshot(image)
    if condition == "chain_filter":
        return _social(degrade(degrade(image, "filter", seed), "rescale", seed))
    if condition == "chain_shot":
        return _social(_screenshot(degrade(image, "noise4", seed)))
    raise ValueError(f"Unknown condition: {condition}")


def condition_seed(path: Path, condition: str) -> int:
    """Stable per-image, per-condition seed (independent of Python's hash randomization)."""
    return zlib.crc32(f"{path.name}|{condition}".encode())


def app_normalize(image: Image.Image) -> Image.Image:
    """Mirrors ImageLoader: long edge capped at MAX_DIMENSION_PX (2048), JPEG quality 92."""
    long_edge = max(image.size)
    if long_edge > 2048:
        scale = 2048 / long_edge
        image = image.resize(
            (max(1, round(image.width * scale)), max(1, round(image.height * scale))),
            Image.BILINEAR,
        )
    return _jpeg(image, 92)


def to_model_input(image: Image.Image, mode: str) -> Image.Image:
    if mode == "squash":
        return image.resize((INPUT_SIZE, INPUT_SIZE), Image.BILINEAR)
    if mode == "center_crop":
        scale = INPUT_SIZE / min(image.size)
        width = max(INPUT_SIZE, round(image.width * scale))
        height = max(INPUT_SIZE, round(image.height * scale))
        resized = image.resize((width, height), Image.BILINEAR)
        left = (width - INPUT_SIZE) // 2
        top = (height - INPUT_SIZE) // 2
        return resized.crop((left, top, left + INPUT_SIZE, top + INPUT_SIZE))
    raise ValueError(f"Unknown preprocess mode: {mode}")


def to_tensor(image: Image.Image) -> np.ndarray:
    array = np.asarray(image, dtype=np.float32) / 255.0
    array = (array - MEAN) / STD
    chw = np.transpose(array, (2, 0, 1))  # HWC -> CHW
    return np.expand_dims(chw, axis=0).astype(np.float32)


def preprocess(image_path: Path, condition: str = "original", mode: str = "squash") -> np.ndarray:
    image = Image.open(image_path).convert("RGB")
    return to_tensor(to_model_input(app_normalize(degrade(image, condition)), mode))


def _sigmoid(x: float) -> float:
    # Written to saturate cleanly for extreme logits instead of overflowing exp().
    if x >= 0:
        return 1.0 / (1.0 + np.exp(-x))
    e = np.exp(x)
    return float(e / (1.0 + e))


def interpret_output(raw_output: np.ndarray) -> float:
    """Mirrors ModelConfig.interpretOutput in the Kotlin code - keep them in sync.

    The export emits raw logits (output tensor "logits"; no softmax layer in the
    graph), ordered [ai, human] per the model's config.json label_mapping
    ({"0": "ai", "1": "human"}). P(ai) is therefore the 2-class softmax, i.e.
    sigmoid(ai_logit - human_logit).

    An earlier version of this function had the label order inverted AND used
    ai / (ai + human) - not a softmax, and it collapsed to 0.5 whenever both logits
    were negative - so evaluation numbers from it were meaningless.
    """
    flat = raw_output.reshape(-1)
    if np.isnan(flat).any():
        return 0.5
    if flat.size == 2:
        ai, human = float(flat[0]), float(flat[1])
        return float(_sigmoid(ai - human))
    if flat.size == 1:
        return float(_sigmoid(float(flat[0])))
    return 0.5


def logit_difference(raw_output: np.ndarray) -> float:
    """ai_logit - human_logit (or the single AI logit): the input interpret_output squashes."""
    flat = raw_output.reshape(-1)
    if np.isnan(flat).any():
        return 0.0
    if flat.size == 2:
        return float(flat[0]) - float(flat[1])
    if flat.size == 1:
        return float(flat[0])
    return 0.0


def calibrated_probability(logit_diff: float, slope: float = 1.0, intercept: float = 0.0) -> float:
    """sigmoid(slope * logit_diff + intercept); slope=1, intercept=0 is the raw model output."""
    return float(_sigmoid(slope * logit_diff + intercept))


def run_inference(session: "ort.InferenceSession", tensor: np.ndarray) -> float:
    """Returns the logit difference; see calibrated_probability for P(ai)."""
    outputs = session.run(None, {INPUT_NAME: tensor})
    return logit_difference(outputs[0])


COMMFOR_MODEL_NAME = "commfor-224 (app onnx)"
ENSEMBLE_MODEL_NAME = "app ensemble"
COMMFOR_SIZE = 224
COMMFOR_RESIZE = 256


def commfor_view(image: Image.Image) -> Image.Image:
    """The 224x224 Community Forensics view as the app computes it, matching the authors'
    torchvision test transform pixel for pixel: short side -> 256 with the long side
    *truncated* (torchvision Resize), center-crop offsets rounded half-to-even (torchvision
    CenterCrop). Off-by-one-pixel differences move this ViT's logit by up to ~1, so the
    geometry must match exactly (checked by tools/build_models.py)."""
    short, long = sorted(image.size)
    new_long = int(COMMFOR_RESIZE * long / short)
    width, height = (COMMFOR_RESIZE, new_long) if image.width <= image.height else (new_long, COMMFOR_RESIZE)
    resized = image.resize((width, height), Image.BILINEAR)
    left = int(round((width - COMMFOR_SIZE) / 2.0))
    top = int(round((height - COMMFOR_SIZE) / 2.0))
    return resized.crop((left, top, left + COMMFOR_SIZE, top + COMMFOR_SIZE))


def commfor_input(image: Image.Image) -> np.ndarray:
    """commfor_view with ImageNet normalization, NCHW."""
    return to_tensor(commfor_view(image))


class CommforOnnx:
    """The Community Forensics ONNX file the app bundles; one output logit, sigmoid = P(fake)."""

    def __init__(self, path: Path):
        self.session = ort.InferenceSession(str(path), providers=["CPUExecutionProvider"])
        self.input_name = self.session.get_inputs()[0].name

    def gap(self, image: Image.Image) -> float:
        return float(self.session.run(None, {self.input_name: commfor_input(image)})[0].reshape(-1)[0])


def collect_images(directory: Path) -> list[Path]:
    if not directory.is_dir():
        return []
    return sorted(p for p in directory.rglob("*") if p.is_file() and p.suffix.lower() in IMAGE_EXTENSIONS)


def generator_of(path: Path, ai_dir: Path) -> str:
    relative = path.relative_to(ai_dir)
    return relative.parts[0] if len(relative.parts) > 1 else "ai"


def evaluate_all(
    model_path: Path,
    dataset_dir: Path,
    conditions: list[str],
    modes: list[str],
    slope: float = 1.0,
    intercept: float = 0.0,
    commfor: "CommforOnnx | None" = None,
    ensemble: dict | None = None,
) -> dict[tuple[str, str], list[Prediction]]:
    """Runs every (condition, preprocess) combination, decoding each image once.

    With `commfor`, also scores the bundled Community Forensics ONNX on the same degraded
    image under the key (condition, "commfor") - raw sigmoid, for ensemble fitting.
    With `commfor` and `ensemble` (APP_ENSEMBLE-shaped constants), also scores the app's
    shipped ensemble under (condition, "ensemble"): both bundled views averaged, combined
    with Community Forensics, photo-calibrated - exactly EnsembleConfig."""
    session = ort.InferenceSession(str(model_path), providers=["CPUExecutionProvider"])

    ai_dir = dataset_dir / "ai"
    labeled = [(p, True, generator_of(p, ai_dir)) for p in collect_images(ai_dir)]
    labeled += [(p, False, "real") for p in collect_images(dataset_dir / "real")]

    if not labeled:
        print(
            f"No images found under {dataset_dir}/ai or {dataset_dir}/real. "
            "See this script's docstring for the expected layout.",
            file=sys.stderr,
        )
        sys.exit(1)

    results: dict[tuple[str, str], list[Prediction]] = {(c, m): [] for c in conditions for m in modes}
    if commfor is not None:
        results.update({(c, "commfor"): [] for c in conditions})
    if ensemble is not None:
        if commfor is None:
            raise ValueError("the ensemble needs the Community Forensics model")
        results.update({(c, "ensemble"): [] for c in conditions})
    skipped = 0
    for index, (path, is_ai, generator) in enumerate(labeled, start=1):
        try:
            image = Image.open(path).convert("RGB")
        except Exception as e:  # noqa: BLE001 - one unreadable file must not abort the run
            print(f"Skipping unreadable image {path}: {e}", file=sys.stderr)
            skipped += 1
            continue
        for condition in conditions:
            degraded = app_normalize(degrade(image, condition, condition_seed(path, condition)))
            needed = ({m for m in modes if m in BASE_MODES}
                      | (set(BASE_MODES) if "avg" in modes or ensemble is not None else set()))
            diffs = {m: run_inference(session, to_tensor(to_model_input(degraded, m))) for m in needed}
            if "avg" in modes:
                diffs["avg"] = (diffs["squash"] + diffs["center_crop"]) / 2.0
            for mode in modes:
                d = diffs[mode]
                results[(condition, mode)].append(
                    Prediction(path, is_ai, calibrated_probability(d, slope, intercept), generator, d)
                )
            if commfor is not None:
                c = commfor.gap(degraded)
                results[(condition, "commfor")].append(Prediction(path, is_ai, calibrated_probability(c), generator, c))
                if ensemble is not None:
                    s = ensemble_score((diffs["squash"] + diffs["center_crop"]) / 2.0, c, ensemble)
                    slope_e, intercept_e = ensemble["photo"]
                    results[(condition, "ensemble")].append(
                        Prediction(path, is_ai, calibrated_probability(s, slope_e, intercept_e), generator, s))
        if index % 100 == 0:
            print(f"  {index}/{len(labeled)} images", file=sys.stderr)
    if skipped:
        print(f"Skipped {skipped} unreadable images", file=sys.stderr)
    return results


def evaluate(model_path: Path, dataset_dir: Path, threshold: float) -> list[Prediction]:
    """Original single-configuration entry point (app behavior: original file, squash)."""
    return evaluate_all(model_path, dataset_dir, ["original"], ["squash"])[("original", "squash")]


def roc_auc(labels: np.ndarray, scores: np.ndarray) -> float | None:
    """Mann-Whitney AUC with average ranks for ties (no sklearn dependency)."""
    positives = int(labels.sum())
    negatives = len(labels) - positives
    if positives == 0 or negatives == 0:
        return None
    order = np.argsort(scores, kind="mergesort")
    sorted_scores = scores[order]
    ranks = np.empty(len(scores), dtype=np.float64)
    i = 0
    while i < len(scores):
        j = i
        while j + 1 < len(scores) and sorted_scores[j + 1] == sorted_scores[i]:
            j += 1
        ranks[order[i : j + 1]] = (i + j) / 2.0 + 1.0
        i = j + 1
    positive_rank_sum = ranks[labels == 1].sum()
    return float((positive_rank_sum - positives * (positives + 1) / 2.0) / (positives * negatives))


def reliability(labels: np.ndarray, scores: np.ndarray, bins: int = 10) -> tuple[float, list[dict]]:
    """Expected calibration error of P(ai) plus the per-bin table behind it."""
    edges = np.linspace(0.0, 1.0, bins + 1)
    table = []
    ece = 0.0
    for b in range(bins):
        low, high = edges[b], edges[b + 1]
        mask = (scores >= low) & ((scores < high) if b < bins - 1 else (scores <= high))
        count = int(mask.sum())
        if count == 0:
            table.append({"bin": f"{low:.1f}-{high:.1f}", "n": 0, "mean_score": None, "frac_ai": None})
            continue
        mean_score = float(scores[mask].mean())
        frac_ai = float(labels[mask].mean())
        ece += count / len(scores) * abs(mean_score - frac_ai)
        table.append({"bin": f"{low:.1f}-{high:.1f}", "n": count, "mean_score": mean_score, "frac_ai": frac_ai})
    return float(ece), table


def _bands(scores: np.ndarray) -> dict[str, float]:
    if len(scores) == 0:
        return {"low": 0.0, "uncertain": 0.0, "high": 0.0}
    return {
        "low": float((scores < LOW_THRESHOLD).mean()),
        "uncertain": float(((scores >= LOW_THRESHOLD) & (scores < HIGH_THRESHOLD)).mean()),
        "high": float((scores >= HIGH_THRESHOLD).mean()),
    }


def compute_metrics(predictions: list[Prediction], threshold: float) -> dict:
    labels = np.array([1 if p.ground_truth_is_ai else 0 for p in predictions], dtype=np.int64)
    scores = np.array([p.ai_probability for p in predictions], dtype=np.float64)
    predicted = scores >= threshold

    tp = int((predicted & (labels == 1)).sum())
    fn = int((~predicted & (labels == 1)).sum())
    fp = int((predicted & (labels == 0)).sum())
    tn = int((~predicted & (labels == 0)).sum())
    total = len(predictions)
    precision = tp / (tp + fp) if (tp + fp) else 0.0
    recall = tp / (tp + fn) if (tp + fn) else 0.0
    ece, reliability_table = reliability(labels, scores)

    per_generator = {}
    for generator in sorted({p.generator for p in predictions}):
        generator_scores = np.array([p.ai_probability for p in predictions if p.generator == generator])
        is_real = generator == "real"
        per_generator[generator] = {
            "n": int(len(generator_scores)),
            # For AI generators: share detected; for real: share correctly passed.
            "correct_at_threshold": float(
                ((generator_scores < threshold) if is_real else (generator_scores >= threshold)).mean()
            ),
            "mean_score": float(generator_scores.mean()),
            "bands": _bands(generator_scores),
        }

    return {
        "n": total,
        "n_ai": int(labels.sum()),
        "n_real": int(total - labels.sum()),
        "threshold": threshold,
        "confusion": {"tp": tp, "fn": fn, "fp": fp, "tn": tn},
        "accuracy": (tp + tn) / total if total else 0.0,
        "precision": precision,
        "recall": recall,
        "f1": 2 * precision * recall / (precision + recall) if (precision + recall) else 0.0,
        "fpr": fp / (fp + tn) if (fp + tn) else 0.0,
        "fnr": fn / (fn + tp) if (fn + tp) else 0.0,
        "auc": roc_auc(labels, scores),
        "ece": ece,
        "reliability": reliability_table,
        "bands_real": _bands(scores[labels == 0]),
        "bands_ai": _bands(scores[labels == 1]),
        "extreme_share": float(((scores > 0.99) | (scores < 0.01)).mean()) if total else 0.0,
        "per_generator": per_generator,
    }


def print_report(predictions: list[Prediction], threshold: float) -> None:
    m = compute_metrics(predictions, threshold)
    c = m["confusion"]
    print(f"Images evaluated: {m['n']} (threshold={threshold})")
    print()
    print("Confusion matrix (rows = actual, columns = predicted):")
    print(f"{'':>14}{'Predicted AI':>14}{'Predicted Real':>16}")
    print(f"{'Actual AI':>14}{c['tp']:>14}{c['fn']:>16}")
    print(f"{'Actual Real':>14}{c['fp']:>14}{c['tn']:>16}")
    print()
    print(f"Accuracy:              {m['accuracy']:.3f}")
    print(f"Precision (AI class):  {m['precision']:.3f}")
    print(f"Recall (AI class):     {m['recall']:.3f}")
    print(f"F1 (AI class):         {m['f1']:.3f}")
    print(f"False positive rate:   {m['fpr']:.3f}  (real images flagged as AI)")
    print(f"False negative rate:   {m['fnr']:.3f}  (AI images missed)")
    auc = m["auc"]
    print(f"ROC-AUC:               {'n/a' if auc is None else f'{auc:.3f}'}")
    print(f"ECE (calibration):     {m['ece']:.3f}  (0 = scores mean what they say)")
    print(f"Scores >99% or <1%:    {m['extreme_share']:.1%}")
    print()
    print(f"App bands (LOW <{LOW_THRESHOLD:.2f} / UNCERTAIN / HIGH >={HIGH_THRESHOLD:.2f}):")
    for name in ("real", "ai"):
        b = m[f"bands_{name}"]
        print(f"  {name:>4}: LOW {b['low']:.1%}  UNCERTAIN {b['uncertain']:.1%}  HIGH {b['high']:.1%}")
    print()
    print("Per generator (share classified correctly at threshold, mean P(ai)):")
    for generator, g in m["per_generator"].items():
        print(f"  {generator:>16}: n={g['n']:<5} correct={g['correct_at_threshold']:.1%}  mean={g['mean_score']:.3f}")


def main() -> None:
    parser = argparse.ArgumentParser(description=__doc__, formatter_class=argparse.RawDescriptionHelpFormatter)
    parser.add_argument("--model", type=Path, required=True, help="Path to the .onnx classifier")
    parser.add_argument("--dataset", type=Path, required=True, help="Path to the dataset/ai, dataset/real folder")
    parser.add_argument("--threshold", type=float, default=0.5, help="AI-probability threshold for a positive prediction")
    parser.add_argument("--conditions", default="original", help=f"Comma-separated subset of {','.join(CONDITIONS)}")
    parser.add_argument("--preprocess", default="squash", help=f"Comma-separated subset of {','.join(PREPROCESS_MODES)}")
    parser.add_argument("--dataset-name", default=None, help="Name used in JSON output (default: dataset folder name)")
    parser.add_argument("--json-dir", type=Path, default=None, help="Write one JSON result per combination here")
    parser.add_argument("--model-name", default=None, help="Label for this configuration in reports")
    parser.add_argument("--commfor-onnx", type=Path, default=None,
                        help="Also score this Community Forensics ONNX (the app's second ensemble model)")
    parser.add_argument("--ensemble", action="store_true",
                        help="Also score the app's shipped ensemble (needs --commfor-onnx)")
    parser.add_argument("--ensemble-params", type=Path, default=None,
                        help="ensemble-params.json for a candidate model set (default: APP_ENSEMBLE)")
    parser.add_argument("--scores-csv", type=Path, default=None, help="Append per-image logit differences here")
    parser.add_argument("--calibration", default=None, help="SLOPE,INTERCEPT as in ModelConfig.interpretOutput, or 'app' for the shipped values")
    args = parser.parse_args()

    slope, intercept = 1.0, 0.0
    if args.calibration:
        try:
            slope, intercept = (APP_CALIBRATION if args.calibration == "app"
                                else (float(v) for v in args.calibration.split(",")))
        except ValueError:
            parser.error("--calibration must be SLOPE,INTERCEPT, e.g. 0.4,-0.1")

    conditions = [c.strip() for c in args.conditions.split(",") if c.strip()]
    modes = [m.strip() for m in args.preprocess.split(",") if m.strip()]
    for c in conditions:
        if c not in CONDITIONS:
            parser.error(f"unknown condition {c!r}; choose from {CONDITIONS}")
    for m in modes:
        if m not in PREPROCESS_MODES:
            parser.error(f"unknown preprocess mode {m!r}; choose from {PREPROCESS_MODES}")
    if args.ensemble and not args.commfor_onnx:
        parser.error("--ensemble needs --commfor-onnx")

    if not args.model.exists():
        print(f"Model file not found: {args.model}", file=sys.stderr)
        sys.exit(1)

    dataset_name = args.dataset_name or args.dataset.resolve().name
    commfor = CommforOnnx(args.commfor_onnx) if args.commfor_onnx else None
    ensemble = None
    if args.ensemble:
        ensemble = load_ensemble_params(args.ensemble_params) if args.ensemble_params else APP_ENSEMBLE
    results = evaluate_all(args.model, args.dataset, conditions, modes, slope, intercept, commfor, ensemble)
    if args.json_dir:
        args.json_dir.mkdir(parents=True, exist_ok=True)

    def labels(mode: str) -> tuple[str | None, str]:
        """(model name, preprocess) for a results key; the Community Forensics and ensemble rows
        are their own models."""
        if mode == "commfor":
            return COMMFOR_MODEL_NAME, "native"
        if mode == "ensemble":
            return ENSEMBLE_MODEL_NAME, "ensemble"
        return args.model_name, mode

    for (condition, mode), predictions in results.items():
        model_name, preprocess_label = labels(mode)
        print()
        print(f"=== {dataset_name} | {model_name or 'bundled'} | condition={condition} | preprocess={preprocess_label} ===")
        print_report(predictions, args.threshold)
        if args.json_dir:
            payload = {
                **({"model": model_name} if model_name else {}),
                "dataset": dataset_name,
                "condition": condition,
                "preprocess": preprocess_label,
                "calibration": ({"slope": ensemble["photo"][0], "intercept": ensemble["photo"][1]}
                                if mode == "ensemble"
                                else {"slope": slope, "intercept": intercept}
                                if args.calibration and mode != "commfor" else None),
                "metrics": compute_metrics(predictions, args.threshold),
            }
            prefix = f"{model_name.replace(' ', '_').replace('/', '_')}__" if model_name else ""
            out = args.json_dir / f"{prefix}{dataset_name}__{condition}__{preprocess_label}.json"
            out.write_text(json.dumps(payload, indent=2))

    if args.scores_csv:
        new_file = not args.scores_csv.exists()
        with args.scores_csv.open("a", newline="") as f:
            writer = csv.writer(f)
            if new_file:
                writer.writerow(["model", "dataset", "condition", "preprocess", "image", "generator", "is_ai",
                                 "logit_diff"])
            for (condition, mode), predictions in results.items():
                model_name, preprocess_label = labels(mode)
                for p in predictions:
                    writer.writerow([model_name or "dafilab (bundled)", dataset_name, condition, preprocess_label,
                                     p.path.relative_to(args.dataset).as_posix(), p.generator,
                                     int(p.ground_truth_is_ai), f"{p.logit_diff:.6f}"])


if __name__ == "__main__":
    main()
