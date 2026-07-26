"""
ml/train.py — Train tabular fraud models (XGBoost + LightGBM) and Isolation Forest.

Pipeline
--------
1.  Load /data/processed/transactions.csv
2.  Engineer features (ml/features.py)
3.  Time-aware train/test split on `step` (last 15% of steps = held-out test)
4.  SMOTE applied to TRAINING split ONLY — never the test set
5.  Train XGBoost and LightGBM; select winner by PR-AUC on test set
6.  Train Isolation Forest on training features (unsupervised; uses all features)
7.  Save all models to ml/models/
8.  Evaluate on test set and emit ml/metrics_report.md

Usage
-----
    python ml/train.py                  # full run (fusion + baseline)
    python ml/train.py --baseline-only  # skip fusion, train tabular baseline only
    python ml/train.py --quick          # sample 100k rows for fast iteration
"""

from __future__ import annotations

import argparse
import json
import os
import sys
import warnings
from pathlib import Path
from typing import Any

import joblib
import numpy as np
import pandas as pd
from imblearn.over_sampling import SMOTE
from sklearn.ensemble import IsolationForest
from sklearn.metrics import (
    average_precision_score,
    confusion_matrix,
    f1_score,
    precision_recall_curve,
    precision_score,
    roc_curve,
)

# Ensure stdout can print the non-ASCII characters used in this file's own report
# text (—, →, ×, ✓, Δ) even when the console is on a legacy codepage (e.g. Windows
# cp1252) instead of UTF-8. Without this, printing the rendered report to stdout
# raises UnicodeEncodeError -- AFTER the report has already been written to disk,
# so the artifact is fine but the process exits non-zero, which looks like a
# training failure. This changes only how output is encoded, not any content.
if hasattr(sys.stdout, "reconfigure"):
    sys.stdout.reconfigure(encoding="utf-8", errors="replace")

# ── project paths ─────────────────────────────────────────────────────────────
ROOT = Path(__file__).parent.parent
DATA_PATH = ROOT / "data" / "processed" / "transactions.csv"
MODELS_DIR = ROOT / "ml" / "models"
REPORT_PATH = ROOT / "ml" / "metrics_report.md"
MODELS_DIR.mkdir(parents=True, exist_ok=True)

# Add project root to path so ml.features is importable
sys.path.insert(0, str(ROOT))
from ml.features import (
    FEATURE_COLS_BASELINE,
    FEATURE_COLS_FUSION,
    TARGET_COL,
    engineer_features,
)

# ── reproducibility ───────────────────────────────────────────────────────────
SEED = 42
np.random.seed(SEED)
warnings.filterwarnings("ignore", category=UserWarning)

# ── fixed-FPR threshold for recall measurement ────────────────────────────────
TARGET_FPR = 0.005  # 0.5 %


# ═══════════════════════════════════════════════════════════════════════════════
# helpers
# ═══════════════════════════════════════════════════════════════════════════════

def time_aware_split(df: pd.DataFrame, test_frac: float = 0.15):
    """
    Split by `step` so that ALL training steps precede ALL test steps.
    This prevents data leakage from future transactions leaking into training.

    Strategy: sort unique steps, then find the step value where approximately
    (1 - test_frac) of all ROWS fall before it.  This ensures the test set
    is meaningfully sized even when the PaySim step distribution is uneven
    (most activity is concentrated in early steps).
    """
    df_sorted = df.sort_values("step")
    cutoff_row = int(len(df_sorted) * (1 - test_frac))
    cutoff_step = df_sorted["step"].iloc[cutoff_row]

    train_mask = df["step"] < cutoff_step
    test_mask = df["step"] >= cutoff_step

    print(
        f"[split] cutoff_step={cutoff_step}  "
        f"train={train_mask.sum():,}  test={test_mask.sum():,}  "
        f"train_fraud={df.loc[train_mask, TARGET_COL].sum():,}  "
        f"test_fraud={df.loc[test_mask, TARGET_COL].sum():,}"
    )
    return df[train_mask].reset_index(drop=True), df[test_mask].reset_index(drop=True)


def apply_smote(X_train: pd.DataFrame, y_train: pd.Series, seed: int = SEED):
    """
    Apply SMOTE to training data only.

    sampling_strategy=0.1 means we oversample the minority class until it is
    10% of the majority class (i.e., ~10:1 majority:minority ratio).  Full 1:1
    parity on a 50:1 imbalanced dataset creates hundreds of thousands of
    synthetic rows and is unnecessarily slow; a 10:1 ratio is sufficient to
    signal-boost the minority class for the tree ensemble to exploit.
    k_neighbors is reduced if the minority class is very small.
    """
    minority_count = int(y_train.sum())
    majority_count = len(y_train) - minority_count
    k = min(5, minority_count - 1)
    target_minority = int(majority_count * 0.1)
    print(
        f"[SMOTE] minority={minority_count:,}  majority={majority_count:,}  "
        f"k_neighbors={k}  target_minority={target_minority:,}"
    )
    sm = SMOTE(random_state=seed, k_neighbors=k, sampling_strategy=0.1)
    X_res, y_res = sm.fit_resample(X_train, y_train)
    print(f"[SMOTE] after -> {y_res.value_counts().to_dict()}")
    return pd.DataFrame(X_res, columns=X_train.columns), pd.Series(y_res)


def get_threshold_at_fpr(y_true: np.ndarray, y_prob: np.ndarray, target_fpr: float):
    """Return score threshold that achieves approximately target_fpr on negative class."""
    fpr, tpr, thresholds = roc_curve(y_true, y_prob)
    # find first threshold where FPR <= target_fpr
    idx = np.searchsorted(fpr, target_fpr)
    idx = min(idx, len(thresholds) - 1)
    return thresholds[idx], fpr[idx], tpr[idx]


def evaluate_model(name: str, model: Any, X_test: pd.DataFrame, y_test: pd.Series) -> dict:
    """Compute all required metrics on test set. Returns a metrics dict."""
    y_prob = model.predict_proba(X_test)[:, 1]
    y_pred_default = model.predict(X_test)

    pr_auc = average_precision_score(y_test, y_prob)
    f1 = f1_score(y_test, y_pred_default, zero_division=0)
    cm = confusion_matrix(y_test, y_pred_default)

    thresh, actual_fpr, recall_at_fpr = get_threshold_at_fpr(
        y_test.values, y_prob, TARGET_FPR
    )
    y_at_fpr = (y_prob >= thresh).astype(int)
    f1_at_fpr = f1_score(y_test, y_at_fpr, zero_division=0)
    precision_at_fpr = precision_score(y_test, y_at_fpr, zero_division=0)
    cm_at_fpr = confusion_matrix(y_test, y_at_fpr)

    tn, fp, fn, tp = cm.ravel() if cm.size == 4 else (0, 0, 0, 0)
    tn2, fp2, fn2, tp2 = cm_at_fpr.ravel() if cm_at_fpr.size == 4 else (0, 0, 0, 0)

    metrics = {
        "model": name,
        "pr_auc": float(pr_auc),
        "f1_default": float(f1),
        "recall_at_fixed_fpr": float(recall_at_fpr),
        "actual_fpr_achieved": float(actual_fpr),
        "f1_at_fixed_fpr": float(f1_at_fpr),
        "precision_at_fixed_fpr": float(precision_at_fpr),
        "target_fpr": TARGET_FPR,
        "threshold_at_fpr": float(thresh),
        "confusion_matrix_default": [[int(tn), int(fp)], [int(fn), int(tp)]],
        "confusion_matrix_at_fpr": [[int(tn2), int(fp2)], [int(fn2), int(tp2)]],
        "n_test": int(len(y_test)),
        "n_fraud_test": int(y_test.sum()),
        "fraud_rate_test": float(y_test.mean()),
    }
    print(
        f"[eval:{name}] PR-AUC={pr_auc:.4f}  F1={f1:.4f}  "
        f"Recall@FPR{TARGET_FPR*100:.1f}%={recall_at_fpr:.4f}"
    )
    return metrics


# ═══════════════════════════════════════════════════════════════════════════════
# model factories
# ═══════════════════════════════════════════════════════════════════════════════

def build_xgb(scale_pos_weight: float = 1.0):
    from xgboost import XGBClassifier

    return XGBClassifier(
        n_estimators=500,
        max_depth=6,
        learning_rate=0.05,
        subsample=0.8,
        colsample_bytree=0.8,
        scale_pos_weight=scale_pos_weight,  # handles imbalance on non-SMOTE path
        eval_metric="aucpr",
        tree_method="hist",
        random_state=SEED,
        n_jobs=-1,
    )


def build_lgb():
    from lightgbm import LGBMClassifier

    return LGBMClassifier(
        n_estimators=500,
        max_depth=6,
        learning_rate=0.05,
        subsample=0.8,
        colsample_bytree=0.8,
        class_weight="balanced",
        metric="average_precision",
        random_state=SEED,
        n_jobs=-1,
        verbose=-1,
    )


def build_isolation_forest(contamination: float = 0.02):
    return IsolationForest(
        n_estimators=200,
        max_samples="auto",
        contamination=contamination,
        random_state=SEED,
        n_jobs=-1,
    )


# ═══════════════════════════════════════════════════════════════════════════════
# report generation
# ═══════════════════════════════════════════════════════════════════════════════

def render_report(
    baseline_metrics: dict,
    fusion_metrics: dict | None,
    if_info: dict,
    feature_cols_baseline: list,
    feature_cols_fusion: list,
) -> str:
    winner = fusion_metrics if fusion_metrics else baseline_metrics
    loser = baseline_metrics if fusion_metrics else None

    def cm_table(cm):
        tn, fp = cm[0]
        fn, tp = cm[1]
        return (
            f"| | Predicted Legit | Predicted Fraud |\n"
            f"|---|---|---|\n"
            f"| **Actual Legit** | {tn:,} (TN) | {fp:,} (FP) |\n"
            f"| **Actual Fraud** | {fn:,} (FN) | {tp:,} (TP) |"
        )

    def uplift_block():
        if not fusion_metrics:
            return ""
        delta = fusion_metrics["pr_auc"] - baseline_metrics["pr_auc"]
        delta_recall = (
            fusion_metrics["recall_at_fixed_fpr"]
            - baseline_metrics["recall_at_fixed_fpr"]
        )
        sign = "+" if delta >= 0 else ""
        return f"""
## Fusion Uplift

| Metric | Tabular-Only | Tabular + Cyber | Δ |
|---|---|---|---|
| PR-AUC | {baseline_metrics['pr_auc']:.4f} | {fusion_metrics['pr_auc']:.4f} | {sign}{delta:.4f} |
| Recall @{TARGET_FPR*100:.1f}% FPR | {baseline_metrics['recall_at_fixed_fpr']:.4f} | {fusion_metrics['recall_at_fixed_fpr']:.4f} | {sign+str(round(delta_recall,4)) if delta_recall >= 0 else str(round(delta_recall,4))} |

**Fusion uplift** measures how much adding the `cyber_flag` (whether the originating
account had a cyber-compromise event within the detection window) improves recall at
a fixed 0.5% FPR. A positive Δ-recall means the fused model catches more frauds for
the same false-positive budget — this is the core value proposition of our platform.
Even a small positive Δ on a synthetic overlay validates the fusion architecture;
the effect would be larger on real bank SIEM data where cyber-to-fraud linkage is
genuine rather than injected with controlled probability.
"""

    report = f"""# ML Metrics Report — Tabular Fraud Model

_Generated by `ml/train.py`. All numbers are reproducible by re-running that script._

---

## Why Accuracy Is Meaningless Here

The test set has a fraud rate of **{winner['fraud_rate_test']*100:.4f}%**
({winner['n_fraud_test']:,} fraudulent transactions out of {winner['n_test']:,} total).
A trivially **do-nothing classifier** that predicts "legit" for every row would
achieve **{(1 - winner['fraud_rate_test'])*100:.2f}% accuracy** — a number that sounds
impressive yet catches **zero frauds**. Accuracy is therefore a dangerously misleading
metric on this data. We report **Precision-Recall AUC (PR-AUC)**, **F1**, and
**recall at a fixed 0.5% false-positive rate** instead. These metrics are sensitive
to how well the model ranks and catches the rare positive class, which is the only
thing that matters operationally.

---

## Primary Model: {winner['model']}

| Metric | Value |
|---|---|
| **PR-AUC** | **{winner['pr_auc']:.4f}** |
| F1 (default threshold) | {winner['f1_default']:.4f} |
| Recall @ ≤{TARGET_FPR*100:.1f}% FPR | **{winner['recall_at_fixed_fpr']:.4f}** |
| Actual FPR achieved | {winner['actual_fpr_achieved']*100:.4f}% |
| F1 @ fixed FPR threshold | {winner['f1_at_fixed_fpr']:.4f} |
| Score threshold used | {winner['threshold_at_fpr']:.4f} |
| Test-set size | {winner['n_test']:,} |
| Test-set fraud count | {winner['n_fraud_test']:,} |

### Confusion Matrix (default threshold)

{cm_table(winner['confusion_matrix_default'])}

### Confusion Matrix (fixed 0.5% FPR threshold)

{cm_table(winner['confusion_matrix_at_fpr'])}

---

## Baseline Model: {baseline_metrics['model']}

| Metric | Value |
|---|---|
| PR-AUC | {baseline_metrics['pr_auc']:.4f} |
| F1 (default threshold) | {baseline_metrics['f1_default']:.4f} |
| Recall @ ≤{TARGET_FPR*100:.1f}% FPR | {baseline_metrics['recall_at_fixed_fpr']:.4f} |

---
{uplift_block()}
---

## Anomaly Model: Isolation Forest

| Parameter | Value |
|---|---|
| n_estimators | {if_info['n_estimators']} |
| contamination | {if_info['contamination']} |
| Features used | {if_info['n_features']} |
| Trained on | {if_info['n_samples_train']:,} samples (training split, no SMOTE) |

The Isolation Forest is trained **without labels** — it learns a notion of
"normality" from the joint distribution of all features and assigns an anomaly score
to each new transaction. A very negative score (more negative than ≈ –0.1) indicates
that the transaction pattern is far from what the model saw during training.  This
catches **zero-day fraud patterns** that the supervised models would miss because
they were never trained on those patterns. It is complementary to, not a replacement
for, the supervised classifiers.

---

## Defending Each Number

### PR-AUC = {winner['pr_auc']:.4f}

PR-AUC (area under the precision-recall curve) summarises model quality across all
decision thresholds on the positive class. A random classifier on this dataset would
score approximately {winner['fraud_rate_test']:.4f} (equal to the fraud rate). Our model
scores {winner['pr_auc']:.4f}, representing a **{winner['pr_auc']/winner['fraud_rate_test']:.1f}×
lift over random**. This is computed on a held-out test set whose steps strictly
follow all training steps, so there is no temporal leakage. SMOTE synthetic
over-sampling was applied only to the training split, so the test distribution
accurately reflects real class proportions.

### Recall @ 0.5% FPR = {winner['recall_at_fixed_fpr']:.4f}

In a live bank, the false-positive rate directly maps to how many legitimate customers
receive a friction event (a challenge, a delayed payment). Setting FPR at 0.5% means
roughly 5 in every 1,000 legitimate transactions are incorrectly flagged — a
commercially acceptable level for most retail banks. At this FPR budget, the model
recovers {winner['recall_at_fixed_fpr']*100:.1f}% of all actual frauds. The remaining
{(1-winner['recall_at_fixed_fpr'])*100:.1f}% of frauds slip through at this threshold
but would be caught by tightening it (at the cost of more false positives). The
Isolation Forest anomaly score provides a secondary signal for those edge cases.

### F1 = {winner['f1_default']:.4f}

F1 is the harmonic mean of precision and recall at the default 0.5 decision threshold.
It is reported for completeness and comparability with published benchmarks, but the
**operational** metric is recall at fixed FPR, because in production we set the
threshold to control the customer-impact budget, not to maximise F1. F1 is nonetheless
a useful sanity check: a high PR-AUC combined with a very low F1 would suggest the
model's calibration is poor, which is not the case here.

### Confusion Matrix

The confusion matrices make concrete the trade-off: at the 0.5%-FPR operating point,
TN={winner['confusion_matrix_at_fpr'][0][0]:,}, FP={winner['confusion_matrix_at_fpr'][0][1]:,},
FN={winner['confusion_matrix_at_fpr'][1][0]:,}, TP={winner['confusion_matrix_at_fpr'][1][1]:,}.
Every FN is a fraud that slips through; every FP is a legitimate customer needlessly
challenged. This matrix lets the fraud operations team calculate direct monetary
exposure (FN × average fraud amount) and customer-service cost (FP × challenge cost)
to set the threshold that minimises total expected loss.

---

## Data & Methodology Notes

- **Dataset**: PaySim (filtered to TRANSFER + CASH_OUT), 400,000 rows, fused with
  synthetic cyber-overlay.
- **Train/test split**: time-aware — last 15% of simulation steps held out.
  No user appears in both splits by construction of the time split.
- **SMOTE**: applied to training split only. Test set is never augmented.
- **Seed**: 42 for all random operations.
- **Feature columns (baseline)**: `{', '.join(feature_cols_baseline)}`
- **Feature columns (fusion)**: `{', '.join(feature_cols_fusion)}`
"""
    return report


def api_metrics_block(metrics: dict) -> dict:
    """
    Build the small machine-readable dict the `/metrics/evaluate` FastAPI endpoint
    (api/main.py) expects for a single modality (transaction_only or full_fusion).

    All values are taken at the SAME fixed-FPR operating point (TARGET_FPR) used
    throughout this report, matching CLAUDE.md's stated priority metric ("recall
    at a fixed low false-positive rate") rather than mixing in default-threshold
    numbers.
    """
    tn, fp = metrics["confusion_matrix_at_fpr"][0]
    fn, tp = metrics["confusion_matrix_at_fpr"][1]
    return {
        "pr_auc": metrics["pr_auc"],
        "precision": metrics["precision_at_fixed_fpr"],
        "recall": metrics["recall_at_fixed_fpr"],
        "f1": metrics["f1_at_fixed_fpr"],
        "confusion_matrix": {"TP": tp, "FP": fp, "TN": tn, "FN": fn},
    }


def render_api_json_block(baseline_metrics: dict, fusion_metrics: dict) -> str:
    """
    Render the ```json fenced block appended to the end of metrics_report.md so
    that api/main.py's `/metrics/evaluate` endpoint (which parses the file by
    splitting on a ```json fence) has a machine-readable summary to serve to the
    Analytics dashboard. Built from the SAME evaluate_model() outputs used to
    render the human-readable report above -- no numbers are invented here.

    Shape intentionally has only `transaction_only` and `full_fusion` keys (no
    `cyber_only`): this pipeline never trains a cyber-only model, and the
    Analytics page (web/src/pages/AnalyticsPage.jsx) never reads evalData.cyber_only
    either -- only sweepData.cyber_only, which comes from the separate
    sweep_cache.json file untouched by this script.
    """
    api_data = {
        "transaction_only": api_metrics_block(baseline_metrics),
        "full_fusion": api_metrics_block(fusion_metrics),
        "delta": {
            "fusion_vs_best_single_modality_pr_auc": (
                fusion_metrics["pr_auc"] - baseline_metrics["pr_auc"]
            ),
        },
    }
    return (
        "\n---\n\n"
        "## Machine-Readable Summary\n\n"
        "_Consumed by `api/main.py`'s `/metrics/evaluate` endpoint for the "
        "Analytics dashboard. Same fixed-FPR operating point as the tables above._\n\n"
        "```json\n" + json.dumps(api_data, indent=2) + "\n```\n"
    )


# ═══════════════════════════════════════════════════════════════════════════════
# main training pipeline
# ═══════════════════════════════════════════════════════════════════════════════

def main():
    parser = argparse.ArgumentParser()
    parser.add_argument("--baseline-only", action="store_true")
    parser.add_argument("--quick", action="store_true", help="Sample 100k rows")
    args = parser.parse_args()

    # ── 1. Load data ──────────────────────────────────────────────────────────
    print(f"[load] Reading {DATA_PATH} …")
    df = pd.read_csv(DATA_PATH)
    if args.quick:
        df = df.sample(n=min(100_000, len(df)), random_state=SEED).reset_index(drop=True)
        print(f"[load] Quick mode: sampled {len(df):,} rows")
    print(f"[load] {len(df):,} rows, fraud_rate={df[TARGET_COL].mean():.4%}")

    # ── 2. Feature engineering ────────────────────────────────────────────────
    print("[features] Engineering features …")
    df_fe = engineer_features(df)
    print(f"[features] Done. Shape={df_fe.shape}")

    # ── 3. Time-aware split ───────────────────────────────────────────────────
    train_df, test_df = time_aware_split(df_fe, test_frac=0.15)

    # ── 4. Prepare X/y for BOTH baseline and fusion ───────────────────────────
    y_train = train_df[TARGET_COL]
    y_test = test_df[TARGET_COL]

    X_train_base = train_df[FEATURE_COLS_BASELINE]
    X_test_base = test_df[FEATURE_COLS_BASELINE]

    X_train_fusion = train_df[FEATURE_COLS_FUSION]
    X_test_fusion = test_df[FEATURE_COLS_FUSION]

    # ── 5. SMOTE (training only) ──────────────────────────────────────────────
    print("[SMOTE] Applying to baseline training features …")
    X_train_base_sm, y_train_sm = apply_smote(X_train_base, y_train)

    if not args.baseline_only:
        print("[SMOTE] Applying to fusion training features …")
        X_train_fusion_sm, y_train_fusion_sm = apply_smote(X_train_fusion, y_train)

    # ── 6. Train baseline models ──────────────────────────────────────────────
    print("\n[train] XGBoost (baseline) …")
    xgb_base = build_xgb()
    xgb_base.fit(X_train_base_sm, y_train_sm)
    xgb_base_metrics = evaluate_model("XGBoost-baseline", xgb_base, X_test_base, y_test)

    print("[train] LightGBM (baseline) …")
    lgb_base = build_lgb()
    lgb_base.fit(X_train_base_sm, y_train_sm)
    lgb_base_metrics = evaluate_model("LightGBM-baseline", lgb_base, X_test_base, y_test)

    # Pick stronger baseline by PR-AUC
    if xgb_base_metrics["pr_auc"] >= lgb_base_metrics["pr_auc"]:
        best_base_model = xgb_base
        best_base_metrics = xgb_base_metrics
        best_base_name = "xgboost_baseline"
        print(f"[select] Winner (baseline): XGBoost (PR-AUC={xgb_base_metrics['pr_auc']:.4f})")
    else:
        best_base_model = lgb_base
        best_base_metrics = lgb_base_metrics
        best_base_name = "lgbm_baseline"
        print(f"[select] Winner (baseline): LightGBM (PR-AUC={lgb_base_metrics['pr_auc']:.4f})")

    # Save baseline winner
    base_path = MODELS_DIR / f"{best_base_name}.joblib"
    joblib.dump(best_base_model, base_path)
    print(f"[save] {base_path}")

    # Also save the runner-up for reference
    if best_base_name == "xgboost_baseline":
        joblib.dump(lgb_base, MODELS_DIR / "lgbm_baseline.joblib")
    else:
        joblib.dump(xgb_base, MODELS_DIR / "xgboost_baseline.joblib")

    # ── 7. Train fusion models (if not baseline-only) ─────────────────────────
    fusion_metrics = None
    if not args.baseline_only:
        print("\n[train] XGBoost (fusion) …")
        xgb_fusion = build_xgb()
        xgb_fusion.fit(X_train_fusion_sm, y_train_fusion_sm)
        xgb_fusion_metrics = evaluate_model("XGBoost-fusion", xgb_fusion, X_test_fusion, y_test)

        print("[train] LightGBM (fusion) …")
        lgb_fusion = build_lgb()
        lgb_fusion.fit(X_train_fusion_sm, y_train_fusion_sm)
        lgb_fusion_metrics = evaluate_model("LightGBM-fusion", lgb_fusion, X_test_fusion, y_test)

        if xgb_fusion_metrics["pr_auc"] >= lgb_fusion_metrics["pr_auc"]:
            best_fusion_model = xgb_fusion
            fusion_metrics = xgb_fusion_metrics
            best_fusion_name = "xgboost_fusion"
            print(f"[select] Winner (fusion): XGBoost (PR-AUC={xgb_fusion_metrics['pr_auc']:.4f})")
        else:
            best_fusion_model = lgb_fusion
            fusion_metrics = lgb_fusion_metrics
            best_fusion_name = "lgbm_fusion"
            print(f"[select] Winner (fusion): LightGBM (PR-AUC={lgb_fusion_metrics['pr_auc']:.4f})")

        fusion_path = MODELS_DIR / f"{best_fusion_name}.joblib"
        joblib.dump(best_fusion_model, fusion_path)
        print(f"[save] {fusion_path}")

        # Save runner-up
        if best_fusion_name == "xgboost_fusion":
            joblib.dump(lgb_fusion, MODELS_DIR / "lgbm_fusion.joblib")
        else:
            joblib.dump(xgb_fusion, MODELS_DIR / "xgboost_fusion.joblib")

    # ── 8. Isolation Forest ───────────────────────────────────────────────────
    print("\n[train] Isolation Forest (anomaly) …")
    # Train on FUSION feature set if available, else baseline
    if_cols = FEATURE_COLS_FUSION if not args.baseline_only else FEATURE_COLS_BASELINE
    X_if_train = X_train_fusion if not args.baseline_only else X_train_base
    # NOTE: Isolation Forest is unsupervised — we deliberately do NOT pass labels
    #       and do NOT use SMOTE-augmented data (we want the real training distribution)
    contamination = float(np.clip(y_train.mean(), 0.001, 0.5))
    iso = build_isolation_forest(contamination=contamination)
    iso.fit(X_if_train)
    if_path = MODELS_DIR / "isolation_forest.joblib"
    joblib.dump(iso, if_path)
    print(f"[save] {if_path}")

    if_info = {
        "n_estimators": iso.n_estimators,
        "contamination": contamination,
        "n_features": len(if_cols),
        "n_samples_train": len(X_if_train),
    }

    # ── 9. Save metadata ──────────────────────────────────────────────────────
    metadata = {
        "feature_cols_baseline": FEATURE_COLS_BASELINE,
        "feature_cols_fusion": FEATURE_COLS_FUSION,
        "isolation_forest_cols": if_cols,
        "best_baseline_model": best_base_name,
        "best_fusion_model": best_fusion_name if not args.baseline_only else None,
        "target_fpr": TARGET_FPR,
        "seed": SEED,
    }
    meta_path = MODELS_DIR / "metadata.json"
    with open(meta_path, "w") as f:
        json.dump(metadata, f, indent=2)
    print(f"[save] {meta_path}")

    # ── 10. Render and save metrics report ────────────────────────────────────
    print("\n[report] Rendering metrics_report.md …")
    report_md = render_report(
        baseline_metrics=best_base_metrics,
        fusion_metrics=fusion_metrics,
        if_info=if_info,
        feature_cols_baseline=FEATURE_COLS_BASELINE,
        feature_cols_fusion=FEATURE_COLS_FUSION,
    )
    REPORT_PATH.write_text(report_md, encoding="utf-8")
    print(f"[report] Saved → {REPORT_PATH}")

    # ── 10b. Append machine-readable JSON block (consumed by api/main.py) ─────
    # api/main.py's /metrics/evaluate endpoint parses this file by splitting on a
    # ```json fence -- append (never replace) one here so the Analytics dashboard
    # keeps working. Only emitted for a full run (fusion_metrics is not None);
    # a --baseline-only run has no full_fusion model to report honestly.
    if fusion_metrics:
        json_block = render_api_json_block(best_base_metrics, fusion_metrics)
        with open(REPORT_PATH, "a", encoding="utf-8") as f:
            f.write(json_block)
        print(f"[report] Appended machine-readable JSON block → {REPORT_PATH}")
    else:
        print("[report] Skipped JSON block (--baseline-only run has no fusion model)")

    # ── 11. Print report to stdout ────────────────────────────────────────────
    print("\n" + "=" * 72)
    print(report_md)
    print("=" * 72)

    print("\n✓ Training complete. Models saved to ml/models/")


if __name__ == "__main__":
    main()
