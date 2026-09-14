"""Generic per-participant train/eval driver.

Replaces the hand-rolled per-participant loops in CNV_XGB_4.3.py /
CNV_LSTM_3.py / CNV_ML_SVM_1.py. Picks a model factory by name, applies a
configurable feature-selection schedule, runs nested hyperparameter search,
and returns fold-level metrics.

Smoke-friendliness: every heavy step (RFECV iterations, hyperparameter search,
SHAP) is driven by ``cfg["modeling"]`` and shrinks automatically when the
smoke config is active.
"""

from __future__ import annotations

import copy
import importlib
import os
import re
import time

import numpy as np
import pandas as pd
from sklearn.experimental import enable_halving_search_cv  # noqa: F401
from sklearn.model_selection import (
    GridSearchCV,
    HalvingRandomSearchCV,
    KFold,
    ParameterGrid,
    RandomizedSearchCV,
    RepeatedStratifiedKFold,
    StratifiedGroupKFold,
    StratifiedKFold,
)

from ..config import apply_participant_override
from ..features.assemble import build_for_participant
from ..features.tensor import build_tensor_for_participant
from ..io import write_csv, run_dir, ensure_dir
from ..logging_utils import get_logger, make_run_id, stamp_run
from ..progress import FoldETA, CohortETA
from ..resources import resolve_n_jobs
from . import feature_selection as fs
from . import xgb as xgb_factory
from . import svm as svm_factory
from . import lstm as lstm_factory
from . import logistic as logistic_factory
from . import riemannian as riemannian_factory
from . import cnn as cnn_factory
from . import eegnet as eegnet_factory
from . import eegnext as eegnext_factory
from .normalization import maybe_prefix_param_grid, maybe_wrap_estimator, unwrap_classifier
from .evaluate import participant_metrics, cv_rollup


log = get_logger(__name__)


def _lazy(module: str, attr: str):
    """Resolve ``models.<module>.<attr>`` on first call instead of at import.

    For model modules that import a heavy framework when they load
    (``eegnet_torch`` imports PyTorch): classical runs, and their joblib
    workers, import this driver without paying for it.
    """

    def call(*args, **kwargs):
        return getattr(importlib.import_module(f".{module}", __package__), attr)(*args, **kwargs)

    call.__name__ = call.__qualname__ = attr
    return call


# --- Model registry -------------------------------------------------------
# Each entry describes how to build the model, the hyperparameter grid, and
# which optimization stages apply. ``data_representation`` selects the
# training data path: "tabular" uses the flat feature parquet from
# features.assemble; "tensor" loads (n_epochs, n_channels, n_times) data
# from features.tensor and skips the feature-selection stages entirely
# (correlation drop, k-best, RFECV, gain, SHAP -- none apply to tensor input).
MODEL_FACTORIES: dict[str, dict] = {
    "xgb": {
        "make":         xgb_factory.make_xgb,
        "param_grid":   xgb_factory.param_grid,
        "rfecv_base":   xgb_factory.make_rfecv_base,
        "supports_gain": True,
        "supports_shap": True,
        "data_representation": "tabular",
    },
    "svm": {
        "make":         svm_factory.make_svm,
        "param_grid":   svm_factory.param_grid,
        "rfecv_base":   None,
        "supports_gain": False,
        "supports_shap": False,
        "data_representation": "tabular",
    },
    "lstm": {
        "make":         lstm_factory.make_lstm,
        "param_grid":   lstm_factory.param_grid,
        "rfecv_base":   None,
        "supports_gain": False,
        "supports_shap": False,
        "data_representation": "tabular",  # legacy n_timesteps=1 path
    },
    "logistic": {
        "make":         logistic_factory.make_logistic,
        "param_grid":   logistic_factory.param_grid,
        "rfecv_base":   None,
        "supports_gain": False,
        "supports_shap": False,
        "data_representation": "tabular",
    },
    "riemannian": {
        "make":         riemannian_factory.make_riemannian,
        "param_grid":   riemannian_factory.param_grid,
        "rfecv_base":   None,
        "supports_gain": False,
        "supports_shap": False,
        "data_representation": "tensor",
    },
    "cnn": {
        "make":         cnn_factory.make_cnn,
        "param_grid":   cnn_factory.param_grid,
        "rfecv_base":   None,
        "supports_gain": False,
        "supports_shap": False,
        "data_representation": "tensor",
    },
    "eegnet": {
        "make":         eegnet_factory.make_eegnet,
        "param_grid":   eegnet_factory.param_grid,
        "rfecv_base":   None,
        "supports_gain": False,
        "supports_shap": False,
        "data_representation": "tensor",
    },
    # PyTorch port of eegnet (same layers, constraints and training settings).
    # Registered lazily because its module imports torch.
    "eegnet_torch": {
        "make":         _lazy("eegnet_torch", "make_eegnet_torch"),
        "param_grid":   _lazy("eegnet_torch", "param_grid"),
        "rfecv_base":   None,
        "supports_gain": False,
        "supports_shap": False,
        "data_representation": "tensor",
    },
    "eegnext": {
        "make":         eegnext_factory.make_eegnext,
        "param_grid":   eegnext_factory.param_grid,
        "rfecv_base":   None,
        "supports_gain": False,
        "supports_shap": False,
        "data_representation": "tensor",
    },
}

# Hybrid neural models fuse the raw epoch tensor with the XGB-style tabular
# branch and are constructed with an ``input_shape`` kwarg (unlike lstm, which
# takes ``n_features``, or riemannian, which builds its own pipeline).
NEURAL_HYBRID_MODELS = {"cnn", "eegnet", "eegnet_torch", "eegnext"}


def _participant_metrics_path(rdir, participant_id: str):
    """Return the per-participant checkpoint path within a run directory."""
    return ensure_dir(rdir / "participants") / f"{participant_id}_metrics.csv"


# ---------------------------------------------------------------------------
def train_one_participant(
    participant_id: str,
    cfg: dict,
    model_name: str,
    *,
    channel_mode: str | None = None,
    cv_mode: str | None = None,
) -> list[dict]:
    """Run nested CV for one participant and return one metrics row per fold."""
    cfg = apply_participant_override(cfg, participant_id)
    factory = MODEL_FACTORIES[model_name]
    representation = factory.get("data_representation", "tabular")

    if representation == "tensor":
        return _train_one_participant_tensor(
            participant_id, cfg, model_name, factory,
            channel_mode=channel_mode, cv_mode=cv_mode,
        )

    df = build_for_participant(participant_id, cfg)
    df = _apply_channel_selection(df, cfg, model_name, channel_mode=channel_mode)
    df = df.dropna(axis=1, how="any")

    groups = df["block_id"] if "block_id" in df.columns else None
    X = df.drop(columns=["condition", "participant_id", "block_id"], errors="ignore")
    y = df["condition"].map({"One": 0, "Two": 1}).astype(int)
    X = X.reset_index(drop=True)
    y = y.reset_index(drop=True)
    if groups is not None:
        groups = groups.reset_index(drop=True)

    splits = _outer_splits(X, y, groups, cfg, cv_mode=cv_mode)
    log.info(
        "[%s/%s] starting nested CV: %d outer fold(s), inner grid≈%s candidate(s)",
        participant_id, model_name, len(splits),
        _param_grid_size(factory["param_grid"](cfg)),
    )
    eta = FoldETA(total_folds=len(splits))
    rows: list[dict] = []
    for fold_idx, split in enumerate(splits, 1):
        log.info(
            "[%s/%s] outer fold %d/%d starting (cv_mode=%s, repeat=%d, fold=%d)",
            participant_id, model_name, fold_idx, len(splits),
            split.get("cv_mode"), split.get("repeat"), split.get("fold"),
        )
        t0 = time.perf_counter()
        row = _fit_score_split(
            participant_id,
            cfg,
            model_name,
            factory,
            X,
            y,
            split["train_idx"],
            split["test_idx"],
        )
        fold_dt = time.perf_counter() - t0
        eta.record(fold_dt)
        log.info(
            "[%s/%s] outer fold %d/%d done in %.1fs · %s",
            participant_id, model_name, fold_idx, len(splits),
            fold_dt, eta.format(),
        )
        row.update({k: v for k, v in split.items() if not k.endswith("_idx")})
        row["channel_mode"] = _effective_channel_mode(cfg, model_name, channel_mode)
        row["prediction_window"] = cfg.get("_prediction_window", "late_cnv")
        row["window_min_time"] = float(cfg["features"]["min_time"])
        row["window_max_time"] = float(cfg["features"]["max_time"])
        rows.append(row)
    return rows


def _train_one_participant_tensor(
    participant_id: str,
    cfg: dict,
    model_name: str,
    factory: dict,
    *,
    channel_mode: str | None,
    cv_mode: str | None,
) -> list[dict]:
    """Tensor/hybrid-input training path (Riemannian, CNN, EEGNet).

    Skips correlation drop / k-best / RFECV / gain / SHAP -- none of those
    are applied to the tensor branch. CNN/EEGNet may append XGB-style tabular
    features, but the branch is passed directly to the neural model rather
    than through the classical feature-selection schedule.
    """
    log.info("[%s/%s] loading epoch tensor...", participant_id, model_name)
    bundle = build_tensor_for_participant(participant_id, cfg)
    tensor = np.asarray(bundle["data"])
    if _neural_uses_tabular_features(cfg, model_name):
        X, tabular_info = _build_neural_hybrid_input(
            participant_id,
            cfg,
            model_name,
            bundle,
            tensor,
            channel_mode=channel_mode,
        )
        cfg["_neural_hybrid_input"] = {
            "n_channels": int(tensor.shape[1]),
            "n_times": int(tensor.shape[2]),
            "n_tabular_features": int(tabular_info["n_tabular_features"]),
        }
    else:
        X = tensor
        tabular_info = {"n_tabular_features": 0, "n_source_features": 0}
    y = pd.Series(bundle["labels"]).map({"One": 0, "Two": 1}).astype(int).reset_index(drop=True)
    block_ids = bundle.get("block_ids")
    groups = pd.Series(block_ids).reset_index(drop=True) if block_ids is not None else None
    log.info(
        "[%s/%s] tensor ready: %d epochs × %d channels × %d samples (class balance %d/%d)",
        participant_id, model_name,
        tensor.shape[0], tensor.shape[1], tensor.shape[2],
        int((y == 0).sum()), int((y == 1).sum()),
    )
    if int(tabular_info["n_tabular_features"]) > 0:
        log.info(
            "[%s/%s] hybrid neural features: %d flattened EEG samples + %d tabular "
            "features (%d source-space)",
            participant_id, model_name,
            int(tensor.shape[1] * tensor.shape[2]),
            int(tabular_info["n_tabular_features"]),
            int(tabular_info["n_source_features"]),
        )

    splits = _outer_splits_tensor(X, y, groups, cfg, cv_mode=cv_mode)
    grid = factory["param_grid"](cfg)
    inner_splits = int(_cv_config(cfg).get("inner_splits", cfg.get("modeling", {}).get("inner_cv_splits", 2)))
    log.info(
        "[%s/%s] starting nested CV: %d outer fold(s) × %d candidate(s) × %d inner fold(s) "
        "= %d inner fit(s) + %d outer refit(s)",
        participant_id, model_name,
        len(splits), _param_grid_size(grid), inner_splits,
        len(splits) * _param_grid_size(grid) * inner_splits, len(splits),
    )
    eta = FoldETA(total_folds=len(splits))

    rows: list[dict] = []
    for fold_idx, split in enumerate(splits, 1):
        log.info(
            "[%s/%s] outer fold %d/%d starting (cv_mode=%s, repeat=%d, fold=%d, "
            "train=%d, test=%d)",
            participant_id, model_name, fold_idx, len(splits),
            split.get("cv_mode"), split.get("repeat"), split.get("fold"),
            len(split["train_idx"]), len(split["test_idx"]),
        )
        t0 = time.perf_counter()
        row = _fit_score_split_tensor(
            participant_id, cfg, model_name, factory,
            X, y,
            split["train_idx"], split["test_idx"],
        )
        fold_dt = time.perf_counter() - t0
        eta.record(fold_dt)
        log.info(
            "[%s/%s] outer fold %d/%d done in %.1fs · %s",
            participant_id, model_name, fold_idx, len(splits),
            fold_dt, eta.format(),
        )
        row.update({k: v for k, v in split.items() if not k.endswith("_idx")})
        row["channel_mode"] = "full"          # tensor models always use every channel
        row["prediction_window"] = cfg.get("_prediction_window", "late_cnv")
        row["window_min_time"] = float(cfg["features"]["min_time"])
        row["window_max_time"] = float(cfg["features"]["max_time"])
        rows.append(row)
    return rows


def _fit_score_split_tensor(
    participant_id: str,
    cfg: dict,
    model_name: str,
    factory: dict,
    X: np.ndarray,
    y: pd.Series,
    train_idx: np.ndarray,
    test_idx: np.ndarray,
) -> dict:
    """Fit and score one outer fold on tensor input. No feature selection."""
    X_train, X_test = X[train_idx], X[test_idx]
    y_train, y_test = y.iloc[train_idx].copy(), y.iloc[test_idx].copy()

    search = _fit_search(
        factory, cfg, model_name, X_train, y_train,
        scale_pos_weight=_scale_pos_weight(y_train),
    )
    log.info("[%s/%s] outer fold best CV=%.3f, params=%s",
             participant_id, model_name, search.best_score_, search.best_params_)

    best = search.best_estimator_
    proba = (
        best.predict_proba(X_test)[:, 1]
        if hasattr(best, "predict_proba")
        else best.decision_function(X_test)
    )
    pred = (proba >= 0.5).astype(int)

    metrics = participant_metrics(np.asarray(y_test), pred, np.asarray(proba))
    metrics["participant_id"] = participant_id
    metrics["model"] = model_name
    # Report the input dimensionality. Riemannian uses channels × times; hybrid
    # CNN/EEGNet packs flattened EEG plus tabular XGB-style features.
    metrics["n_features_final"] = int(
        X_train.shape[1] * X_train.shape[2]
        if getattr(X_train, "ndim", 2) == 3
        else X_train.shape[1]
    )
    metrics["best_params"] = str(search.best_params_)
    metrics["inner_best_score"] = float(search.best_score_)
    metrics["search_method"] = _search_method(cfg, model_name)
    return metrics


def _neural_uses_tabular_features(cfg: dict, model_name: str) -> bool:
    if model_name not in NEURAL_HYBRID_MODELS:
        return False
    ncfg = cfg.get("modeling", {}).get(model_name, {}).get("tabular_features", {})
    return bool(ncfg.get("enabled", True))


def _build_neural_hybrid_input(
    participant_id: str,
    cfg: dict,
    model_name: str,
    bundle: dict,
    tensor: np.ndarray,
    *,
    channel_mode: str | None,
) -> tuple[np.ndarray, dict]:
    """Append XGB-style tabular features to flattened EEG tensors."""
    feature_df = build_for_participant(participant_id, cfg)
    feature_df = _apply_channel_selection(
        feature_df,
        cfg,
        model_name,
        channel_mode=channel_mode,
    )
    feature_df = feature_df.dropna(axis=1, how="any")

    keys = pd.DataFrame({
        "condition": np.asarray(bundle["labels"], dtype=object),
        "epoch": np.asarray(bundle["selection"], dtype=int),
        "_tensor_row": np.arange(tensor.shape[0]),
    })
    merged = keys.merge(
        feature_df,
        on=["condition", "epoch"],
        how="left",
        validate="one_to_one",
    ).sort_values("_tensor_row")
    missing_rows = (
        merged["participant_id"].isna()
        if "participant_id" in merged
        else pd.Series(False, index=merged.index)
    )
    if missing_rows.any():
        missing = int(missing_rows.sum())
        raise RuntimeError(
            f"[{participant_id}/{model_name}] {missing} tensor epochs did not match "
            "the XGB-style feature table. Rebuild tensor and feature caches with "
            "the same config/window/bin width."
        )

    tabular = merged.drop(
        columns=["_tensor_row", "condition", "participant_id", "block_id"],
        errors="ignore",
    )
    tabular = tabular.apply(pd.to_numeric, errors="coerce").dropna(axis=1, how="any")
    source_cols = [c for c in tabular.columns if _is_source_feature_column(c)]
    stat_cols = [c for c in tabular.columns if _is_channel_stat_feature_column(c)]

    ncfg = cfg.get("modeling", {}).get(model_name, {}).get("tabular_features", {})
    if bool(ncfg.get("require_source", False)) and not source_cols:
        raise RuntimeError(
            f"[{participant_id}/{model_name}] no source-localization columns were found "
            "in the tabular feature matrix. Run the source and feature stages with the "
            "same config first, for example: python run.py --speed-tier "
            f"{model_name} --participants {participant_id} --stages src features --force"
        )

    flat_tensor = tensor.reshape(tensor.shape[0], -1)
    X = np.concatenate([flat_tensor, tabular.to_numpy(dtype=float)], axis=1)
    return X, {
        "n_tabular_features": int(tabular.shape[1]),
        "n_source_features": int(len(source_cols)),
        "n_channel_stat_features": int(len(stat_cols)),
    }


def _is_source_feature_column(column: str) -> bool:
    return bool(re.search(r"-(?:lh|rh)_bin_-?\d+$", column))


def _is_channel_stat_feature_column(column: str) -> bool:
    return bool(
        re.match(
            r"^amp_w[^_]+_.+?_(?:std|min|max|median)_bin_-?\d+$",
            column,
        )
    )


def _outer_splits_tensor(
    X: np.ndarray,
    y: pd.Series,
    groups: pd.Series | None,
    cfg: dict,
    *,
    cv_mode: str | None = None,
) -> list[dict]:
    """Outer splits for tensor input.

    ``sklearn`` splitters work on any input where ``len(X)`` is the sample
    count, so a 3-D ``np.ndarray`` is fine. The chronological sanity check is
    not meaningful without a tabular ``epoch`` column, so it is disabled
    here regardless of ``modeling.cv.chronological_check``.
    """
    cv = _cv_config(cfg)
    mode = cv_mode or cv.get("mode", "repeated_stratified")
    n_splits = _bounded_splits(y, int(cv.get("n_splits", 5)))
    random_state = int(cfg["modeling"].get("random_state", 1))
    rows: list[dict] = []

    if mode == "repeated_stratified":
        splitter = RepeatedStratifiedKFold(
            n_splits=n_splits,
            n_repeats=int(cv.get("n_repeats", 20)),
            random_state=random_state,
        )
        for i, (train_idx, test_idx) in enumerate(splitter.split(np.zeros(len(y)), y)):
            rows.append({
                "cv_mode": "repeated_stratified",
                "repeat": i // n_splits,
                "fold":   i % n_splits,
                "train_idx": train_idx,
                "test_idx":  test_idx,
            })
        return rows

    if mode == "grouped":
        if groups is None or groups.nunique(dropna=False) < n_splits:
            log.warning("Grouped CV requested without enough block_id groups; falling back to repeated stratified.")
            return _outer_splits_tensor(X, y, groups, cfg, cv_mode="repeated_stratified")
        splitter = StratifiedGroupKFold(n_splits=n_splits, shuffle=True, random_state=random_state)
        for fold, (train_idx, test_idx) in enumerate(
            splitter.split(np.zeros(len(y)), y, groups)
        ):
            rows.append({
                "cv_mode": "grouped",
                "repeat":  0,
                "fold":    fold,
                "train_idx": train_idx,
                "test_idx":  test_idx,
            })
        return rows

    if mode == "chronological":
        # No tabular ordering key on tensor data; fall back to the natural
        # epoch order with a no-shuffle KFold.
        splitter = KFold(n_splits=n_splits, shuffle=False)
        for fold, (train_idx, test_idx) in enumerate(splitter.split(np.arange(len(y)))):
            rows.append({
                "cv_mode": "chronological",
                "repeat":  0,
                "fold":    fold,
                "train_idx": train_idx,
                "test_idx":  test_idx,
            })
        return rows

    raise ValueError("cv_mode must be one of: repeated_stratified, grouped, chronological")


def _fit_score_split(
    participant_id: str,
    cfg: dict,
    model_name: str,
    factory: dict,
    X: pd.DataFrame,
    y: pd.Series,
    train_idx: np.ndarray,
    test_idx: np.ndarray,
    *,
    groups: np.ndarray | None = None,
) -> dict:
    """Fit feature selection and hyperparameter search inside one outer fold.

    ``groups`` (optional) labels each row of ``X`` with a grouping key (e.g. the
    subject id in pooled training). When provided, the inner hyperparameter
    search uses subject-grouped CV so tuning does not leak across subjects.
    Left as ``None`` for the per-participant path, which is unchanged.
    """
    mcfg = cfg["modeling"]
    X_train, X_test = X.iloc[train_idx].copy(), X.iloc[test_idx].copy()
    y_train, y_test = y.iloc[train_idx].copy(), y.iloc[test_idx].copy()
    g_train = np.asarray(groups)[train_idx] if groups is not None else None

    # 0. Optional cheap univariate pre-filter (ANOVA top-K) BEFORE the dense
    #    correlation drop. Fit on the TRAIN fold only (leakage-safe, like every
    #    other funnel stage). On wide rich frames (~8k-32k cols) the correlation
    #    drop builds a p x p matrix whose cost is quadratic in p; cutting p with
    #    a linear-time ANOVA pre-filter first makes the rich-feature path
    #    tractable (XGB_MODEL_SUMMARY §4). Default null = legacy/off (no pre-cut).
    pre_k = mcfg.get("pre_kbest", None)
    if pre_k not in (None, "none", "None", 0) and int(pre_k) < X_train.shape[1]:
        keep = fs.select_kbest(X_train, y_train, k=int(pre_k))
        X_train, X_test = X_train[keep], X_test[keep]

    # 1. Correlation drop (cheap)
    keep = fs.correlation_drop(X_train, threshold=float(mcfg.get("correlation_threshold", 0.9)))
    X_train, X_test = X_train[keep], X_test[keep]

    # 2. Univariate top-K
    keep = fs.select_kbest(X_train, y_train, k=int(mcfg.get("k_best", 500)))
    X_train, X_test = X_train[keep], X_test[keep]

    # 3. In-fold selection (fit on train only, applied to test). Default is
    #    stability selection; "rfecv" keeps the legacy iterated-RFECV path.
    fscfg = mcfg.get("feature_selection", {}) or {}
    method = str(fscfg.get("method", "stability")).lower()

    # 3a. Optional leakage-safe functional PCA over amplitude time courses,
    #     fit on the training fold before selection.
    fpca_cfg = fscfg.get("fpca", {}) or {}
    if bool(fpca_cfg.get("enabled", False)):
        from ..features.basis import FunctionalPCABasis
        fpca = FunctionalPCABasis(
            n_components=int(fpca_cfg.get("n_components", 4)),
            random_state=int(mcfg.get("random_state", 1)),
        )
        fpca.fit(X_train)
        X_train, X_test = fpca.transform(X_train), fpca.transform(X_test)
        log.info("[%s/%s] fPCA -> %d feature(s)",
                 participant_id, model_name, X_train.shape[1])

    if method == "stability":
        scfg = fscfg.get("stability", {}) or {}
        mf = scfg.get("max_features", 150)
        keep, _prob = fs.stability_select(
            X_train, y_train,
            n_subsamples=int(scfg.get("n_subsamples", 50)),
            sample_fraction=float(scfg.get("sample_fraction", 0.5)),
            l1_ratio=float(scfg.get("l1_ratio", 0.5)),
            n_lambda=int(scfg.get("n_lambda", 15)),
            threshold=float(scfg.get("threshold", 0.6)),
            max_features=(None if mf in (None, "none", "None") else int(mf)),
            min_features=int(scfg.get("min_features", 10)),
            random_state=int(mcfg.get("random_state", 1)),
        )
        if keep:
            X_train, X_test = X_train[keep], X_test[keep]
    elif method == "rfecv":
        rfecv_cfg = mcfg.get("rfecv", {})
        if factory["rfecv_base"] is not None:
            scale_pos_weight = _scale_pos_weight(y_train)
            rfecv_base = factory["rfecv_base"](cfg, scale_pos_weight=scale_pos_weight)
            keep, _imp = fs.rfecv_iterated(
                X_train, y_train, rfecv_base,
                n_iterations=int(rfecv_cfg.get("n_iterations", 5)),
                step=float(rfecv_cfg.get("step", 0.05)),
                min_features_to_select=int(rfecv_cfg.get("min_features_to_select", 200)),
                scoring=rfecv_cfg.get("scoring", "roc_auc"),
                n_jobs=1,
            )
            X_train, X_test = X_train[keep], X_test[keep]
        else:
            log.info("[%s/%s] rfecv selected but model has no rfecv_base; skipping.",
                     participant_id, model_name)
    elif method == "none":
        log.info("[%s/%s] feature_selection.method=none; skipping selection.",
                 participant_id, model_name)
    else:
        raise ValueError(
            f"feature_selection.method must be 'stability', 'rfecv', or 'none'; got {method!r}"
        )

    scale_pos_weight = _scale_pos_weight(y_train)
    search = _fit_search(
        factory, cfg, model_name, X_train, y_train,
        scale_pos_weight=scale_pos_weight, groups=g_train,
    )
    log.info("[%s/%s] outer fold best CV=%.3f, params=%s",
             participant_id, model_name, search.best_score_, search.best_params_)

    best = search.best_estimator_
    best_classifier = unwrap_classifier(best)

    # 4. (Optional) gain prune + retrain
    gp = mcfg.get("gain_prune", {}) or {}
    gain_prune_enabled = bool(gp.get("enabled", True))
    gain_prune_refit = bool(gp.get("refit", True))
    if (
        gain_prune_enabled
        and gain_prune_refit
        and factory["supports_gain"]
        and hasattr(best_classifier, "feature_importances_")
    ):
        keep_gain = fs.gain_prune(
            best_classifier.feature_importances_, X_train.columns.tolist(),
            mode=gp.get("mode", "zero"),
            percentile=float(gp.get("percentile", 10)),
            absolute=float(gp.get("absolute", 0.001)),
        )
        if keep_gain and len(keep_gain) < X_train.shape[1]:
            X_train, X_test = X_train[keep_gain], X_test[keep_gain]
            search = _fit_search(
                factory, cfg, model_name, X_train, y_train,
                scale_pos_weight=scale_pos_weight, groups=g_train,
            )
            best = search.best_estimator_
            best_classifier = unwrap_classifier(best)
    elif not (gain_prune_enabled and gain_prune_refit):
        log.info("[%s/%s] gain-prune refit disabled by config; skipping.",
                 participant_id, model_name)

    # 5. (Optional) SHAP prune + retrain
    shap_cfg = mcfg.get("shap_prune", {}) or {}
    shap_quantile = float(
        shap_cfg.get("quantile", mcfg.get("shap_prune_quantile", 0.2))
    )
    shap_enabled = bool(shap_cfg.get("enabled", shap_quantile > 0))
    shap_refit = bool(shap_cfg.get("refit", True))
    if (
        shap_enabled
        and shap_refit
        and shap_quantile > 0
        and factory["supports_shap"]
    ):
        keep_shap = fs.shap_prune(
            best_classifier,
            X_train,
            quantile=shap_quantile,
        )
        if keep_shap and len(keep_shap) < X_train.shape[1]:
            X_train, X_test = X_train[keep_shap], X_test[keep_shap]
            search = _fit_search(
                factory, cfg, model_name, X_train, y_train,
                scale_pos_weight=scale_pos_weight, groups=g_train,
            )
            best = search.best_estimator_
    elif not (shap_enabled and shap_refit and shap_quantile > 0):
        log.info("[%s/%s] SHAP prune disabled by config; skipping.",
                 participant_id, model_name)

    proba = (
        best.predict_proba(X_test)[:, 1]
        if hasattr(best, "predict_proba")
        else best.decision_function(X_test)
    )
    pred = (proba >= 0.5).astype(int)

    metrics = participant_metrics(np.asarray(y_test), pred, np.asarray(proba))
    metrics["participant_id"] = participant_id
    metrics["model"] = model_name
    metrics["n_features_final"] = int(X_train.shape[1])
    metrics["best_params"] = str(search.best_params_)
    metrics["inner_best_score"] = float(search.best_score_)
    metrics["search_method"] = _search_method(cfg, model_name)
    return metrics


def _fit_search(
    factory: dict,
    cfg: dict,
    model_name: str,
    X_train: pd.DataFrame,
    y_train: pd.Series,
    *,
    scale_pos_weight: float,
    groups: np.ndarray | None = None,
) -> GridSearchCV | RandomizedSearchCV | HalvingRandomSearchCV:
    mcfg = cfg["modeling"]
    estimator, param_grid = _make_search_estimator(
        factory, cfg, model_name,
        scale_pos_weight=scale_pos_weight,
        n_features=X_train.shape[1:] if getattr(X_train, "ndim", 2) == 3 else X_train.shape[1],
    )
    n_inner = int(_cv_config(cfg).get("inner_splits", mcfg.get("inner_cv_splits", 2)))
    fit_params: dict = {}
    if groups is not None:
        # Pooled modes: keep all epochs from one subject together inside the
        # inner hyperparameter-search CV so tuning never peeks across the
        # train/test subject boundary (otherwise the inner score is optimistic).
        groups = np.asarray(groups)
        n_groups = int(pd.unique(groups).size)
        inner_cv = StratifiedGroupKFold(
            n_splits=max(2, min(n_inner, n_groups)),
            shuffle=True,
            random_state=int(mcfg.get("random_state", 1)),
        )
        fit_params["groups"] = groups
    else:
        inner_cv = StratifiedKFold(
            n_splits=_bounded_splits(y_train, n_inner),
            shuffle=True,
            random_state=int(mcfg.get("random_state", 1)),
        )
    search = _make_search_cv(
        estimator=estimator,
        param_grid=param_grid,
        cfg=cfg,
        model_name=model_name,
        cv=inner_cv,
    )
    search.fit(X_train, y_train, **fit_params)
    return search


def _make_search_cv(
    *,
    estimator,
    param_grid: dict,
    cfg: dict,
    model_name: str,
    cv: StratifiedKFold,
) -> GridSearchCV | RandomizedSearchCV | HalvingRandomSearchCV:
    mcfg = cfg["modeling"]
    method = _search_method(cfg, model_name)
    common = {
        "estimator": estimator,
        "scoring": mcfg.get("scoring", "accuracy"),
        "n_jobs": _search_n_jobs(cfg, model_name),
        "cv": cv,
        "refit": True,
        # modeling.search.verbose -- opt-in per-candidate progress from sklearn.
        # 0=silent (default), 1=one line per candidate completion, 3=one line
        # per candidate × CV-fold pair. Useful when staring at a slow Riemannian
        # or XGB fit and wanting to see something move.
        "verbose": int(mcfg.get("search", {}).get("verbose", 0)),
    }
    if method == "grid":
        return GridSearchCV(param_grid=param_grid, **common)
    if method == "random":
        scfg = mcfg.get("search", {})
        # Discrete grids are sampled WITHOUT replacement, so n_iter must not
        # exceed the grid size or RandomizedSearchCV raises. Cap it like the
        # halving branch does. Applies uniformly to every model family.
        n_iter = min(int(scfg.get("n_iter", 100)), _param_grid_size(param_grid))
        return RandomizedSearchCV(
            param_distributions=param_grid,
            n_iter=max(1, n_iter),
            random_state=int(mcfg.get("random_state", 1)),
            **common,
        )
    if method == "halving_random":
        scfg = mcfg.get("search", {})
        hcfg = scfg.get("halving", {})
        resource = hcfg.get("resource", "n_estimators")
        # Defensive: HalvingRandomSearchCV raises at fit time with
        # "Cannot use resource=<name> which is not supported by estimator <X>"
        # when the estimator doesn't expose the configured resource parameter.
        # SVC, LogisticRegression, KerasClassifier, etc. have no n_estimators.
        # Fall back to exhaustive grid search rather than crashing the run.
        if not _estimator_supports_resource(estimator, resource):
            log.warning(
                "search.method='halving_random' requested but estimator %s "
                "does not expose resource=%r; falling back to GridSearchCV.",
                type(estimator).__name__, resource,
            )
            return GridSearchCV(param_grid=param_grid, **common)
        xgb_cfg = mcfg.get("xgb", {})
        max_resources = int(hcfg.get("max_resources", xgb_cfg.get("n_estimators", 1000)))
        min_resources = min(int(hcfg.get("min_resources", 100)), max_resources)
        n_candidates = min(
            int(scfg.get("n_iter", 100)),
            _param_grid_size(param_grid),
        )
        return HalvingRandomSearchCV(
            param_distributions=param_grid,
            n_candidates=max(1, n_candidates),
            resource=resource,
            min_resources=min_resources,
            max_resources=max_resources,
            factor=int(hcfg.get("factor", 3)),
            aggressive_elimination=bool(hcfg.get("aggressive_elimination", False)),
            random_state=int(mcfg.get("random_state", 1)),
            **common,
        )
    raise ValueError(
        "modeling.search.method must be one of: auto, grid, random, halving_random"
    )


def _estimator_supports_resource(estimator, resource: str) -> bool:
    """Return True if the (top-level) estimator accepts ``resource`` as a param.

    HalvingRandomSearchCV uses ``resource`` (typically ``n_estimators``) as
    its successive-halving budget. The parameter must be visible at the
    top level of the estimator's ``get_params()``; nested pipeline params
    would need to be addressed as e.g. ``classifier__n_estimators`` and
    that's not how the tier configs are written.
    """
    try:
        params = estimator.get_params(deep=False)
        return resource in params
    except Exception:                                          # noqa: BLE001
        return False


def _search_method(cfg: dict, model_name: str) -> str:
    method = cfg.get("modeling", {}).get("search", {}).get("method", "auto")
    if method == "auto":
        return "halving_random" if model_name == "xgb" else "grid"
    return method


def _search_n_jobs(cfg: dict, model_name: str) -> int:
    value = cfg.get("modeling", {}).get("search", {}).get("n_jobs")
    if value is None and model_name == "xgb":
        return 1
    return resolve_n_jobs(cfg, value, default=-8)


def _param_grid_size(param_grid: dict) -> int:
    return max(1, len(ParameterGrid(param_grid)))


def _outer_splits(
    X: pd.DataFrame,
    y: pd.Series,
    groups: pd.Series | None,
    cfg: dict,
    *,
    cv_mode: str | None = None,
) -> list[dict]:
    cv = _cv_config(cfg)
    mode = cv_mode or cv.get("mode", "repeated_stratified")
    primary = _primary_outer_splits(X, y, groups, cfg, mode)
    if mode != "chronological" and bool(cv.get("chronological_check", True)):
        primary.extend(_chronological_splits(X, y, cfg))
    return primary


def _primary_outer_splits(
    X: pd.DataFrame,
    y: pd.Series,
    groups: pd.Series | None,
    cfg: dict,
    mode: str,
) -> list[dict]:
    cv = _cv_config(cfg)
    n_splits = _bounded_splits(y, int(cv.get("n_splits", 5)))
    random_state = int(cfg["modeling"].get("random_state", 1))
    rows: list[dict] = []

    if mode == "repeated_stratified":
        splitter = RepeatedStratifiedKFold(
            n_splits=n_splits,
            n_repeats=int(cv.get("n_repeats", 20)),
            random_state=random_state,
        )
        for i, (train_idx, test_idx) in enumerate(splitter.split(X, y)):
            rows.append({
                "cv_mode": "repeated_stratified",
                "repeat": i // n_splits,
                "fold": i % n_splits,
                "train_idx": train_idx,
                "test_idx": test_idx,
            })
        return rows

    if mode == "grouped":
        if groups is None or groups.nunique(dropna=False) < n_splits:
            log.warning("Grouped CV requested without enough block_id groups; using repeated stratified CV.")
            return _primary_outer_splits(X, y, groups, cfg, "repeated_stratified")
        splitter = StratifiedGroupKFold(n_splits=n_splits, shuffle=True, random_state=random_state)
        for fold, (train_idx, test_idx) in enumerate(splitter.split(X, y, groups)):
            rows.append({
                "cv_mode": "grouped",
                "repeat": 0,
                "fold": fold,
                "train_idx": train_idx,
                "test_idx": test_idx,
            })
        return rows

    if mode == "chronological":
        return _chronological_splits(X, y, cfg)

    raise ValueError("cv_mode must be one of: repeated_stratified, grouped, chronological")


def _chronological_splits(X: pd.DataFrame, y: pd.Series, cfg: dict) -> list[dict]:
    cv = _cv_config(cfg)
    X_ordered, y_ordered = _sort_for_chronological(X, y)
    n_splits = _bounded_splits(y_ordered, int(cv.get("n_splits", 5)))
    splitter = KFold(n_splits=n_splits, shuffle=False)
    rows = []
    for fold, (train_pos, test_pos) in enumerate(splitter.split(X_ordered)):
        y_train = y_ordered.iloc[train_pos]
        y_test = y_ordered.iloc[test_pos]
        if y_train.nunique() < 2 or y_test.nunique() < 2:
            log.warning("Skipping chronological fold %d because it contains one class.", fold)
            continue
        rows.append({
            "cv_mode": "chronological",
            "repeat": 0,
            "fold": fold,
            "train_idx": X_ordered.index.to_numpy()[train_pos],
            "test_idx": X_ordered.index.to_numpy()[test_pos],
        })
    return rows


def _sort_for_chronological(X: pd.DataFrame, y: pd.Series) -> tuple[pd.DataFrame, pd.Series]:
    order = pd.DataFrame({"_idx": np.arange(len(X)), "_y": y.to_numpy()}, index=X.index)
    if "epoch" in X.columns:
        order["epoch"] = X["epoch"].to_numpy()
    else:
        order["epoch"] = np.arange(len(X))
    ordered_index = order.sort_values(["epoch", "_y", "_idx"]).index
    return X.loc[ordered_index], y.loc[ordered_index]


def _bounded_splits(y: pd.Series, requested: int) -> int:
    min_class = int(y.value_counts().min())
    return max(2, min(int(requested), min_class))


def _cv_config(cfg: dict) -> dict:
    return cfg.get("modeling", {}).get("cv", {})


def _effective_channel_mode(
    cfg: dict,
    model_name: str,
    channel_mode: str | None = None,
) -> str:
    # Tensor-input models (riemannian + the hybrid neural CNNs) always train on
    # every channel; ROI selection only applies to the tabular feature path.
    if MODEL_FACTORIES.get(model_name, {}).get("data_representation") == "tensor":
        return "full"
    return channel_mode or cfg.get("channel_selection", {}).get("mode", "full")


def _apply_channel_selection(
    df: pd.DataFrame,
    cfg: dict,
    model_name: str,
    *,
    channel_mode: str | None = None,
) -> pd.DataFrame:
    mode = _effective_channel_mode(cfg, model_name, channel_mode)
    if mode == "full":
        log.info("Channel mode: full (%d columns)", df.shape[1])
        return df
    if mode != "roi":
        raise ValueError("channel mode must be one of: full, roi")

    roi = set(cfg.get("channel_selection", {}).get("roi", {}).get("channels", []))
    if not roi:
        raise ValueError("channel_selection.roi.channels must not be empty")

    keep = [
        col for col in df.columns
        if _keep_column_for_roi(col, roi)
    ]
    log.info(
        "Channel mode: roi (%d channels), columns %d → %d",
        len(roi), df.shape[1], len(keep),
    )
    return df[keep]


def _keep_column_for_roi(column: str, roi: set[str]) -> bool:
    if column in {"epoch", "condition", "participant_id"}:
        return True
    channel = _feature_channel(column)
    return channel is None or channel in roi


def _feature_channel(column: str) -> str | None:
    """Return electrode channel for amplitude/slope/PSD columns, else None."""
    m = re.match(
        r"^amp_w[^_]+_(?P<ch>.+?)_(?:mean|std|min|max|median)_bin_-?\d+$",
        column,
    )
    if m:
        return m.group("ch")
    m = re.match(r"^cnv_benchmark_(?P<ch>.+?)_bin_-?\d+$", column)
    if m:
        return m.group("ch")
    # Shape-decomposition / fPCA coefficients: poly_{ch}_{k}, bspl_{ch}_{k}, fpca_{ch}_{k}
    m = re.match(r"^(?:poly|bspl|fpca)_(?P<ch>.+?)_\d+$", column)
    if m:
        return m.group("ch")
    if column.startswith("slope_"):
        m = re.match(r"^slope_(?P<ch>.+?)_bin_\d+$", column)
        return m.group("ch") if m else None
    m = re.match(r"^(?P<ch>.+?)(?:_[A-Za-z]+)?_bin_\d+$", column)
    if not m:
        return None
    ch = m.group("ch")
    # Source-space features also end in _bin_N but are not electrode channels.
    if "-" in ch or ch.endswith(("-lh", "-rh")):
        return None
    return ch


def _scale_pos_weight(y: pd.Series) -> float:
    pos = int((y == 1).sum())
    neg = int((y == 0).sum())
    return (neg / pos) if pos > 0 else 1.0


def _make_model(factory, cfg, model_name, *, scale_pos_weight, n_features):
    if model_name == "lstm":
        return factory["make"](cfg, n_features=n_features)
    if model_name in NEURAL_HYBRID_MODELS:
        return factory["make"](cfg, input_shape=n_features)
    try:
        return factory["make"](cfg, scale_pos_weight=scale_pos_weight)
    except TypeError:
        return factory["make"](cfg)


def _make_search_estimator(factory, cfg, model_name, *, scale_pos_weight, n_features):
    model_shape = n_features
    if model_name not in NEURAL_HYBRID_MODELS and not isinstance(n_features, int):
        model_shape = int(n_features[0]) if n_features else 0
    base = _make_model(
        factory, cfg, model_name,
        scale_pos_weight=scale_pos_weight,
        n_features=model_shape,
    )
    estimator = maybe_wrap_estimator(base, model_name, cfg, n_features=model_shape)
    param_grid = maybe_prefix_param_grid(factory["param_grid"](cfg), estimator)
    return estimator, param_grid


# ---------------------------------------------------------------------------
def _parallel_participants(cfg: dict) -> int:
    """Resolve the number of participants to train concurrently.

    Defaults to 1 (sequential) for backwards compatibility. Negative values
    follow the project convention of "reserve this many logical CPUs".
    """
    raw = (
        cfg.get("modeling", {})
        .get("parallel", {})
        .get("participants")
    )
    if raw is None:
        return 1
    raw = int(raw)
    if raw == 0:
        return 1
    if raw < 0:
        cpus = os.cpu_count() or 1
        return max(1, cpus - abs(raw))
    return raw


def _force_single_threaded_inner(cfg: dict) -> dict:
    """Return a copy of cfg with inner XGB/search workers pinned to one thread.

    Used inside joblib workers so each participant runs single-threaded and
    we don't oversubscribe (joblib workers × XGB threads × sklearn threads).
    """
    out = copy.deepcopy(cfg)
    modeling = out.setdefault("modeling", {})
    modeling.setdefault("xgb", {})["n_jobs"] = 1
    modeling.setdefault("search", {})["n_jobs"] = 1
    # Cap the project-wide n_jobs so anything reading resources.n_jobs also
    # falls back to one thread inside the worker.
    out.setdefault("resources", {})["n_jobs"] = 1
    out["_parallel_worker"] = True
    return out


def _train_one_with_checkpoint(
    pid: str,
    cfg: dict,
    model: str,
    rdir,
    *,
    channel_mode: str | None,
    cv_mode: str | None,
) -> tuple[str, list[dict] | None, Exception | None]:
    """Train (or load) one participant. Returns (pid, rows, exc)."""
    try:
        participant_path = _participant_metrics_path(rdir, pid)
        if participant_path.exists():
            log.info("[%s] checkpoint exists; loading %s", pid, participant_path)
            participant_df = pd.read_csv(participant_path)
            return pid, participant_df.to_dict(orient="records"), None

        participant_rows = train_one_participant(
            pid, cfg, model, channel_mode=channel_mode, cv_mode=cv_mode,
        )
        participant_df = pd.DataFrame(participant_rows)
        write_csv(participant_df, participant_path)
        log.info("[%s] wrote training checkpoint %s", pid, participant_path)
        return pid, participant_rows, None
    except Exception as exc:                              # noqa: BLE001
        return pid, None, exc


def _run_pooled(
    cfg: dict,
    model: str,
    rdir,
    mode: str,
    *,
    channel_mode: str | None = None,
) -> pd.DataFrame:
    """Cross-subject pooled training path (modeling.pooling.mode = partial|full).

    Builds the shared pooled feature frame once and runs the requested pooling
    workflow from :mod:`models.pooling` (imported lazily to avoid the
    train<->pooling import cycle). Writes the same metrics.csv / rollup.csv
    artifacts as the per-participant path so downstream tooling is unchanged;
    pooled rows carry cv_mode="pooled_<mode>" and a held_out_participant column.
    """
    from . import pooling  # lazy: pooling imports train at module load

    if MODEL_FACTORIES[model].get("data_representation") != "tabular":
        raise ValueError(
            f"modeling.pooling.mode={mode!r} supports tabular models only "
            "(xgb / svm / logistic); tensor models have no shared feature frame."
        )
    participants = list(cfg["participants"])
    log.info(
        "Cross-subject pooling: mode=%s model=%s on %d subjects",
        mode, model, len(participants),
    )
    pooled = pooling.build_pooled_frame(cfg, participants, model, channel_mode=channel_mode)
    rows = pooling.train_pooled(
        cfg, model, mode=mode, channel_mode=channel_mode, pooled_frame=pooled,
    )
    df = pd.DataFrame(rows)
    write_csv(df, rdir / "metrics.csv")
    rollup = cv_rollup(df)
    log.info("Pooled cohort rollup: %s", rollup.to_dict(orient="records"))
    rollup.to_csv(rdir / "rollup.csv", index=False)
    return df


def run(
    cfg: dict,
    *,
    model: str = "xgb",
    run_id: str | None = None,
    channel_mode: str | None = None,
    cv_mode: str | None = None,
) -> pd.DataFrame:
    """Stage entry point — train per participant, write report, return DataFrame."""
    if model not in MODEL_FACTORIES:
        raise ValueError(f"Unknown model: {model!r} (choose from {list(MODEL_FACTORIES)})")

    effective_channel_mode = _effective_channel_mode(cfg, model, channel_mode)
    window = cfg.get("_prediction_window", "late_cnv")
    run_id = run_id or make_run_id(prefix=f"{model}_{effective_channel_mode}_{window}")
    rdir = ensure_dir(run_dir(cfg, run_id))
    if cfg.get("logging", {}).get("stamp_runs", True):
        stamp_run(rdir, cfg, model=model)

    # Cross-subject pooling (modeling.pooling.mode). Default "per_participant"
    # is the legacy within-subject path below; "partial"/"full" route through
    # models.pooling, which shares each subject's training data with the rest of
    # the cohort to escape the ~80-epoch p>>n budget (the single biggest lever on
    # the inner-vs-outer gap; OVERFITTING_GAP_SOLUTIONS.md §6). Tabular models only.
    pool_mode = str(
        (cfg.get("modeling", {}).get("pooling", {}) or {}).get("mode", "per_participant")
    ).lower()
    if pool_mode != "per_participant":
        # Pooling shares a tabular feature frame across subjects; it is undefined
        # for tensor models and for cohorts with <2 subjects. Fall back to the
        # per-participant path in those cases so a global pooling default stays
        # safe for neural runs and single-subject smoke configs.
        is_tabular = MODEL_FACTORIES[model].get("data_representation") == "tabular"
        n_subjects = len(cfg.get("participants", []))
        if not is_tabular:
            log.info("[pooling] mode=%s requested but %s is a tensor model; "
                     "using per-participant training.", pool_mode, model)
        elif n_subjects < 2:
            log.info("[pooling] mode=%s requested but only %d subject(s); "
                     "using per-participant training.", pool_mode, n_subjects)
        else:
            return _run_pooled(cfg, model, rdir, pool_mode, channel_mode=channel_mode)

    n_workers = _parallel_participants(cfg)
    participants = list(cfg["participants"])
    rows: list[dict] = []
    cohort_eta = CohortETA(total_participants=len(participants), n_workers=n_workers)

    if n_workers <= 1:
        for pid in participants:
            _pid, prows, exc = _train_one_with_checkpoint(
                pid, cfg, model, rdir,
                channel_mode=channel_mode, cv_mode=cv_mode,
            )
            cohort_eta.record_completion()
            if exc is not None:
                log.exception("[%s] failed: %s", pid, exc)
            else:
                rows.extend(prows or [])
            log.info("Cohort progress: %s", cohort_eta.format())
    else:
        from joblib import Parallel, delayed

        worker_cfg = _force_single_threaded_inner(cfg)
        log.info(
            "Training %d participants with %d parallel workers (inner threads pinned to 1)",
            len(participants), n_workers,
        )
        delayed_jobs = (
            delayed(_train_one_with_checkpoint)(
                pid, worker_cfg, model, rdir,
                channel_mode=channel_mode, cv_mode=cv_mode,
            )
            for pid in participants
        )
        # Prefer joblib's streaming API (>=1.3) so we can update the cohort
        # ETA as each worker returns rather than waiting for the entire pool
        # to drain. Fall back to a synchronous list on older joblib.
        try:
            results_iter = Parallel(
                n_jobs=n_workers, backend="loky", verbose=10,
                return_as="generator_unordered",
            )(delayed_jobs)
        except TypeError:
            try:
                results_iter = Parallel(
                    n_jobs=n_workers, backend="loky", verbose=10,
                    return_as="generator",
                )(delayed_jobs)
            except TypeError:
                results_iter = Parallel(
                    n_jobs=n_workers, backend="loky", verbose=10,
                )(delayed_jobs)
        for pid, prows, exc in results_iter:
            cohort_eta.record_completion()
            if exc is not None:
                log.exception("[%s] failed: %s", pid, exc)
            else:
                rows.extend(prows or [])
            log.info("Cohort progress: %s", cohort_eta.format())

    df = pd.DataFrame(rows)
    write_csv(df, rdir / "metrics.csv")
    rollup = cv_rollup(df)
    log.info("Cohort rollup: %s", rollup.to_dict(orient="records"))

    rollup.to_csv(rdir / "rollup.csv", index=False)
    return df
