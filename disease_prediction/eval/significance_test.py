"""
KG-enhanced model vs binary baseline significance tests.

Label-level analysis tests whether the paired metric differences across labels
within a prevalence group are systematically shifted in favor of the
KG-enhanced model.

Each label contributes one paired difference:
    delta = KG-enhanced - baseline

Statistical inference:
- one-sided Wilcoxon signed-rank test for a positive location shift in the
  paired differences;
- Benjamini-Hochberg FDR correction;
- bootstrap confidence interval for the mean paired difference;
- sign-flip permutation sensitivity analysis using mean(delta).

frac_labels_favor_B is the fraction of ALL tested labels with delta > 0.

Usage:

    python -m disease_prediction.eval.significance_test \
        --model_a_dir disease_prediction/save/nn5_binary/test_bin_2 \
        --model_b_dir disease_prediction/save/nn5_gpt-5-minimal_12r_TransE_ene/test_bin_2 \
        --tag 0906
"""

import argparse

from disease_prediction import config
import hashlib
import json
import os

import numpy as np
import pandas as pd
import scipy.stats

from disease_prediction.evaluation_manifest import validate_run_pairing


METRIC_COLS = {
    "AUROC": "auroc",
    "AUPRC": "auprc",
    "F1": "f1",
}

DEFAULT_METRICS = ["AUROC", "AUPRC", "F1"]

REQUIRED_METRIC_COLUMNS = {
    "train_col_sum",
    "val_col_sum",
    "test_col_sum",
    "auroc",
    "auprc",
    "f1",
}


# ============================================================
# Utilities
# ============================================================

def get_bins(bin_choice):
    if bin_choice == 1:
        return [(0, 10), (10, 100), (100, 1000), (1000, np.inf)]
    if bin_choice == 2:
        return [(0, 10), (10, 100), (100, 500), (500, np.inf)]
    raise ValueError(f"Invalid bin_choice: {bin_choice}")


def bin_name(low, high):
    return f"{low}+" if high == np.inf else f"{low}-{high}"


def bh_fdr(pvals):
    """Benjamini-Hochberg q-values; NaN values remain NaN."""
    p = np.asarray(pvals, dtype=float)
    q = np.full(p.shape, np.nan)

    ok = np.isfinite(p)
    if not ok.any():
        return q

    try:
        q[ok] = scipy.stats.false_discovery_control(p[ok], method="bh")
    except AttributeError:  # scipy < 1.11
        vals = p[ok]
        n = vals.size
        order = np.argsort(vals)
        ranked = vals[order] * n / np.arange(1, n + 1)
        ranked = np.minimum.accumulate(ranked[::-1])[::-1]

        out = np.empty(n)
        out[order] = np.clip(ranked, 0, 1)
        q[ok] = out

    return q


def model_tag(model_dir):
    """test output directory -> model directory name."""
    return os.path.basename(os.path.dirname(os.path.normpath(model_dir)))


# ============================================================
# Shared sampling-cache validation
# ============================================================

def labels_sha256(labels, chunk_rows=4096):
    """
    Compute the same SHA256 fingerprint used by the updated test.py.

    The fingerprint contains:
    - array shape
    - dtype
    - complete matrix content
    """
    labels = np.asarray(labels)

    hasher = hashlib.sha256()
    hasher.update(str(labels.shape).encode("utf-8"))
    hasher.update(str(labels.dtype).encode("utf-8"))

    for start in range(0, labels.shape[0], chunk_rows):
        chunk = np.ascontiguousarray(labels[start:start + chunk_rows])
        hasher.update(chunk.view(np.uint8))

    return hasher.hexdigest()


def _sample_idx_paths(sample_idx_dir, split, neg_to_pos_ratio):
    base = os.path.join(
        sample_idx_dir,
        f"eval_sample_idx_{split}_r{neg_to_pos_ratio}",
    )
    return base + ".npy", base + "_manifest.json"


def validate_sampling_manifest(label_path, sample_idx_dir, split, neg_to_pos_ratio):
    """
    Verify that the shared sampling cache was generated from the exact
    validation/test label matrix supplied to this significance analysis.
    """
    idx_path, manifest_path = _sample_idx_paths(
        sample_idx_dir, split, neg_to_pos_ratio
    )

    if not os.path.isfile(idx_path):
        raise FileNotFoundError(f"Shared sampling cache not found: {idx_path}")

    if not os.path.isfile(manifest_path):
        raise FileNotFoundError(f"Sampling manifest not found: {manifest_path}")

    labels = np.load(label_path, mmap_mode="r")

    if labels.ndim != 2:
        raise ValueError(
            f"{label_path} must be a 2D label matrix, got shape {labels.shape}"
        )

    with open(manifest_path, "r", encoding="utf-8") as f:
        manifest = json.load(f)

    problems = []

    if int(manifest.get("n_rows", -1)) != int(labels.shape[0]):
        problems.append(f"n_rows {manifest.get('n_rows')} != {labels.shape[0]}")

    if int(manifest.get("n_labels_total", -1)) != int(labels.shape[1]):
        problems.append(
            f"n_labels_total {manifest.get('n_labels_total')} != {labels.shape[1]}"
        )

    if int(manifest.get("neg_to_pos_ratio", -1)) != int(neg_to_pos_ratio):
        problems.append(
            f"neg_to_pos_ratio {manifest.get('neg_to_pos_ratio')} != {neg_to_pos_ratio}"
        )

    cached_hash = manifest.get("labels_sha256")
    current_hash = labels_sha256(labels)

    if cached_hash is None:
        problems.append("manifest does not contain labels_sha256")
    elif cached_hash != current_hash:
        problems.append("labels_sha256 does not match the current label matrix")

    if problems:
        raise RuntimeError(
            f"Shared {split} sampling cache does not match the current data:\n  - "
            + "\n  - ".join(problems)
        )

    print(f"[pairing] {split} sampling manifest verified: {manifest_path}")
    return manifest, labels


def _check_expected_labels(actual_labels, expected_labels, context):
    """Require exactly the same evaluable-label set."""
    actual = set(int(x) for x in actual_labels)
    expected = set(int(x) for x in expected_labels)

    if actual == expected:
        return

    missing = sorted(expected - actual)
    extra = sorted(actual - expected)

    details = []
    if missing:
        details.append(f"missing {len(missing)} labels (examples: {missing[:5]})")
    if extra:
        details.append(f"extra {len(extra)} labels (examples: {extra[:5]})")

    raise ValueError(
        f"{context}: label set does not match the shared test sampling cache: "
        + "; ".join(details)
    )


# ============================================================
# Label-level analysis (primary)
# ============================================================

def load_label_metrics(model_dir, expected_labels=None):
    """Load metrics.csv generated by test.py."""
    path = os.path.join(model_dir, "metrics.csv")

    if not os.path.isfile(path):
        raise FileNotFoundError(f"Metrics file not found: {path}")

    df = pd.read_csv(path, index_col=0)
    df.index = df.index.astype(int)
    df.index.name = "label"

    if df.index.duplicated().any():
        duplicated = df.index[df.index.duplicated()].unique().tolist()
        raise ValueError(
            f"{path} contains duplicated label IDs (examples: {duplicated[:5]})"
        )

    missing = REQUIRED_METRIC_COLUMNS - set(df.columns)
    if missing:
        raise ValueError(f"{path} is missing required columns: {sorted(missing)}")

    df = df.sort_index()

    if expected_labels is not None:
        _check_expected_labels(df.index, expected_labels, path)

    return df


def validate_metric_pairing(df_a, df_b, model_a_dir, model_b_dir):
    """
    Require strict pairing between baseline and KG-enhanced metrics.

    The two runs must contain:
    - exactly the same labels;
    - identical train/validation/test prevalence counts for each label.
    """
    if not df_a.index.equals(df_b.index):
        labels_a = set(df_a.index)
        labels_b = set(df_b.index)

        missing_b = sorted(labels_a - labels_b)
        extra_b = sorted(labels_b - labels_a)

        raise ValueError(
            f"Label sets differ between {model_tag(model_a_dir)} and "
            f"{model_tag(model_b_dir)}. "
            f"Missing in B: {missing_b[:5]}; extra in B: {extra_b[:5]}"
        )

    for col in ["train_col_sum", "val_col_sum", "test_col_sum"]:
        a = df_a[col].to_numpy()
        b = df_b[col].to_numpy()

        mismatch = a != b
        if np.any(mismatch):
            bad_labels = df_a.index[mismatch].tolist()

            raise ValueError(
                f"{col} differs between {model_tag(model_a_dir)} and "
                f"{model_tag(model_b_dir)} for {len(bad_labels)} labels "
                f"(examples: {bad_labels[:5]}). "
                f"The two runs are not strictly paired."
            )


def _bootstrap_mean_ci(d, n_boot, seed, alpha=0.05):
    """Bootstrap labels with replacement to obtain a CI for mean(delta)."""
    if d.size < 2:
        return np.nan, np.nan

    rng = np.random.default_rng(seed)
    idx = rng.integers(0, d.size, size=(n_boot, d.size))
    means = d[idx].mean(axis=1)

    return (
        float(np.percentile(means, 100 * alpha / 2)),
        float(np.percentile(means, 100 * (1 - alpha / 2))),
    )


def _signflip_p(d, n_perm, seed):
    """Sensitivity analysis using mean(delta) as the sign-flip statistic."""
    if d.size < 2:
        return np.nan

    rng = np.random.default_rng(seed)
    obs = d.mean()
    signs = rng.choice([-1.0, 1.0], size=(n_perm, d.size))
    null = (signs * d).mean(axis=1)

    return float((1.0 + np.sum(null >= obs)) / (1.0 + n_perm))


def label_level_test(
    model_a_dir,
    model_b_dirs,
    bins,
    metrics,
    expected_labels,
    n_boot=10000,
    n_perm=10000,
    seed=0,
):
    """
    Perform paired label-level tests for each:
        model comparison × metric × prevalence bin.

    The primary Wilcoxon test evaluates whether the distribution of paired
    differences is shifted in the positive direction (KG-enhanced > baseline).

    The reported mean difference and its bootstrap CI are effect-size summaries
    and should not be interpreted as the quantity directly tested by Wilcoxon.

    BH FDR is applied separately within each metric across prevalence bins and
    KG-enhanced models. The overall rows are not included in FDR correction.
    """
    df_a = load_label_metrics(model_a_dir, expected_labels=expected_labels)
    rows = []

    for model_b_dir in model_b_dirs:
        df_b = load_label_metrics(model_b_dir, expected_labels=expected_labels)
        validate_metric_pairing(df_a, df_b, model_a_dir, model_b_dir)

        common = df_a.index
        prevalence = df_a.loc[common, "train_col_sum"]

        groups = [
            (
                bin_name(low, high),
                common[(prevalence > low) & (prevalence <= high)],
            )
            for low, high in bins
        ]
        groups.append(("overall", common))

        for metric in metrics:
            col = METRIC_COLS[metric]

            for gname, labels in groups:
                a = df_a.loc[labels, col].to_numpy(dtype=float)
                b = df_b.loc[labels, col].to_numpy(dtype=float)

                ok = np.isfinite(a) & np.isfinite(b)
                a, b = a[ok], b[ok]
                d = b - a

                if d.size == 0:
                    rows.append(
                        dict(
                            model=model_tag(model_b_dir),
                            metric=metric,
                            bin=gname,
                            n_labels=0,
                        )
                    )
                    continue

                # One-sided Wilcoxon:
                # H1 = paired differences are shifted toward positive values.
                if np.allclose(d, 0):
                    w_p = 1.0
                else:
                    try:
                        w_p = float(
                            scipy.stats.wilcoxon(
                                d,
                                alternative="greater",
                            ).pvalue
                        )
                    except ValueError as exc:
                        print(f"[warn] Wilcoxon failed ({metric}/{gname}): {exc}")
                        w_p = np.nan

                ci_lo, ci_hi = _bootstrap_mean_ci(d, n_boot, seed)

                rows.append(
                    dict(
                        model=model_tag(model_b_dir),
                        metric=metric,
                        bin=gname,
                        n_labels=int(d.size),
                        mean_A=float(a.mean()),
                        mean_B=float(b.mean()),
                        mean_diff=float(d.mean()),
                        mean_diff_ci_lo=ci_lo,
                        mean_diff_ci_hi=ci_hi,
                        median_diff=float(np.median(d)),
                        # Denominator intentionally includes ALL tested labels.
                        frac_labels_favor_B=float((d > 0).mean()),
                        wilcoxon_p=w_p,
                        signflip_p=_signflip_p(d, n_perm, seed),
                    )
                )

    df = pd.DataFrame(rows)

    if df.empty:
        return df

    df["wilcoxon_q"] = np.nan
    is_bin = df["bin"] != "overall"

    for metric in df["metric"].unique():
        sel = is_bin & (df["metric"] == metric)

        if sel.any():
            df.loc[sel, "wilcoxon_q"] = bh_fdr(
                df.loc[sel, "wilcoxon_p"].to_numpy()
            )

    return df.sort_values(["metric", "model", "bin"]).reset_index(drop=True)


# ============================================================
# CLI
# ============================================================

def args_argument():
    p = argparse.ArgumentParser(
        description="Label-level significance tests: KG-enhanced vs baseline"
    )

    p.add_argument(
        "--model_a_dir",
        required=True,
        help=(
            "Baseline test output directory, e.g. "
            "disease_prediction/save/nn5_binary/test_bin_2"
        ),
    )
    p.add_argument(
        "--model_b_dir",
        required=True,
        nargs="+",
        help="One or more KG-enhanced model test output directories",
    )
    p.add_argument(
        "--output_dir",
        default="disease_prediction/eval/results",
        help="Output directory for label-level summaries",
    )
    p.add_argument("--metrics", default=",".join(DEFAULT_METRICS))
    p.add_argument("--bin_choice", type=int, default=2)
    p.add_argument(
        "--val_label_path",
        default=os.path.join(config.RAW_DIR, "labels_val.npy"),
    )
    p.add_argument(
        "--test_label_path",
        default=os.path.join(config.RAW_DIR, "labels_test.npy"),
    )
    p.add_argument(
        "--sample_idx_dir",
        default=config.RAW_DIR,
        help="Directory containing the shared sampling cache and manifests",
    )
    p.add_argument(
        "--neg_to_pos_ratio",
        type=int,
        default=10,
        help="Negative-to-positive ratio used by the shared sampling cache",
    )
    p.add_argument("--n_perm", type=int, default=1000)
    p.add_argument("--n_boot", type=int, default=10000)
    p.add_argument("--seed", type=int, default=0)
    p.add_argument("--tag", default=config.TAG, help="Optional output filename suffix")

    return p.parse_args()


def main(args):
    metrics = [m.strip() for m in args.metrics.split(",") if m.strip()]
    unknown = set(metrics) - set(METRIC_COLS)

    if unknown:
        raise ValueError(
            f"Unknown metrics {sorted(unknown)}; supported: {sorted(METRIC_COLS)}"
        )

    bins = get_bins(args.bin_choice)
    suffix = f"_{args.tag}" if args.tag else ""

    os.makedirs(args.output_dir, exist_ok=True)

    # Strictly verify that the current validation/test labels are exactly the
    # matrices used to build the shared sampling cache.
    validate_sampling_manifest(
        args.val_label_path,
        args.sample_idx_dir,
        "val",
        args.neg_to_pos_ratio,
    )

    test_manifest, _ = validate_sampling_manifest(
        args.test_label_path,
        args.sample_idx_dir,
        "test",
        args.neg_to_pos_ratio,
    )

    validate_run_pairing(
        [args.model_a_dir, *args.model_b_dir],
        args.val_label_path, args.test_label_path,
        args.sample_idx_dir, args.neg_to_pos_ratio,
    )

    expected_labels = [int(x) for x in test_manifest.get("label_keys", [])]

    if not expected_labels:
        raise ValueError(
            "The test sampling manifest does not contain any label_keys."
        )

    print(
        f"[pairing] expected evaluable labels from shared test cache: "
        f"{len(expected_labels)}"
    )
    print("\n===== label-level test (primary) =====")

    df = label_level_test(
        args.model_a_dir,
        args.model_b_dir,
        bins,
        metrics,
        expected_labels=expected_labels,
        n_boot=args.n_boot,
        n_perm=args.n_perm,
        seed=args.seed,
    )

    out = os.path.join(
        args.output_dir,
        f"significance_label_level{suffix}.csv",
    )

    df.to_csv(out, index=False)
    print(df.to_string(index=False))
    print(f"\n✅ saved → {out}")


if __name__ == "__main__":
    main(args_argument())
