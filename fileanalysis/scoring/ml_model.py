"""Machine learning threat scoring model (LightGBM) and inference wrapper."""

from __future__ import annotations

import logging
from pathlib import Path
from typing import TYPE_CHECKING
import numpy as np
import lightgbm as lgb

if TYPE_CHECKING:
    from fileanalysis.analyzers.base import AnalysisResult

from fileanalysis.analyzers.base import RiskLevel
from fileanalysis.scoring.features import NUM_FEATURES, FeatureExtractor

logger = logging.getLogger(__name__)

# Default model weights path (alongside this file)
DEFAULT_MODEL_PATH = Path(__file__).parent / "threat_model_lgb.txt"
DEFAULT_SCALER_PATH = Path(__file__).parent / "feature_scaler.npz"

import threading

_LGB_CACHE: dict[Path, lgb.Booster] = {}
_SCALER_CACHE: dict[Path, tuple[np.ndarray, np.ndarray]] = {}
_LGB_LOCK = threading.Lock()


class LightGBMThreatScorer:
    """Gradient-Boosted Tree-based threat scorer.

    Loads a pre-trained LightGBM model once and uses it thread-safely across files.
    Falls back to a clear error if LightGBM is unavailable or weights are missing.
    """

    def __init__(self, model_path: str | Path | None = None) -> None:
        self.model_path = Path(model_path).resolve() if model_path else DEFAULT_MODEL_PATH.resolve()
        self.scaler_path = self.model_path.parent / "feature_scaler.npz"
        self.extractor = FeatureExtractor()
        self.feat_mean, self.feat_std = self._load_scaler()
        self.model = self._load_model()

    def _load_scaler(self):
        """Load saved feature normalization parameters (cached singleton)."""
        with _LGB_LOCK:
            if self.scaler_path in _SCALER_CACHE:
                return _SCALER_CACHE[self.scaler_path]
            if self.scaler_path.exists():
                data = np.load(self.scaler_path)
                logger.info("Loaded feature scaler from %s", self.scaler_path)
                res = (data["mean"], data["std"])
            else:
                logger.warning("No feature scaler found at %s, using raw features", self.scaler_path)
                res = (np.zeros(NUM_FEATURES, dtype=np.float32), np.ones(NUM_FEATURES, dtype=np.float32))
            _SCALER_CACHE[self.scaler_path] = res
            return res

    def _load_model(self):
        """Load the LightGBM model with pre-trained weights (cached singleton)."""
        with _LGB_LOCK:
            if self.model_path in _LGB_CACHE:
                return _LGB_CACHE[self.model_path]

            if not self.model_path.exists():
                raise FileNotFoundError(
                    f"Model weights not found at {self.model_path}. "
                    f"Run 'python -m fileanalysis.scoring.sandbox_train' to generate them."
                )

            model = lgb.Booster(model_file=str(self.model_path))
            logger.info("Loaded LightGBM model from %s", self.model_path)
            _LGB_CACHE[self.model_path] = model
            return model

    def calculate_score(self, result: AnalysisResult) -> None:
        """Run ML inference on the AnalysisResult and set ml_score/ml_risk_level.

        This writes to the ml_* fields on AnalysisResult so it can coexist
        with the heuristic scorer's risk_score/risk_level fields and the nn_* fields.
        """
        # Extract and normalize features
        features = self.extractor.extract(result)
        features = (features - self.feat_mean) / (self.feat_std + 1e-8)
        
        # Inference
        raw_output = self.model.predict(features.reshape(1, -1))[0]

        # Convert output [0, 1] → score [0, 100]
        confidence = float(raw_output)
        
        # Anti-False-Positive Filter for LightGBM:
        # LightGBM correlates high entropy with malware, causing false positives on PDFs/archives.
        heuristic_conf = getattr(result, 'risk_score', 0.0) / 100.0
        if result.metadata.file_type not in ["pe", "elf", "macho"]:
            # Hardcap out-of-distribution files based on heuristic reality
            confidence = min(confidence, max(0.2, heuristic_conf))
        elif heuristic_conf < 0.1:
            # If executable but completely devoid of any suspicious traits, cap at LOW risk
            confidence = min(confidence, 0.4)

        final_score = round(confidence * 100.0, 1)

        result.ml_score = final_score
        result.ml_confidence = round(confidence, 4)

        # Determine risk level (same thresholds as heuristic)
        if final_score <= 20.0:
            result.ml_risk_level = RiskLevel.CLEAN
        elif final_score <= 40.0:
            result.ml_risk_level = RiskLevel.LOW
        elif final_score <= 60.0:
            result.ml_risk_level = RiskLevel.MODERATE
        elif final_score <= 80.0:
            result.ml_risk_level = RiskLevel.HIGH
        else:
            result.ml_risk_level = RiskLevel.CRITICAL
