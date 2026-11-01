"""
TrustGuard AI - Image Authenticity & DeepFake Detection Service
Loads the certified MobileNetV2 V8-Exp4 multi-task dual-stream model with graceful
fallback to V4 and V3 legacy backbones. Performs consistent preprocessing,
forensic ELA, attention visualization, and cross-model consensus verification.
"""

import io
import json
import logging
import uuid
from pathlib import Path
from typing import Any, Dict, Optional, Tuple, Union

import numpy as np
import tensorflow as tf
from PIL import Image, ImageOps

try:
    import cv2
except ImportError:
    cv2 = None

from app.services.cross_model_service import compare_models
from app.services.image_forensics import (
    calculate_sha256,
    evaluate_calibration,
    extract_exif_metadata,
    generate_attention_map,
    perform_error_level_analysis,
)

logger = logging.getLogger(__name__)

ROOT = Path(__file__).resolve().parents[2]

# Model priority hierarchy:
# 1. V8-Exp4 Multi-Task Dual-Stream (Certified Best on 1,000 Dev-Val Pairs)
# 2. V4 Best (Single-Stream Calibrated)
# 3. V4 Convenience
# 4. V3 Backup
V8_EXP4_PATH = ROOT / "models" / "deepfake_image_v8" / "deepfake_mobilenetv8_exp4_multitask_best.keras"
V4_PATH = ROOT / "models" / "deepfake_image_v4" / "deepfake_mobilenetv4_best.keras"
V4_CONVENIENCE_PATH = ROOT / "model" / "deepfake_mobilenetv2_v4_best.keras"
V3_BACKUP_PATH = ROOT / "model" / "deepfake_mobilenetv2_v3_best.keras"

METADATA_V8_PATH = ROOT / "training" / "reports" / "v8_exp4_validation_metrics.json"
METADATA_V4_PATH = ROOT / "models" / "deepfake_image_v4" / "metadata.json"

IMAGE_SIZE = (224, 224)

# Multi-task auxiliary class mapping (Verified from V8-Exp4 training code)
AUX_CLASSES = {
    0: "GENUINE_AUTHENTIC",
    1: "FACE_SWAP_MANIPULATION",
    2: "STYLEGAN_GENERATIVE"
}

# ---------------------------------------------------------------------------
# MODEL LOADING WITH GRACEFUL FALLBACK
# ---------------------------------------------------------------------------
model = None
MODEL_PATH = None
MODEL_NAME = "Unknown"
MODEL_VERSION = "0.0.0"
DEFAULT_THRESHOLD = 0.50
IS_DUAL_STREAM = False
IS_MULTI_TASK = False

candidate_models = [
    ("V8-Exp4", V8_EXP4_PATH, "MobileNetV2 V8-Exp4 Multi-Task Dual-Stream", "8.4.0", 0.50),
    ("V4-Best", V4_PATH, "MobileNetV2 DeepFake Detector V4", "4.0.0", 0.50),
    ("V4-Convenience", V4_CONVENIENCE_PATH, "MobileNetV2 DeepFake Detector V4", "4.0.0", 0.50),
    ("V3-Backup", V3_BACKUP_PATH, "MobileNetV2 V3 (Legacy Backup)", "3.0.0", 0.9941),
]

for label, path, name, version, default_t in candidate_models:
    if path.exists():
        try:
            loaded = tf.keras.models.load_model(str(path), compile=False)
            # Inspect signature
            input_names = [getattr(inp, "name", str(inp)) for inp in loaded.inputs]
            output_shapes = [out.shape for out in loaded.outputs]
            
            # Verify if model is dual-stream (expects crop_input and frame_input)
            has_crop = any("crop" in n.lower() for n in input_names)
            has_frame = any("frame" in n.lower() for n in input_names)
            is_dual = len(loaded.inputs) == 2 and (has_crop or has_frame)
            is_multi = len(loaded.outputs) >= 2

            model = loaded
            MODEL_PATH = path
            MODEL_NAME = name
            MODEL_VERSION = version
            DEFAULT_THRESHOLD = default_t
            IS_DUAL_STREAM = is_dual
            IS_MULTI_TASK = is_multi

            print(
                f"[TrustGuard Predictor] Loaded Model: {MODEL_NAME} (Version: {MODEL_VERSION})\n"
                f"  Path: {MODEL_PATH}\n"
                f"  Dual-Stream: {IS_DUAL_STREAM} | Multi-Task: {IS_MULTI_TASK} | Threshold: {DEFAULT_THRESHOLD}"
            )
            break
        except Exception as e:
            print(f"[TrustGuard Predictor Warning] Failed loading candidate {label} at {path}: {e}. Trying fallback.")
            continue

if model is None:
    raise FileNotFoundError("No trained deepfake model could be loaded from model/ or models/.")


# ---------------------------------------------------------------------------
# HAAR CASCADE FACE DETECTION & CROPPING
# ---------------------------------------------------------------------------
_face_cascade = None

def _get_face_cascade():
    """Lazily load and cache Haar cascade classifier with multiple fallback search paths."""
    global _face_cascade
    if _face_cascade is not None:
        return _face_cascade

    if cv2 is None:
        return None

    cascade_paths = [
        ROOT / "models" / "deepfake_image_v8" / "haarcascade_frontalface_default.xml",
        Path(cv2.data.haarcascades) / "haarcascade_frontalface_default.xml" if hasattr(cv2, "data") and hasattr(cv2.data, "haarcascades") else None,
        ROOT / "server" / ".venv312" / "Lib" / "site-packages" / "cv2" / "data" / "haarcascade_frontalface_default.xml",
        ROOT / ".venv" / "Lib" / "site-packages" / "cv2" / "data" / "haarcascade_frontalface_default.xml",
    ]

    for p in cascade_paths:
        if p is not None and p.exists():
            try:
                clf = cv2.CascadeClassifier(str(p))
                if not clf.empty():
                    _face_cascade = clf
                    return _face_cascade
            except Exception:
                pass
    return None


def detect_faces(image: Image.Image) -> int:
    """Detect faces count using OpenCV Haar Cascade."""
    clf = _get_face_cascade()
    if clf is None or cv2 is None:
        return 1  # Default single subject assumption
    try:
        img_np = np.array(image)
        gray = cv2.cvtColor(img_np, cv2.COLOR_RGB2GRAY)
        faces = clf.detectMultiScale(gray, scaleFactor=1.1, minNeighbors=4, minSize=(60, 60))
        return len(faces)
    except Exception:
        return 1


def preprocess_dual_stream(image: Image.Image) -> Dict[str, Any]:
    """
    Extract facial crop and full frame matching the verified training pipeline:
    - crop_input: Haar cascade detected largest face + 20% margin with boundary clamping,
                  or central 80% canvas fallback if no face detected. Resized to (224, 224).
    - frame_input: Full image resized to (224, 224).
    Both inputs are shape (1, 224, 224, 3), float32, in [0.0, 255.0] (unnormalized,
    matching the model's internal native Rescaling layer).
    """
    W, H = image.size
    clf = _get_face_cascade()

    crop_box = None
    crop_status = "FALLBACK_CENTRAL_80"
    faces_count = 0

    if clf is not None and cv2 is not None:
        try:
            img_bgr = cv2.cvtColor(np.array(image), cv2.COLOR_RGB2BGR)
            H_cv, W_cv = img_bgr.shape[:2]
            gray = cv2.cvtColor(img_bgr, cv2.COLOR_BGR2GRAY)
            faces = clf.detectMultiScale(gray, scaleFactor=1.1, minNeighbors=4, minSize=(60, 60))
            faces_count = len(faces)

            if faces_count > 0:
                # Select largest face by area
                x, y, w, h = max(faces, key=lambda b: b[2] * b[3])
                margin_x = int(w * 0.20)
                margin_y = int(h * 0.20)
                x1 = max(0, x - margin_x)
                y1 = max(0, y - margin_y)
                x2 = min(W_cv, x + w + margin_x)
                y2 = min(H_cv, y + h + margin_y)
                crop_box = (x1, y1, x2, y2)
                crop_status = "FACE_DETECTED"
        except Exception:
            faces_count = 1

    if crop_box is None:
        # Central 80% fallback crop
        x1 = int(W * 0.10)
        y1 = int(H * 0.10)
        x2 = int(W * 0.90)
        y2 = int(H * 0.90)
        crop_box = (x1, y1, x2, y2)
        crop_status = "FALLBACK_CENTRAL_80"

    # Extract crop from PIL image
    crop_pil = image.crop(crop_box)
    resample_method = Image.Resampling.BILINEAR if hasattr(Image, "Resampling") else Image.BILINEAR
    crop_resized = crop_pil.resize(IMAGE_SIZE, resample=resample_method)
    crop_arr = np.expand_dims(np.asarray(crop_resized, dtype=np.float32), axis=0)

    # Full frame resized
    frame_resized = image.resize(IMAGE_SIZE, resample=resample_method)
    frame_arr = np.expand_dims(np.asarray(frame_resized, dtype=np.float32), axis=0)

    return {
        "crop_input": crop_arr,
        "frame_input": frame_arr,
        "crop_status": crop_status,
        "faces_detected": max(1, faces_count),
    }


def preprocess_image(image: Image.Image) -> np.ndarray:
    """
    Single-stream fallback preprocessing: resize image to (224, 224).
    The model architecture contains its internal native Rescaling layer.
    """
    resample_method = Image.Resampling.BILINEAR if hasattr(Image, "Resampling") else Image.BILINEAR
    resized = image.resize(IMAGE_SIZE, resample=resample_method)
    arr = np.asarray(resized, dtype=np.float32)
    return np.expand_dims(arr, axis=0)


def load_image(image_source: Union[bytes, str, Path, Image.Image]) -> Tuple[Image.Image, bytes]:
    """
    Safely load an image from bytes, filepath, or PIL.Image.
    Applies EXIF orientation transpose and standardizes to RGB.
    Returns (PIL.Image, original_bytes).
    """
    if isinstance(image_source, Image.Image):
        buf = io.BytesIO()
        image_source.save(buf, format="JPEG")
        raw_bytes = buf.getvalue()
        img = image_source
    elif isinstance(image_source, bytes):
        raw_bytes = image_source
        img = Image.open(io.BytesIO(raw_bytes))
    elif isinstance(image_source, (str, Path)):
        p = Path(image_source)
        if not p.exists():
            raise FileNotFoundError(f"Image file not found: {p}")
        with open(p, "rb") as f:
            raw_bytes = f.read()
        img = Image.open(p)
    else:
        raise TypeError("image_source must be bytes, file path, or PIL.Image")

    img = ImageOps.exif_transpose(img)
    img = img.convert("RGB")
    return img, raw_bytes


def predict_image(
    image_source: Union[bytes, str, Path, Image.Image],
    include_forensics: bool = True,
    include_cross_model: bool = True,
) -> Dict[str, Any]:
    """
    Execute full multi-metric authenticity verification on an image:
    1. Preprocessing (Dual-Stream crop+frame for V8-Exp4, single-stream for V4 fallback)
    2. Primary authenticity inference (P(REAL) at fixed threshold 0.50)
    3. Auxiliary manipulation subtype classification (Genuine / Face-Swap / StyleGAN)
    4. Error Level Analysis (ELA) forensics
    5. Model attention visualization
    6. Cross-model comparison
    7. SHA-256 integrity hash & EXIF provenance
    """
    image, raw_bytes = load_image(image_source)
    orig_w, orig_h = image.size
    verification_id = str(uuid.uuid4())
    sha256_hash = calculate_sha256(raw_bytes)

    # 1. Model Inference
    manipulation_subtype: Optional[Dict[str, Any]] = None
    crop_status: str = "N/A"

    if IS_DUAL_STREAM:
        dual_data = preprocess_dual_stream(image)
        feed_dict = {
            "crop_input": dual_data["crop_input"],
            "frame_input": dual_data["frame_input"]
        }
        raw_outputs = model.predict(feed_dict, verbose=0)
        faces_detected = dual_data["faces_detected"]
        crop_status = dual_data["crop_status"]

        if IS_MULTI_TASK:
            # Output 0 is primary_output (1, 1); Output 1 is auxiliary_output (1, 3)
            primary_preds = raw_outputs[0]
            aux_preds = raw_outputs[1]
            raw_score = float(primary_preds[0][0])
            
            aux_probs = aux_preds[0]  # (3,)
            aux_class_id = int(np.argmax(aux_probs))
            manipulation_subtype = {
                "predicted_class": AUX_CLASSES.get(aux_class_id, "UNKNOWN"),
                "class_id": aux_class_id,
                "confidence": round(float(aux_probs[aux_class_id]) * 100.0, 2),
                "probabilities": {
                    "GENUINE_AUTHENTIC": round(float(aux_probs[0]), 4),
                    "FACE_SWAP_MANIPULATION": round(float(aux_probs[1]), 4),
                    "STYLEGAN_GENERATIVE": round(float(aux_probs[2]), 4),
                }
            }
        else:
            raw_score = float(raw_outputs[0][0])
    else:
        # Legacy single-stream fallback (V4/V3)
        processed_arr = preprocess_image(image)
        raw_score = float(model.predict(processed_arr, verbose=0)[0][0])
        faces_detected = detect_faces(image)

    # 2. Decision Logic at Fixed Threshold 0.50
    # Primary sigmoid output represents P(REAL): score >= 0.50 -> REAL, score < 0.50 -> FAKE
    if raw_score < DEFAULT_THRESHOLD:
        label = "FAKE"
        confidence = round((1.0 - raw_score) * 100.0, 2)
        confidence_level = "HIGH" if confidence >= 85.0 else "MEDIUM"
        if manipulation_subtype and manipulation_subtype["predicted_class"] != "GENUINE_AUTHENTIC":
            sub_name = manipulation_subtype["predicted_class"].replace("_", " ")
            primary_reason = (
                f"{sub_name.title()} detected by TrustGuard {MODEL_NAME} "
                f"(Authenticity P(REAL): {raw_score:.4f} < {DEFAULT_THRESHOLD:.2f})."
            )
        else:
            primary_reason = (
                f"Synthetic manipulation detected by {MODEL_NAME} "
                f"(Authenticity P(REAL): {raw_score:.4f} < {DEFAULT_THRESHOLD:.2f})."
            )
    else:
        label = "REAL"
        confidence = round(raw_score * 100.0, 2)
        confidence_level = "HIGH" if confidence >= 85.0 else "MEDIUM"
        primary_reason = (
            f"Verified authentic human photograph by {MODEL_NAME} "
            f"(Authenticity P(REAL): {raw_score:.4f} >= {DEFAULT_THRESHOLD:.2f})."
        )

    # Optional Forensics (ELA)
    forensics = perform_error_level_analysis(raw_bytes) if include_forensics else {}
    if forensics:
        forensics["file_hash_sha256"] = sha256_hash

    # Optional Attention map
    attention = generate_attention_map(raw_bytes) if include_forensics else {}

    # Optional Cross-model comparison
    cross_model_data = compare_models(
        pil_image=image,
        raw_score=raw_score,
        primary_label=label,
        confidence=confidence,
    ) if include_cross_model else {}

    # Metadata & EXIF
    exif_info = extract_exif_metadata(image)

    # Plain-English findings
    findings = []
    if label == "REAL":
        findings.append(f"Authentic human photograph confirmed (Confidence: {confidence:.1f}%).")
        findings.append(primary_reason)
        findings.append("No recurring synthetic generative patterns or face-swap boundaries detected in facial regions.")
    else:
        findings.append(f"AI deepfake / facial manipulation detected (Confidence: {confidence:.1f}%).")
        findings.append(primary_reason)
        findings.append("Identified unnatural frequency artifacts or facial boundary tampering typical of synthetic manipulation.")

    if forensics.get("tampering_detected"):
        findings.append("Auxiliary Error Level Analysis detected localized compression variances.")

    # Calibrated probabilities reflecting verdict
    if label == "FAKE":
        prob_fake = round(confidence / 100.0, 4)
        prob_real = round(max(0.0, 1.0 - prob_fake), 4)
    else:
        prob_real = round(confidence / 100.0, 4)
        prob_fake = round(max(0.0, 1.0 - prob_real), 4)

    result_dict: Dict[str, Any] = {
        "prediction": label,
        "confidence": confidence,
        "confidence_level": confidence_level,
        "raw_score": round(raw_score, 6),
        "threshold": DEFAULT_THRESHOLD,
        "probabilities": {
            "REAL": prob_real,
            "FAKE": prob_fake,
        },
        "verification_id": verification_id,
        "integrity_hash": sha256_hash,
        "model_version": MODEL_VERSION,
        "model_name": MODEL_NAME,
        "faces_detected": faces_detected,
        "original_image_size": {
            "width": orig_w,
            "height": orig_h,
        },
        "model_input_size": {
            "width": IMAGE_SIZE[0],
            "height": IMAGE_SIZE[1],
        },
        "findings": findings,
        "forensics": forensics,
        "attention_map": attention.get("attention_map_base64"),
        "cross_model": cross_model_data,
        "cross_model_comparison": cross_model_data,
        "metadata": exif_info,
        "disclaimer": (
            "Verification result is a calibrated statistical assessment produced by machine learning models, "
            "not a legal guarantee of media authenticity. High-stakes verification should corroborate source provenance."
        ),
    }

    if manipulation_subtype is not None:
        result_dict["manipulation_subtype"] = manipulation_subtype
        result_dict["crop_status"] = crop_status

    return result_dict