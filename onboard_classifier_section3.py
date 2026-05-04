"""
CoverGuard-PFI  |  Failure-Cause Classifier
============================================
Takes 6 multispectral band reflectances and returns the most likely
cause of cover-crop failure.

Failure cause classes
---------------------
  0  HEALTHY
  1  MOISTURE_STRESS      - drought / insufficient soil water
  2  EXCESS_WETNESS       - ponding / waterlogging
  3  NUTRIENT_DEFICIT     - low nitrogen / chlorophyll / organic matter
  4  POOR_ESTABLISHMENT   - sparse canopy, weak early-stage cover
  5  PEST_OR_DISEASE      - biotic stress, pest hotspot

  If no class reaches UNKNOWN_CONFIDENCE_THRESHOLD the output is
  "UNKNOWN" — review the parcel manually.

How to run
----------
  python coverguard_model.py              # train on synthetic data
  python coverguard_model.py --merged     # train on synthetic + real HLS data
  python coverguard_model.py --demo-only  # load saved model and run demo only
"""

import sys
import numpy as np
import pandas as pd
import lightgbm as lgb
from pathlib import Path
from sklearn.model_selection import train_test_split
from sklearn.metrics import classification_report, confusion_matrix
import warnings
warnings.filterwarnings("ignore")

# ─────────────────────────────────────────────────────────────────────────────
# PATHS  (relative to this file, so the project is portable)
# ─────────────────────────────────────────────────────────────────────────────
BASE_DIR     = Path(__file__).parent
_DATA_ROOT   = next(
    (p for p in [BASE_DIR / "classifier_training_datasets", BASE_DIR.parent / "classifier_training_datasets"] if (p / "agriculture_dataset.csv").exists()),
    BASE_DIR / "classifier_training_datasets",
)
DATA_PATH    = _DATA_ROOT / "agriculture_dataset.csv"
MERGED_PATH  = _DATA_ROOT / "merged_training_data.csv"
MODEL_PATH   = BASE_DIR / "trained_model" / "coverguard_lgbm_classifier.txt"
REPORT_PATH  = BASE_DIR / "outputs" / "section3_onboard_classifier" / "coverguard_failure_classification_report.txt"
# ─────────────────────────────────────────────────────────────────────────────
# CONSTANTS
# ─────────────────────────────────────────────────────────────────────────────
FAILURE_CAUSES = {
    0: "HEALTHY",
    1: "MOISTURE_STRESS",
    2: "EXCESS_WETNESS",
    3: "NUTRIENT_DEFICIT",
    4: "POOR_ESTABLISHMENT",
    5: "PEST_OR_DISEASE",
}

# If the top predicted class scores below this threshold the classifier
# returns "UNKNOWN" instead of a potentially wrong label.
# Tune upward (e.g. 0.60) for higher certainty at the cost of more UNKNOWN.
UNKNOWN_CONFIDENCE_THRESHOLD = 0.20

# All 8 indices computable from 6 imager bands (Blue, Green, Red, RedEdge, NIR, SWIR1).
# NBR / NBR2 are excluded — they need SWIR2 (B12) which the imager does not carry.
#
#  Index  | Bands used          | Primary agronomic signal
#  -------|---------------------|------------------------------------------
#  NDVI   | NIR, Red            | Overall canopy greenness / biomass
#  NDRE   | NIR, RedEdge        | Early N/chlorophyll stress (Schepers 1996)
#  NDMI   | NIR, SWIR1          | Leaf water content / drought (Gao 1996)
#  NDWI   | Green, NIR          | Open-water / canopy water saturation
#  SAVI   | NIR, Red            | NDVI corrected for soil brightness
#  EVI    | NIR, Red, Blue      | Reduced atmospheric + soil noise vs NDVI
#  MSAVI  | NIR, Red            | EVI-like but no blue band needed
#  Chlorophyll_Content (CIRE)
#         | NIR, RedEdge        | Canopy chlorophyll concentration
SPECTRAL_COLS = [
    "NDVI", "NDRE", "NDMI", "NDWI",
    "SAVI", "EVI", "MSAVI",
    "Chlorophyll_Content",
]
# No context or satellite ancillary — model trains and infers on spectral only.
# This exactly matches the onboard path: 6 bands -> 8 indices -> class.
ALL_FEATURE_COLS = SPECTRAL_COLS

# Manual class weights replace 'balanced'.
# 'balanced' gave PEST a 53x multiplier vs HEALTHY — causing 2,456 false positives.
# These weights correct for imbalance without over-firing on noisy synthetic labels.
# Rare classes (THERMAL, EXCESS_WET, POOR_EST) get higher weights because they have
# fewer training samples and no HLS corroboration yet.
CLASS_WEIGHTS = {
    0: 1,    # HEALTHY            — 206K samples
    1: 10,   # MOISTURE_STRESS    — 2,378 samples + 315 HLS pixels
    2: 20,   # EXCESS_WETNESS     — 520 samples, very rare
    3: 14,   # NUTRIENT_DEFICIT   — 1,483 samples + 38 HLS pixels
    4: 20,   # POOR_ESTABLISHMENT — 840 samples, hard to distinguish spectrally
    5: 6,    # PEST_OR_DISEASE    — 3,870 samples (large class, modest boost)
}

# ── Per-class spectral profile distributions ─────────────────────────────────
# Synthetic rows have real NDVI/SAVI/CIRE but no NDMI or NDRE — those bands
# weren't in the original agriculture_dataset.csv.
# We sample NDMI and NDRE from per-class Gaussian distributions so the model
# can learn genuine spectral patterns, not just context-label proxies.
#
# Literature basis:
#   NDMI : Gao 1996 (Remote Sens. Environ.) — leaf water content index
#   NDRE : Schepers et al. 1996 — N-deficit detection via red-edge reflectance
#          Fitzgerald et al. 2010 — NDRE < 0.12 = chlorophyll deficient
#   Wet  : Setter & Waters 2003 — anaerobic soils, very high canopy moisture
#   Thermal: Hatfield & Prueger 2015 — desiccated tissue, NDMI < 0
#
# {class_id: {index: (mean, std)}}
# Per-class distributions for indices NOT present in agriculture_dataset.csv.
# Synthetic rows have real NDVI / SAVI / CIRE but no NDMI, NDRE, EVI, NDWI or MSAVI.
# We sample those from class-specific Gaussians so the model sees 212k spectrally
# consistent examples per class, not just 3.6k real HLS pixels.
#
# Literature basis:
#   NDMI  : Gao 1996 — leaf water content; stressed vegetation NDMI < 0.1
#   NDRE  : Schepers 1996; Fitzgerald 2010 — NDRE < 0.12 = N deficiency
#   EVI   : Huete et al. 2002 — reduced soil/atmosphere noise, tracks canopy density
#   NDWI  : McFeeters 1996 — (Green-NIR)/(Green+NIR); negative for all vegetation,
#           near-zero for waterlogged soils
#   MSAVI : Qi et al. 1994 — SAVI variant, same signal, used as corroborating feature
#
# Values are means (std) clipped to [-1, 1].
SPECTRAL_PROFILES = {
    #          NDMI           NDRE           EVI            NDWI           MSAVI
    0: {"NDMI": ( 0.32, 0.08), "NDRE": (0.28, 0.06), "EVI": (0.50, 0.10), "NDWI": (-0.24, 0.06), "MSAVI": (0.48, 0.09)},  # HEALTHY
    1: {"NDMI": ( 0.01, 0.04), "NDRE": (0.18, 0.05), "EVI": (0.18, 0.06), "NDWI": (-0.44, 0.07), "MSAVI": (0.17, 0.05)},  # MOISTURE_STRESS
    2: {"NDMI": ( 0.50, 0.07), "NDRE": (0.12, 0.04), "EVI": (0.28, 0.09), "NDWI": (-0.08, 0.08), "MSAVI": (0.26, 0.08)},  # EXCESS_WETNESS
    3: {"NDMI": ( 0.18, 0.05), "NDRE": (0.07, 0.03), "EVI": (0.22, 0.07), "NDWI": (-0.30, 0.06), "MSAVI": (0.21, 0.06)},  # NUTRIENT_DEFICIT
    4: {"NDMI": ( 0.08, 0.05), "NDRE": (0.16, 0.05), "EVI": (0.10, 0.05), "NDWI": (-0.42, 0.07), "MSAVI": (0.09, 0.04)},  # POOR_ESTABLISHMENT
    5: {"NDMI": ( 0.12, 0.06), "NDRE": (0.13, 0.04), "EVI": (0.21, 0.08), "NDWI": (-0.33, 0.07), "MSAVI": (0.20, 0.07)},  # PEST_OR_DISEASE
}

LGBM_PARAMS = {
    "objective":         "multiclass",
    "num_class":         len(FAILURE_CAUSES),
    "metric":            "multi_logloss",
    "boosting_type":     "gbdt",
    "num_leaves":        63,
    "max_depth":         6,
    "learning_rate":     0.05,
    "n_estimators":      800,
    "min_child_samples": 20,
    "subsample":         0.8,
    "colsample_bytree":  0.8,
    "reg_alpha":         0.1,
    "reg_lambda":        1.0,
    "class_weight":      CLASS_WEIGHTS,
    "n_jobs":            -1,
    "random_state":      42,
    "verbose":           -1,
}


# ─────────────────────────────────────────────────────────────────────────────
# STEP 1 - SPECTRAL FEATURE ENGINEERING
#   This is the real on-orbit entry point.
#   Pass raw reflectance values from the imager, get back all needed indices.
# ─────────────────────────────────────────────────────────────────────────────

def compute_spectral_indices(blue, green, red, red_edge, nir, swir):
    """
    Compute all spectral indices from 6 raw band surface reflectances (0-1).
    Matches the HLS / HLS-VI index family used in the CoverGuard architecture.
    """
    eps = 1e-9
    return {
        "NDVI":          (nir - red)      / (nir + red + eps),
        "NDRE":          (nir - red_edge) / (nir + red_edge + eps),
        "NDMI":          (nir - swir)     / (nir + swir + eps),
        "NDWI":          (green - nir)    / (green + nir + eps),
        "SAVI":          1.5*(nir-red)    / (nir + red + 0.5 + eps),
        "MSAVI":         (2*nir+1 - np.sqrt((2*nir+1)**2 - 8*(nir-red))) / 2,
        "EVI":           2.5*(nir-red)    / (nir + 6*red - 7.5*blue + 1 + eps),
        "NBR":           (nir - swir)     / (nir + swir + eps),
        "NBR2":          (swir - red)     / (swir + red + eps),
        "CIRE":          (nir / (red_edge + eps)) - 1,
        "red_swir_ratio": red / (swir + eps),
    }


# ─────────────────────────────────────────────────────────────────────────────
# STEP 2 - LABEL DERIVATION
#   Creates 7-class failure-cause labels from the CSV's proxy columns.
#   Rules encode agronomic expert knowledge so the model learns the
#   spectral signatures that correspond to each failure mode.
# ─────────────────────────────────────────────────────────────────────────────

def derive_failure_cause(df: pd.DataFrame) -> pd.Series:
    """
    Research-backed agronomic rules for programmatic label assignment.

    Threshold sources
    -----------------
    THERMAL_STRESS  : Hatfield & Prueger 2015 (Field Crops Res.) — cardinal
                      temps for winter cover crops: 4 C (base) / 35 C (ceiling).
    PEST_OR_DISEASE : Jackson et al. 1981 — biotic stress produces intermediate
                      NDVI decline (0.3-0.45) with elevated canopy stress index.
    POOR_EST.       : Kaspar et al. 2012 (J. Soil Water Conserv.) — <20% canopy
                      cover in early growth stages = failed establishment.
                      USDA-NRCS Practice Standard 340 (Cover Crop).
    NUTRIENT_DEFICIT: Schepers et al. 1996 — NDRE < 0.15 flags N deficiency;
                      Fitzgerald et al. 2010 — CIRE < 1.0 = deficient status.
                      OM < 1.5% = low-N substrate (Brady & Weil 2010).
    EXCESS_WETNESS  : Setter & Waters 2003 (Ann. Bot.) — anaerobic conditions
                      begin above ~33% VWC; ponding with drainage impairment.
    MOISTURE_STRESS : Gao 1996 — NDMI < 0 = plant water stress; FAO-56
                      Penman-Monteith: permanent wilting near 15% VWC for
                      loam-textured soils common in mid-Atlantic agriculture.
    """
    labels = pd.Series(np.zeros(len(df), dtype=int), index=df.index)

    ndvi         = df["NDVI"]
    sm           = df["Soil_Moisture"]
    temp         = df["Temperature"]
    rain         = df["Rainfall"]
    chl          = df["Chlorophyll_Content"]
    om           = df["Organic_Matter"]
    csi          = df["Crop_Stress_Indicator"]
    cc           = df["Canopy_Coverage"]
    wf           = df["Water_Flow"]
    drain        = df["Drainage_Features"]
    pest         = df["Pest_Damage"]
    growth       = df["Crop_Growth_Stage"]
    healthy_flag = df["Crop_Health_Label"]

    # Priority order: rarest / most severe labeled first so common classes
    # (drought, wet) cannot mask rare ones (pest, nutrient).
    # THERMAL_STRESS removed — temperature is not derivable from 6 spectral bands.

    # Class 5 — PEST_OR_DISEASE
    # Jackson 1981: biotic stress = moderate NDVI drop + high canopy stress index.
    # Oerke 2006: meaningful yield loss starts at > 60 % damage area.
    # Raised from pest>50 to pest>60 AND csi>70 to reduce borderline false labels.
    labels[(pest > 60) & (csi > 70) & (ndvi < 0.42) & (healthy_flag == 0)] = 5

    # Class 4 — POOR_ESTABLISHMENT
    # Kaspar 2012 / NRCS-340: < 20 % canopy cover in early growth = failure.
    labels[(cc < 20) & (ndvi < 0.30) & (growth <= 2) & (healthy_flag == 0)] = 4

    # Class 3 — NUTRIENT_DEFICIT
    # Schepers 1996 NDRE < 0.15 -> N deficiency; Fitzgerald 2010 CIRE < 1.0.
    # Proxy: chl (CIRE rescaled) < 0.4; soil OM < 1.5 % (Brady & Weil 2010).
    labels[(chl < 0.4) & (om < 1.5) & (sm < 25) & (ndvi < 0.45) & (healthy_flag == 0)] = 3

    # Class 2 — EXCESS_WETNESS
    # Setter & Waters 2003: anaerobic threshold ~33 % VWC; ponding with
    # compromised drainage triggers hypoxia within 24-48 h.
    labels[(sm > 33) & (rain > 30) & ((wf > 30) | (drain == 1)) & (healthy_flag == 0)] = 2

    # Class 1 — MOISTURE_STRESS
    # FAO-56: permanent wilting point ~15 % VWC for loam; Gao 1996 NDMI signal.
    labels[(sm < 15) & (temp > 25) & (rain < 10) & (ndvi < 0.5) & (healthy_flag == 0)] = 1

    labels[healthy_flag == 1] = 0  # force healthy override last

    return labels


# ─────────────────────────────────────────────────────────────────────────────
# STEP 3 - DATA LOADING
# ─────────────────────────────────────────────────────────────────────────────

def load_and_prepare(path: Path):
    print(f"Loading {path.name} ...")
    df = pd.read_csv(path)
    print(f"  {len(df):,} rows, {df.shape[1]} columns")

    # Merged CSV already has failure_cause from hls_data_pull.py
    # Synthetic CSV needs labels derived from agronomic rules
    if "failure_cause" not in df.columns:
        df["failure_cause"] = derive_failure_cause(df)
    else:
        print("  (failure_cause column already present — skipping rule derivation)")

    # THERMAL_STRESS (class 6) is no longer in the model — remap to HEALTHY.
    # This handles any pre-existing merged CSV that was built before the class
    # was removed, without requiring a full re-pull of HLS data.
    thermal_rows = (df["failure_cause"] == 6).sum()
    if thermal_rows > 0:
        df.loc[df["failure_cause"] == 6, "failure_cause"] = 0
        print(f"  Remapped {thermal_rows:,} THERMAL_STRESS rows -> HEALTHY")

    # Print source breakdown if available
    if "source" in df.columns:
        print(f"\n  Data sources: {dict(df['source'].value_counts())}")

    print("\n  Label distribution:")
    for cls_id, count in df["failure_cause"].value_counts().sort_index().items():
        print(f"    {cls_id}  {FAILURE_CAUSES[cls_id]:<22}  {count:>7,}  ({100*count/len(df):.1f}%)")

    # Add any feature columns missing from this CSV as NaN first.
    for col in ALL_FEATURE_COLS:
        if col not in df.columns:
            df[col] = np.nan

    # Augment synthetic rows with per-class NDMI and NDRE profiles.
    # Synthetic rows have real NDVI/SAVI/CIRE but no NDMI or NDRE
    # (not present in agriculture_dataset.csv).  Without this step the model
    # sees NaN for these two indices on 98% of training rows and learns to
    # ignore them entirely — defeating their purpose as key spectral signals.
    #
    # We sample from per-class Gaussian distributions grounded in literature
    # (see SPECTRAL_PROFILES constant above).  This gives the model 212k
    # examples of what NDMI and NDRE look like for each failure class,
    # complementing the 3.6k real HLS pixels where those values are measured.
    # Fill spectral indices that are missing in synthetic rows using per-class
    # Gaussian profiles.  HLS rows already have real measured values; those are
    # never overwritten (only NaN cells are filled).
    rng = np.random.default_rng(42)
    aug_cols = [c for c in ("NDMI", "NDRE", "EVI", "NDWI", "MSAVI") if c in ALL_FEATURE_COLS]
    for col in aug_cols:
        if col not in df.columns:
            df[col] = np.nan
        missing = df[col].isna()
        if missing.any():
            sampled = df.loc[missing, col].copy()
            for cls_id, profiles in SPECTRAL_PROFILES.items():
                if col not in profiles:
                    continue
                cls_mask = missing & (df["failure_cause"] == cls_id)
                n = int(cls_mask.sum())
                if n > 0:
                    mean, std = profiles[col]
                    sampled[cls_mask] = rng.normal(mean, std, n).clip(-1.0, 1.0)
            df[col] = df[col].where(~missing, sampled)

    n_augmented = int((df["source"] == "synthetic").sum()) if "source" in df.columns else 0
    if n_augmented:
        print(f"  Augmented {n_augmented:,} synthetic rows with per-class spectral profiles"
              f" ({', '.join(aug_cols)})")

    X = df[ALL_FEATURE_COLS]
    y = df["failure_cause"]
    return X, y


# ─────────────────────────────────────────────────────────────────────────────
# STEP 4 - TRAINING
# ─────────────────────────────────────────────────────────────────────────────

def train_model(X, y):
    X_train, X_temp, y_train, y_temp = train_test_split(
        X, y, test_size=0.30, stratify=y, random_state=42
    )
    X_val, X_test, y_val, y_test = train_test_split(
        X_temp, y_temp, test_size=0.50, stratify=y_temp, random_state=42
    )
    print(f"\n  Train: {len(X_train):,}  Val: {len(X_val):,}  Test: {len(X_test):,}")

    print("\nTraining LightGBM ...")
    model = lgb.LGBMClassifier(**LGBM_PARAMS)
    model.fit(
        X_train, y_train,
        eval_set=[(X_val, y_val)],
        callbacks=[
            lgb.early_stopping(stopping_rounds=30, verbose=False),
            lgb.log_evaluation(period=100),
        ],
    )
    print(f"  Best iteration: {model.best_iteration_}")
    return model, X_test, y_test


# ─────────────────────────────────────────────────────────────────────────────
# STEP 5 - EVALUATION
# ─────────────────────────────────────────────────────────────────────────────

def evaluate_model(model, X_test, y_test):
    y_pred = model.predict(X_test)
    target_names = [FAILURE_CAUSES[i] for i in range(len(FAILURE_CAUSES))]

    report = classification_report(y_test, y_pred, target_names=target_names)
    cm     = confusion_matrix(y_test, y_pred)

    print("\n=== Classification Report ===")
    print(report)
    print("=== Confusion Matrix ===")
    print(cm)

    feat_imp = pd.Series(model.feature_importances_, index=ALL_FEATURE_COLS)
    print("\n=== Feature Importances (top 12) ===")
    print(feat_imp.sort_values(ascending=False).head(12).to_string())

    # Save report to outputs/
    REPORT_PATH.parent.mkdir(exist_ok=True)
    with open(REPORT_PATH, "w") as f:
        f.write(report)
        f.write("\n\nConfusion Matrix:\n")
        f.write(str(cm))
    print(f"\n  Report saved -> {REPORT_PATH}")


# ─────────────────────────────────────────────────────────────────────────────
# STEP 6 - SAVE / LOAD
# ─────────────────────────────────────────────────────────────────────────────

def save_model(model):
    MODEL_PATH.parent.mkdir(exist_ok=True)
    model.booster_.save_model(str(MODEL_PATH))
    print(f"  Model saved -> {MODEL_PATH}")


def load_model():
    if not MODEL_PATH.exists():
        raise FileNotFoundError(f"No saved model at {MODEL_PATH}. Run without --demo-only first.")
    # Load raw booster — we call predict() directly in _run() below
    booster = lgb.Booster(model_file=str(MODEL_PATH))
    return booster


# ─────────────────────────────────────────────────────────────────────────────
# STEP 7 - INFERENCE WRAPPER
#   This is the class the onboard parcel intelligence layer calls.
# ─────────────────────────────────────────────────────────────────────────────

class CoverGuardClassifier:
    """
    Two inference paths:

    1. infer_from_bands(blue, green, red, red_edge, nir, swir, context)
       -- the real on-orbit path from the multispectral imager

    2. infer_from_features(feature_dict)
       -- debug / ground-segment path, pass pre-computed features directly
    """

    def __init__(self, model):
        self.model = model

    # -- on-orbit path --------------------------------------------------------
    def infer_from_bands(self, blue, green, red, red_edge, nir, swir):
        """
        Classify failure cause from 6 raw surface-reflectance band values.

        Parameters
        ----------
        blue / green / red / red_edge / nir / swir : float
            Surface reflectance in [0, 1] from the multispectral imager.

        Returns
        -------
        dict:
            failure_cause    str    e.g. "MOISTURE_STRESS"
            cause_id         int    0-6
            confidence       float  0-1
            probabilities    dict   {class_name: probability}
            spectral_indices dict   all 8 computed index values
        """
        idx = compute_spectral_indices(blue, green, red, red_edge, nir, swir)

        features = {
            "NDVI":               idx["NDVI"],
            "NDRE":               idx["NDRE"],
            "NDMI":               idx["NDMI"],
            "NDWI":               idx["NDWI"],
            "SAVI":               idx["SAVI"],
            "EVI":                idx["EVI"],
            "MSAVI":              idx["MSAVI"],
            "Chlorophyll_Content": float(np.clip(idx["CIRE"], 0, 8)),
        }
        X = pd.DataFrame([features])[ALL_FEATURE_COLS]
        return self._run(X, idx)

    # -- debug path -----------------------------------------------------------
    def infer_from_features(self, feature_dict: dict):
        X = pd.DataFrame([feature_dict])[ALL_FEATURE_COLS]
        return self._run(X)

    def _run(self, X, spectral_indices=None):
        # Works for both sklearn LGBMClassifier (from training) and
        # raw Booster (from load_model / saved file).
        if isinstance(self.model, lgb.Booster):
            raw   = self.model.predict(X)
            proba = np.array(raw).reshape(-1, len(FAILURE_CAUSES))[0]
        else:
            proba = self.model.predict_proba(X)[0]

        cause_id   = int(np.argmax(proba))
        confidence = float(proba[cause_id])

        # Return UNKNOWN when the model isn't confident enough.
        # The parcel should be flagged for manual review or a follow-up pass.
        if confidence < UNKNOWN_CONFIDENCE_THRESHOLD:
            return {
                "failure_cause":    "UNKNOWN",
                "cause_id":         -1,
                "confidence":       confidence,
                "top_candidate":    FAILURE_CAUSES[cause_id],
                "probabilities":    {FAILURE_CAUSES[i]: float(p) for i, p in enumerate(proba)},
                "spectral_indices": spectral_indices or {},
            }

        return {
            "failure_cause":    FAILURE_CAUSES[cause_id],
            "cause_id":         cause_id,
            "confidence":       confidence,
            "probabilities":    {FAILURE_CAUSES[i]: float(p) for i, p in enumerate(proba)},
            "spectral_indices": spectral_indices or {},
        }


# ─────────────────────────────────────────────────────────────────────────────
# DEMO HELPER
# ─────────────────────────────────────────────────────────────────────────────

def print_result(label, result):
    print(f"\n--- {label} ---")
    cause = result["failure_cause"]
    conf  = result["confidence"]
    if cause == "UNKNOWN":
        print(f"  Predicted cause : UNKNOWN  (confidence too low — flag for review)")
        print(f"  Top candidate   : {result.get('top_candidate', '?')}  ({conf:.1%})")
    else:
        print(f"  Predicted cause : {cause}")
        print(f"  Confidence      : {conf:.1%}")
    print("  All probabilities:")
    for c, prob in sorted(result["probabilities"].items(), key=lambda x: -x[1]):
        bar = "#" * int(prob * 25)
        print(f"    {c:<22}  {prob:.3f}  {bar}")
    if result["spectral_indices"]:
        print("  Spectral indices:")
        for k, v in result["spectral_indices"].items():
            print(f"    {k:<20}  {v:.4f}")


def run_demo(classifier):
    print("\n" + "="*60)
    print("DEMO: On-Orbit Inference from 6 Spectral Bands")
    print("="*60)

    # All scenarios use BANDS ONLY — no context passed.
    # This is the real onboard inference path.

    # Scenario 1: moisture stress / drought
    # NDVI=0.53 (active canopy, > 0.30 floor), NDMI=0.024 (< 0.05 threshold).
    # NIR=0.42, SWIR=0.40 — SWIR nearly equal to NIR signals severe water deficit.
    print_result(
        "Drought scenario  [NDVI=0.53, NDMI=0.024 — active canopy, water-limited]",
        classifier.infer_from_bands(
            blue=0.04, green=0.08, red=0.13,
            red_edge=0.20, nir=0.42, swir=0.40,
        )
    )

    # Scenario 2: excess wetness / waterlogging
    # NDMI=0.58 (> 0.35), NDWI=-0.20 (> -0.35 threshold).
    # High green reflectance (water sheen), low SWIR (water absorbs).
    # CIRE=0.67 (just above 0.65) avoids NUTRIENT_DEFICIT trigger.
    print_result(
        "Waterlogging scenario  [NDMI=0.58, NDWI=-0.20 — saturated root zone]",
        classifier.infer_from_bands(
            blue=0.05, green=0.20, red=0.08,
            red_edge=0.18, nir=0.30, swir=0.08,
        )
    )

    # Scenario 3: nutrient deficit
    # CIRE=0.09 (< 0.65 threshold), NDRE=0.043 (< 0.10 threshold).
    # Yellowing canopy — red-edge barely above red, chlorophyll depleted.
    print_result(
        "Nutrient deficit scenario  [CIRE=0.09, NDRE=0.04 — N-deficient yellowing]",
        classifier.infer_from_bands(
            blue=0.05, green=0.09, red=0.15,
            red_edge=0.22, nir=0.24, swir=0.18,
        )
    )

    # Scenario 4: poor establishment
    # NDVI=0.17 (< 0.22 threshold), SAVI=0.12 (< 0.16).
    # Sparse canopy — not drought (NDMI > 0), just failed germination.
    print_result(
        "Poor establishment scenario  [NDVI=0.17, SAVI=0.12 — sparse/patchy canopy]",
        classifier.infer_from_bands(
            blue=0.06, green=0.09, red=0.20,
            red_edge=0.24, nir=0.28, swir=0.23,
        )
    )

    # Scenario 5: pest or disease
    # Spectral profile match: NDMI=0.11, NDRE=0.15, NDWI=-0.32 (PEST profile).
    # NOTE: NBR2 requires SWIR2 (not carried by imager) so the spectral pest rule
    # cannot fire in HLS data. PEST is learned entirely from synthetic training rows.
    # Confidence may be lower than other classes — this is an honest limitation.
    print_result(
        "Pest/disease scenario  [NDMI=0.11, NDRE=0.15 — matches pest spectral profile]",
        classifier.infer_from_bands(
            blue=0.05, green=0.18, red=0.17,
            red_edge=0.26, nir=0.35, swir=0.28,
        )
    )

    # Scenario 6: healthy field
    # NDVI=0.77 (> 0.60 floor), NDMI=0.64, CIRE=2.06 — full canopy, well-watered.
    print_result(
        "Healthy field  [NDVI=0.77, NDMI=0.64, CIRE=2.06]",
        classifier.infer_from_bands(
            blue=0.04, green=0.10, red=0.07,
            red_edge=0.18, nir=0.55, swir=0.12,
        )
    )


# ─────────────────────────────────────────────────────────────────────────────
# MAIN
# ─────────────────────────────────────────────────────────────────────────────

def main():
    demo_only  = "--demo-only" in sys.argv
    use_merged = "--merged"    in sys.argv

    if demo_only:
        print("Loading saved model ...")
        model = load_model()
    else:
        if use_merged:
            if not MERGED_PATH.exists():
                print(f"ERROR: Merged dataset not found at {MERGED_PATH}")
                print("Run  python hls_data_pull.py  first to generate it.")
                return
            print("Training on MERGED dataset (synthetic + real HLS) ...")
            path = MERGED_PATH
        else:
            path = DATA_PATH

        X, y = load_and_prepare(path)
        model, X_test, y_test = train_model(X, y)
        evaluate_model(model, X_test, y_test)
        save_model(model)

    classifier = CoverGuardClassifier(model)
    run_demo(classifier)


if __name__ == "__main__":
    main()
