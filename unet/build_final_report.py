"""Phase 5c — Consolidate every phase into the tables read by the analysis notebooks (U-Net).

Derived from YOLO26's ``yolo26_seg/build_final_report.py``: the output files,
table layouts and tidy-row schema are **identical**, so the same notebooks
(and a cross-architecture comparison) can read both pipelines. U-Net-specific
differences: the YOLO26 instance-metric columns are NaN (not defined for a
semantic-segmentation network), the single-split and CV tidy rows also carry
the U-Net validation pixel metrics (``val_*``, 256×256), and the base-setup
consistency check compares the U-Net base-setup keys.

Inputs (all produced by earlier steps of ``run_pipeline.sh``)::

    summary/phase1_val.json, summary/phase4_val.json        # single-split val metrics
    phase2_cv_baseline/<m>/metrics_summary.json              # CV validation metrics
    phase2_cv_baseline/<m>/pixel_metrics_summary.json        # CV DSC/JSI (dataset resolution)
    phase3_hpo/tune_<m>/hpo_state.json                        # HPO bookkeeping
    phase5_test/accuracy/*.json, phase5_test/per_image/*.csv  # test accuracy
    phase5_test/efficiency/*.json                             # efficiency

Outputs (``<project>/summary/``):

* ``test_accuracy.csv`` — one row per variant × model × precision (instance
  metrics, DSC/JSI mean ± std, median, 95 % CI, pooled, empty predictions).
* ``efficiency.csv`` — one row per variant × model × precision (forward,
  end-to-end and end-to-end-over-distinct-test-images latency median/P95/P99,
  FPS, VRAM (allocator peak and driver-level process peak incl. the CUDA
  context), RAM, size, params, GFLOPs, native input size).
* ``hpo_gain.csv`` — Optimised − Baseline on the test set per model (FP32):
  ΔDSC, ΔJSI, ΔmAP50-95(M), the paired bootstrap 95 % CI of ΔDSC/ΔJSI and the
  two-sided Wilcoxon signed-rank p-value on per-image DSC/JSI.
* ``phase2_cv_pixel.csv`` — CV DSC/JSI mean ± std (ddof=1) per model.
* ``final_results.csv`` — every number above in tidy long format
  (``phase, variant, model, split, precision, metric, value, std, ci95_low,
  ci95_high, n``) — the single source for the notebooks.
* ``final_results.json`` — the same tables nested, plus HPO bookkeeping and
  ``warnings`` (contended benchmarks, resumed trainings, stale CV std,
  budget mismatch between Baseline and Optimised, missing inputs).

Usage:
    python build_final_report.py --project /workspace/logs/pipeline_final_v1
"""

from __future__ import annotations

import argparse
import csv
import math
import sys
from pathlib import Path
from typing import Any

import numpy as np

from common import (
    DEFAULT_ORDER,
    DEFAULT_PIPELINE_ROOT,
    IMGSZ,
    SEED,
    PipelinePaths,
    atomic_write_json,
    read_json,
    utc_now_iso,
)
from segmentation_metrics import LOWER_IS_BETTER
from train_cv_unet import VAL_KEYS
from training import RUN_STATE_FILE

VARIANTS: tuple[str, ...] = ("baseline", "optimized")
PRECISIONS: tuple[str, ...] = ("fp32", "fp16")

#: YOLO26 instance-metric keys (Ultralytics); NaN for the U-Net, kept for an identical schema.
INSTANCE_KEYS: tuple[str, ...] = (
    "map50_m", "map5095_m", "precision_m", "recall_m", "f1_m",
    "map50_b", "map5095_b", "precision_b", "recall_b", "f1_b",
)
#: Base-setup keys that must be identical between Baseline and Optimised runs.
BASE_CHECK_KEYS: tuple[str, ...] = (
    "epochs", "patience", "amp", "seed", "batch", "imgsz", "n_filters", "activation",
    "batchnorm", "optimizer", "adam_eps", "beta2", "lr_schedule", "loss", "monitor",
)
PIXEL_KEYS: tuple[str, ...] = ("dsc", "jsi", "jsi_thr", "sensitivity", "specificity", "accuracy", "biou", "nsd", "hd95")

#: Per-image scores compared between Baseline and Optimised (paired) in ``hpo_gain``:
#: overlap (DSC, JSI) and boundary (Boundary IoU, NSD, HD95 — lower is better) metrics.
PAIRED_KEYS: tuple[str, ...] = ("dsc", "jsi", "biou", "nsd", "hd95")


def parse_args() -> argparse.Namespace:
    """Parse command-line arguments."""
    p = argparse.ArgumentParser(description="Build the consolidated final report of the 5-phase pipeline.")
    p.add_argument("--models", nargs="+", default=DEFAULT_ORDER, choices=DEFAULT_ORDER)
    p.add_argument("--project", default=DEFAULT_PIPELINE_ROOT, help="Pipeline root.")
    return p.parse_args()


def _write_csv(path: Path, rows: list[dict[str, Any]]) -> None:
    """Write rows (union of keys, first-seen order) to CSV; no file when empty."""
    if not rows:
        return
    fields: list[str] = []
    for r in rows:
        fields += [k for k in r if k not in fields]
    path.parent.mkdir(parents=True, exist_ok=True)
    with path.open("w", newline="") as f:
        w = csv.DictWriter(f, fieldnames=fields)
        w.writeheader()
        w.writerows(rows)


def _read_per_image(path: Path) -> dict[str, dict[str, float]]:
    """Per-image :data:`PAIRED_KEYS` scores keyed by image path (keys absent from older files are skipped)."""
    with path.open() as f:
        return {r["image"]: {k: float(r[k]) for k in PAIRED_KEYS if r.get(k) not in (None, "")}
                for r in csv.DictReader(f)}


def run_training_time(results_csv: Path) -> tuple[int, float]:
    """``(epochs, wall-clock seconds)`` of one training run, from its ``results.csv``.

    Per-epoch durations (``time_s``) are summed; a cumulative clock (Ultralytics'
    ``time``, which restarts from zero when a run is resumed) is integrated
    segment by segment. Validation time per epoch is included.
    """
    with Path(results_csv).open() as f:
        rows = [{k.strip(): v for k, v in r.items()} for r in csv.DictReader(f)]
    if not rows:
        return 0, 0.0
    if "time_s" in rows[0]:
        return len(rows), sum(float(r["time_s"]) for r in rows)
    total, prev = 0.0, 0.0
    for r in rows:
        t = float(r["time"])
        total += t - prev if t >= prev else t
        prev = t
    return len(rows), total


class Report:
    """Accumulates tables, tidy rows and warnings."""

    def __init__(self, paths: PipelinePaths, models: list[str]) -> None:
        self.paths, self.models = paths, models
        self.tidy: list[dict[str, Any]] = []
        self.warnings: list[str] = []
        self.tables: dict[str, list[dict[str, Any]]] = {}

    def add(self, phase: str, variant: str, model: str, split: str, precision: str,
            metric: str, value: Any, std: Any = None, lo: Any = None, hi: Any = None,
            n: Any = None) -> None:
        """Append one tidy row."""
        self.tidy.append({
            "phase": phase, "variant": variant, "model": model, "split": split,
            "precision": precision, "metric": metric, "value": value, "std": std,
            "ci95_low": lo, "ci95_high": hi, "n": n,
        })

    # ---- Phases 1 & 4 (validation split) ---------------------------------
    def single_split(self) -> None:
        """Collect Phase 1 / Phase 4 val metrics and check the shared budget."""
        for phase, variant in (("phase1", "baseline"), ("phase4", "optimized")):
            data = read_json(self.paths.summary_dir / f"{phase}_val.json")
            if data is None:
                self.warnings.append(f"summary/{phase}_val.json missing (run collect_phase_metrics.py)")
                continue
            for row in data["models"]:
                if row["model"] not in self.models:
                    continue
                if row.get("resumed"):
                    self.warnings.append(f"{phase}/{row['model']}: training was resumed after an interruption")
                for k in INSTANCE_KEYS + ("best_epoch", "epochs_trained") + VAL_KEYS:
                    self.add(phase, variant, row["model"], "val", "fp32", k, row.get(k))
        for m in self.models:
            protos = []
            for run in (self.paths.phase1_dir / self.paths.phase1_run_name(m),
                        self.paths.phase4_dir / self.paths.phase4_run_name(m)):
                state = read_json(run / RUN_STATE_FILE)
                if state:
                    protos.append({k: state["protocol"].get(k) for k in BASE_CHECK_KEYS})
            if len(protos) == 2 and protos[0] != protos[1]:
                self.warnings.append(f"{m}: Baseline and Optimised budgets differ: {protos[0]} vs {protos[1]}")

    # ---- Phase 2 (CV) -------------------------------------------------------
    def cross_validation(self) -> None:
        """Collect CV instance metrics and CV pixel metrics (mean ± sample std)."""
        pixel_rows = []
        for m in self.models:
            root = self.paths.cv_model_dir(m, "baseline")
            inst = read_json(root / "metrics_summary.json")
            if inst is None:
                self.warnings.append(f"phase2/{m}: metrics_summary.json missing")
            else:
                if inst.get("std_ddof") != 1:
                    self.warnings.append(f"phase2/{m}: CV std is a population std — re-run Phase 2 to refresh")
                for k in INSTANCE_KEYS + VAL_KEYS:
                    v = inst["summary"].get(k, {})
                    self.add("phase2", "baseline", m, "cv", "fp32", k, v.get("mean"), v.get("std"), n=inst["n_folds"])
            pix = read_json(root / "pixel_metrics_summary.json")
            if pix is None:
                self.warnings.append(f"phase2/{m}: pixel_metrics_summary.json missing (run evaluate_cv_pixels.py)")
                continue
            row = {"model": m, "n_folds": pix["n_folds"]}
            for k in PIXEL_KEYS + ("pooled_dsc", "pooled_jsi"):
                v = pix["summary"].get(k) or {"mean": math.nan, "std": math.nan}
                row[f"{k}_mean"], row[f"{k}_std"] = v["mean"], v["std"]
                self.add("phase2", "baseline", m, "cv", "fp32", k, v["mean"], v["std"], n=pix["n_folds"])
            pixel_rows.append(row)
        self.tables["phase2_cv_pixel"] = pixel_rows

    # ---- Phase 3 (HPO) ------------------------------------------------------
    def hpo(self) -> dict[str, Any]:
        """HPO bookkeeping per model (trials, best fitness, failures)."""
        out = {}
        for m in self.models:
            state = read_json(self.paths.phase3_state(m))
            if state is None:
                self.warnings.append(f"phase3/{m}: hpo_state.json missing")
                continue
            out[m] = {k: state.get(k) for k in (
                "status", "completed_trials", "valid_trials", "target_trials", "best_fitness",
                "best_trial", "accepted_failures", "versions")}
            if state.get("status") != "complete":
                self.warnings.append(f"phase3/{m}: HPO not complete")
        return out

    # ---- Phase 5a (test accuracy) ------------------------------------------
    def test_accuracy(self) -> None:
        """Collect test-set accuracy per variant/model/precision."""
        rows = []
        for variant in VARIANTS:
            for m in self.models:
                for prec in PRECISIONS:
                    acc = read_json(self.paths.phase5_accuracy_json(variant, m, prec))
                    if acc is None:
                        self.warnings.append(f"phase5/{variant}_{m}_{prec}: test accuracy missing")
                        continue
                    pix, inst = acc["pixel_metrics"], acc["instance_metrics"]
                    row = {"variant": variant, "model": m, "precision": prec, "n_images": acc["n_images"],
                           **{k: inst[k] for k in INSTANCE_KEYS},
                           "n_empty_pred": pix["n_empty_pred"],
                           "pooled_dsc": pix["pooled_dsc"], "pooled_jsi": pix["pooled_jsi"]}
                    for k in INSTANCE_KEYS:
                        self.add("phase5", variant, m, "test", prec, k, inst[k], n=acc["n_images"])
                    for k in PIXEL_KEYS:
                        s = pix.get(k) or {}
                        for stat in ("mean", "std", "median", "ci95_low", "ci95_high"):
                            row[f"{k}_{stat}"] = s.get(stat)
                        self.add("phase5", variant, m, "test", prec, k, s.get("mean"), s.get("std"),
                                 s.get("ci95_low"), s.get("ci95_high"), s.get("n"))
                    for k in ("pooled_dsc", "pooled_jsi", "n_empty_pred"):
                        self.add("phase5", variant, m, "test", prec, k, row[k], n=acc["n_images"])
                    rows.append(row)
        self.tables["test_accuracy"] = rows

    # ---- HPO gain (paired, test set, FP32) ---------------------------------
    def hpo_gain(self) -> None:
        """Paired Optimised − Baseline comparison on the same test images."""
        try:
            from scipy.stats import wilcoxon
        except ImportError:  # pragma: no cover - scipy is pinned in the image
            wilcoxon = None
        rng = np.random.default_rng(SEED)
        rows = []
        for m in self.models:
            files = [self.paths.phase5_per_image_csv(v, m, "fp32") for v in VARIANTS]
            accs = [read_json(self.paths.phase5_accuracy_json(v, m, "fp32")) for v in VARIANTS]
            if not all(f.exists() for f in files) or None in accs:
                continue
            base, opt = (_read_per_image(f) for f in files)
            common_imgs = sorted(set(base) & set(opt))
            if len(common_imgs) != len(base) or len(base) != len(opt):
                self.warnings.append(f"hpo_gain/{m}: baseline and optimised were scored on different images")
            row: dict[str, Any] = {"model": m, "n_images": len(common_imgs)}
            for k in PAIRED_KEYS:
                if not all(k in base[i] and k in opt[i] for i in common_imgs):
                    continue   # metric absent from older per-image files
                b = np.array([base[i][k] for i in common_imgs])
                o = np.array([opt[i][k] for i in common_imgs])
                d = o - b
                boot = d[rng.integers(0, len(d), size=(2000, len(d)))].mean(axis=1)
                p = math.nan
                if wilcoxon is not None and np.any(d != 0):
                    p = float(wilcoxon(o, b, zero_method="wilcox", alternative="two-sided").pvalue)
                row.update({
                    f"{k}_baseline": float(b.mean()), f"{k}_optimized": float(o.mean()),
                    f"delta_{k}": float(d.mean()),
                    f"delta_{k}_ci95_low": float(np.quantile(boot, 0.025)),
                    f"delta_{k}_ci95_high": float(np.quantile(boot, 0.975)),
                    f"wilcoxon_p_{k}": p,
                    f"n_improved_{k}": int(((d < 0) if k in LOWER_IS_BETTER else (d > 0)).sum()),
                    f"n_worse_{k}": int(((d > 0) if k in LOWER_IS_BETTER else (d < 0)).sum()),
                })
                self.add("hpo_gain", "optimized-baseline", m, "test", "fp32", f"delta_{k}",
                         row[f"delta_{k}"], None, row[f"delta_{k}_ci95_low"], row[f"delta_{k}_ci95_high"],
                         len(d))
                self.add("hpo_gain", "optimized-baseline", m, "test", "fp32", f"wilcoxon_p_{k}", p, n=len(d))
            dm = accs[1]["instance_metrics"]["map5095_m"] - accs[0]["instance_metrics"]["map5095_m"]
            row["delta_map5095_m"] = dm
            self.add("hpo_gain", "optimized-baseline", m, "test", "fp32", "delta_map5095_m", dm)
            rows.append(row)
        self.tables["hpo_gain"] = rows

    # ---- Training cost (all phases) ----------------------------------------
    def training_cost(self) -> None:
        """Epochs and wall-clock training time per phase and model (from every results.csv)."""
        rows = []
        for m in self.models:
            groups = {
                "phase1_baseline": [self.paths.phase1_dir / self.paths.phase1_run_name(m) / "results.csv"],
                "phase2_cv_baseline": sorted((self.paths.cv_model_dir(m, "baseline") / "runs").glob("fold_*/results.csv")),
                "phase3_hpo": sorted(self.paths.phase3_tune_dir(m).glob("**/results.csv")),
                "phase4_optimized": [self.paths.phase4_dir / self.paths.phase4_run_name(m) / "results.csv"],
            }
            for phase, files in groups.items():
                files = [f for f in files if f.exists()]
                if not files:
                    continue
                runs = [run_training_time(f) for f in files]
                epochs, secs = sum(e for e, _ in runs), sum(t for _, t in runs)
                row = {"phase": phase, "model": m, "runs": len(runs), "epochs": epochs,
                       "train_hours": secs / 3600, "sec_per_epoch": secs / epochs if epochs else math.nan}
                rows.append(row)
                for k in ("runs", "epochs", "train_hours", "sec_per_epoch"):
                    self.add(phase, "all" if phase != "phase4_optimized" else "optimized", m, "train", "fp32",
                             k, row[k])
        self.tables["training_cost"] = rows

    # ---- Phase 5b (efficiency) ---------------------------------------------
    def efficiency(self) -> None:
        """Collect efficiency per variant/model/precision."""
        rows = []
        for variant in VARIANTS:
            for m in self.models:
                for prec in PRECISIONS:
                    e = read_json(self.paths.phase5_efficiency_json(variant, m, prec))
                    if e is None:
                        self.warnings.append(f"phase5/{variant}_{m}_{prec}: efficiency missing")
                        continue
                    if e.get("contended"):
                        self.warnings.append(f"phase5/{variant}_{m}_{prec}: benchmark ran on a busy GPU")
                    fw, ee, mem, mdl = e["forward"], e["end_to_end"], e["memory"], e["model"]
                    row = {
                        "variant": variant, "model": m, "precision": prec, "batch": 1,
                        "gpu": e["env"].get("gpu"), "contended": e.get("contended"),
                        **{f"fwd_{k}": fw[k] for k in ("mean_ms", "std_ms", "median_ms", "p90_ms", "p95_ms", "p99_ms", "fps", "fps_median")},
                        **{f"e2e_{k}": ee[k] for k in ("mean_ms", "median_ms", "p95_ms", "p99_ms", "fps", "fps_median")},
                        **{f"e2e_dataset_{k}": (e.get("end_to_end_dataset") or {}).get(k)
                           for k in ("n", "mean_ms", "median_ms", "p95_ms", "p99_ms", "fps")},
                        "vram_weights_mb": mem["vram_weights_mb"],
                        "vram_peak_allocated_mb": mem["vram_peak_allocated_mb"],
                        "vram_peak_reserved_mb": mem["vram_peak_reserved_mb"],
                        "vram_peak_allocated_e2e_mb": mem["vram_peak_allocated_e2e_mb"],
                        "ram_peak_rss_mb": mem["ram_peak_rss_mb"],
                        "ram_model_delta_mb": mem["ram_model_delta_mb"],
                        "size_mb_disk": mdl["size_mb_disk"],
                        "size_mb_fp32_theoretical": mdl["size_mb_fp32_theoretical"],
                        "size_mb_fp16_theoretical": mdl["size_mb_fp16_theoretical"],
                        "vram_peak_allocated_e2e_dataset_mb": mem.get("vram_peak_allocated_e2e_dataset_mb"),
                        "vram_cuda_context_mb": mem.get("vram_cuda_context_mb"),
                        "vram_process_peak_mb": mem.get("vram_process_peak_mb"),
                        "params": mdl["params"], "params_fused": mdl["params_fused"], "gflops": mdl["gflops"],
                        "gflops_640": mdl.get("gflops_640"), "input_px": IMGSZ,
                    }
                    for k, v in row.items():
                        if k not in ("variant", "model", "precision", "gpu", "batch") and v is not None:
                            self.add("phase5", variant, m, "test", prec, k, v)
                    rows.append(row)
        self.tables["efficiency"] = rows


def main() -> int:
    """Build every table and write CSV + JSON.

    Returns:
        ``0`` if the FP32 test accuracy of both variants exists for every
        requested model, ``1`` otherwise (the partial report is still written).
    """
    args = parse_args()
    paths = PipelinePaths(Path(args.project))
    rep = Report(paths, args.models)
    rep.single_split()
    rep.cross_validation()
    hpo = rep.hpo()
    rep.test_accuracy()
    rep.hpo_gain()
    rep.efficiency()
    rep.training_cost()

    out = paths.summary_dir
    for name in ("test_accuracy", "efficiency", "hpo_gain", "phase2_cv_pixel", "training_cost"):
        _write_csv(out / f"{name}.csv", rep.tables.get(name, []))
    _write_csv(out / "final_results.csv", rep.tidy)
    atomic_write_json(out / "final_results.json", {
        "generated_at": utc_now_iso(), "project": str(paths.root), "models": args.models,
        "tables": rep.tables, "hpo": hpo, "warnings": rep.warnings,
    })

    print(f"Final report written to {out}/")
    for name, rows in rep.tables.items():
        print(f"  {name:<16} {len(rows)} row(s)")
    print(f"  final_results    {len(rep.tidy)} tidy row(s)")
    for g in rep.tables.get("hpo_gain", []):
        print(f"  HPO gain {g['model']:<7}: ΔDSC={g['delta_dsc']:+.4f} "
              f"[{g['delta_dsc_ci95_low']:+.4f}, {g['delta_dsc_ci95_high']:+.4f}]  "
              f"p={g['wilcoxon_p_dsc']:.3g}   ΔJSI={g['delta_jsi']:+.4f}")
    if rep.warnings:
        print(f"\n  {len(rep.warnings)} warning(s):")
        for w in rep.warnings:
            print(f"   - {w}")

    have = {(r["variant"], r["model"]) for r in rep.tables.get("test_accuracy", []) if r["precision"] == "fp32"}
    complete = all((v, m) in have for v in VARIANTS for m in args.models)
    return 0 if complete else 1


if __name__ == "__main__":
    sys.exit(main())
