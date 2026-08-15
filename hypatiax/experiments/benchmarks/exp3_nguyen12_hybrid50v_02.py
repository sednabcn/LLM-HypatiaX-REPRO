#!/usr/bin/env python3
"""
exp3_nguyen12_hybrid50v_02.py  —  Exp 3 · Nguyen-12 SR suite  (§10.8 primary)
==============================================================================
Standalone Python script version — safe to run with `python3` directly.

Origin: extracted from HypatiaX_Experiments_v6_PUBLIC.ipynb (Cell 27)
Fixes applied (v02 → v03):
  - Removed Jupyter-only magic syntax (!pip install, %env, !)
  - Added __main__ guard
  - Added sys.path setup so imports resolve from repo root
  - Stale lock cleared before run (mirrors notebook Cell 27 logic)
  - Deps checked with importlib instead of subprocess pip call
  [PATCH A] Unified seed block — random/numpy/torch/Julia all set from SEED
  [PATCH E] Google Colab import replaced with pipeline-safe API key loader
  [PATCH F] IPython download block replaced with pipeline-safe output printer
  [PATCH G] Protocol imports use try/fallback for pre/post-restructure layout

CI / sharding fixes (v03 → current):
  [FIX-1] _apply_task_ids_nguyen: silent fallback-all replaced with hard exit.
          Previously a 0-match (wrong meta key, bad TASK_IDS format, etc.) made
          the shard silently run ALL 12 equations instead of its assigned subset,
          producing duplicate results across shards and corrupting checkpoints.
          Now: sys.exit(1) with a clear diagnostic so the CI job fails loudly.
  [FIX-2] _apply_case_range no longer applied to sys.path list.
          The two-element path list is not a test-case sequence; applying
          _apply_case_range to it could silently drop the repo-root sys.path
          entry when CASE_RANGE_START=2, breaking all subsequent imports.
          _apply_case_range is now only applied to all_cases (the correct seq).
  [FIX-3] SHARD_IDS env var honoured in addition to TASK_IDS.
          The CI YML sets both; previously only TASK_IDS was read. If TASK_IDS
          is absent but SHARD_IDS is set the filter now uses SHARD_IDS, which
          makes the script forward-compatible with YML changes.
  [FIX-4] Output JSON path uses RESULTS_DIR env var when set, matching the
          worker step env (RESULTS_DIR = OUT_BASE = hypatiax/data/results).
          Previously the path was always relative to _results_dir (repo-local),
          which diverged from the CI artifact upload path under OUT_BASE.
  [FIX-5] N_NGUYEN_TASKS ceiling applied AFTER _apply_task_ids_nguyen, not
          before. The old order [:n_tasks] → filter could silently exclude
          shard-assigned IDs that fell beyond the ceiling. New order: load all,
          filter by TASK_IDS, then apply the N_NGUYEN_TASKS smoke-test cap.
  [FIX-CHECKPOINT-CALL] Invoke _save() after each equation (not just at end).
          The _save() function was defined but never called in the main loop.
          If the job was killed mid-run, zero checkpoint data was written.
          Now checkpoints are saved after every equation and on deadline approach.

Expected result : 11/12 H (91.7 %) · 10/12 P (83.3 %) · 0/12 NN
                  MW P>NN U=113, p=0.0097
Wall time       : 30–90 min
SEED            : 42 (fixed for reproducibility; override with --seed)

Usage
-----
    python3 exp3_nguyen12_hybrid50v_02.py             # SEED=42 (default)
    python3 exp3_nguyen12_hybrid50v_02.py --seed 123  # stability check
    python3 exp3_nguyen12_hybrid50v_02.py --seed 777  # stability check

CI shard usage (set by ci_runner.yml worker dispatch):
    TASK_IDS="N1 N3 N7" PYSR_SEED=42 EXPERIMENT_SEED=42 \\
        python3 exp3_nguyen12_hybrid50v_02.py --seed 42
"""

import argparse
import importlib
import os
import pathlib
import shutil
import random
import re
import sys
import traceback
import threading
import time

import numpy as np


# ── PySR trajectory instrumentation ────────────────────────────────────────
def _read_pysr_hof_snapshot(path):
    """Read the current PySR hall-of-fame checkpoint without requiring pandas.

    PySR/SymbolicRegression writes the hall-of-fame checkpoint as a pipe-delimited
    file and updates it during the search.  We intentionally treat this as an
    *outer-iteration* trajectory, not as an individual mutation/generation log.
    """
    import csv

    path = pathlib.Path(path)
    candidates = [pathlib.Path(str(path) + ".bkup"), path]
    chosen = next((q for q in candidates if q.exists() and q.stat().st_size > 0), None)
    if chosen is None:
        return None

    try:
        stat = chosen.stat()
        with chosen.open("r", encoding="utf-8", errors="replace", newline="") as f:
            rows = list(csv.DictReader(f, delimiter="|"))
        if not rows:
            return None

        # Normalize column names because backend versions have used slightly
        # different capitalization/spelling for these fields.
        norm = {}
        for k in rows[0].keys():
            if k is not None:
                norm[str(k).strip().lower()] = k

        def col(*names):
            for name in names:
                if name in norm:
                    return norm[name]
            return None

        loss_col = col("loss", "mse", "error")
        expr_col = col("equation", "expression", "expr")
        complexity_col = col("complexity")
        score_col = col("score")

        def fnum(row, c):
            if c is None:
                return None
            try:
                x = float(str(row.get(c, "")).strip())
                return x if np.isfinite(x) else None
            except Exception:
                return None

        valid = []
        for row in rows:
            loss = fnum(row, loss_col)
            if loss is not None:
                valid.append((loss, row))
        if not valid:
            return None

        best_loss, best_row = min(valid, key=lambda z: z[0])
        best_expr = None if expr_col is None else str(best_row.get(expr_col, "")).strip()
        best_complexity = fnum(best_row, complexity_col)
        best_score = fnum(best_row, score_col)

        return {
            "source_file": str(chosen),
            "source_mtime_ns": int(stat.st_mtime_ns),
            "source_size_bytes": int(stat.st_size),
            "hall_of_fame_rows": len(rows),
            "best_loss": float(best_loss),
            "best_expression": best_expr,
            "best_complexity": best_complexity,
            "best_score": best_score,
        }
    except (OSError, UnicodeError, csv.Error, ValueError):
        # A writer can be in the middle of replacing/updating the checkpoint.
        # The monitor simply retries on the next polling cycle.
        return None


def _fit_with_pysr_trajectory(model, X, y, variable_names, label, poll_seconds=1.0,
                               seed=None, nguyen_id=None, archive_dir=None):
    """Run model.fit while polling PySR's live hall-of-fame checkpoint.

    Parameters
    ----------
    seed, nguyen_id, archive_dir : optional
        If all three are given, the final hall_of_fame.csv is copied to
        ``archive_dir / f"hall_of_fame_seed{seed}_{H|P}_{nguyen_id}.csv"``
        before returning. `temp_equation_file=True` on PySRRegressor means
        the live checkpoint lives in a temp dir that's not guaranteed to
        survive past this call, so archiving happens here, immediately
        after fit() returns and before that temp dir can be cleaned up —
        not deferred to the caller.
        `label` is normalized to just "H" or "P" for the filename (e.g.
        "H-cold-fallback" -> "H"); the full original label is still kept
        in each trajectory record's own "label" field.

    Returns
    -------
    trajectory : list[dict]
        One record per observed hall-of-fame update.  The `iteration` field is
        an observation index unless the backend exposes an explicit iteration
        number.  The underlying file is emitted by PySR at iteration boundaries,
        so these records represent outer search iterations, not every mutation.
    """
    trajectory = []
    stop_event = threading.Event()
    # [FIX-TRAJECTORY-ROBUST-PATH] Keep diagnostics even when PySR changes
    # its run-directory / hall-of-fame filename conventions.
    fit_result = {
        "error": None,
        "traceback": None,
        "hof_path": None,
        "hof_exists_during_fit": False,
        "hof_exists_at_end": False,
        "hof_candidates_checked": [],
    }
    t0 = time.time()

    def _candidate_hof_paths():
        """Return all plausible live PySR hall-of-fame paths.

        PySR versions differ in whether the run directory is exposed before
        fit(), whether the filename is exactly hall_of_fame.csv, or whether
        it contains a timestamp.  Do not hard-code one filename.
        """
        candidates = []

        def add_run_dir(base, run_id):
            if not base or not run_id:
                return
            try:
                run_dir = pathlib.Path(base) / str(run_id)
                candidates.append(run_dir / "hall_of_fame.csv")
                candidates.extend(sorted(run_dir.glob("hall_of_fame*.csv")))
                candidates.extend(sorted(run_dir.glob(".hall_of_fame*.csv")))
                candidates.extend(sorted(run_dir.glob("*hall_of_fame*.csv")))
            except Exception:
                pass

        # Constructor-time attributes are available before fit in supported
        # PySR versions; underscore variants are populated by newer releases.
        for base_name in ("output_directory_", "output_directory"):
            try:
                base = getattr(model, base_name, None)
                for run_name in ("run_id_", "run_id"):
                    try:
                        add_run_dir(base, getattr(model, run_name, None))
                    except Exception:
                        pass
            except Exception:
                pass

        # Legacy equation-file accessors, including get_equation_file().
        try:
            getter = getattr(model, "get_equation_file", None)
            if callable(getter):
                q = getter()
                if q:
                    candidates.append(pathlib.Path(q))
        except Exception:
            pass
        for attr in ("equation_file_", "equation_file"):
            try:
                q = getattr(model, attr, None)
                if q:
                    candidates.append(pathlib.Path(q))
            except Exception:
                pass

        # De-duplicate while preserving discovery order.
        unique = []
        seen = set()
        for q in candidates:
            try:
                q = pathlib.Path(q)
                key = str(q)
                if key not in seen:
                    seen.add(key)
                    unique.append(q)
            except Exception:
                continue
        return unique

    def _find_hof_path():
        # Prefer an existing, non-empty hall-of-fame file.  If no file exists
        # yet, return the first plausible path so the monitor can discover it
        # as soon as PySR creates it.
        candidates = _candidate_hof_paths()
        fit_result["hof_candidates_checked"] = [str(q) for q in candidates[:50]]
        existing = [
            q for q in candidates
            if q.exists() and q.is_file() and q.stat().st_size > 0
        ]
        if existing:
            # Prefer the most recently modified checkpoint.
            return max(existing, key=lambda q: q.stat().st_mtime_ns)
        return candidates[0] if candidates else None
        # [FIX-TRAJECTORY-EMPTY] Prior to this fix, this function only tried
        # `equation_file_` / `equation_file`, which resolved to None for the
        # entire run under the installed PySR version (1.5.10) and produced
        # zero trajectory observations regardless of whether the fit
        # succeeded:
        #   - `equation_file_` is a @property that unconditionally raises
        #     NotImplementedError in this version ("...is now deprecated.
        #     Please use PySRRegressor.output_directory_ and
        #     PySRRegressor.run_id_ instead."), and the blanket
        #     `except Exception: pass` below silently swallowed that.
        #   - `equation_file` (no trailing underscore) is a deprecated
        #     *constructor-only* kwarg, not a live attribute updated during
        #     fit — since it's never passed, getattr always returned None.
        #
        # Fix: prefer the modern output_directory_/run_id_ path (matches
        # PySRRegressor.get_equation_file() in the installed version), and
        # fall back to the legacy equation_file_ property for older PySR
        # releases where it still resolves to a real path instead of
        # raising. Both branches are kept so this survives future PySR
        # version changes in either direction.
        try:
            if hasattr(model, "output_directory_") and hasattr(model, "run_id_"):
                return pathlib.Path(model.output_directory_) / model.run_id_ / "hall_of_fame.csv"
        except Exception:
            pass
        try:
            q = getattr(model, "equation_file_", None)
            if q:
                return pathlib.Path(q)
        except NotImplementedError:
            pass
        except Exception:
            pass
        try:
            q = getattr(model, "equation_file", None)
            if q:
                return pathlib.Path(q)
        except Exception:
            pass
        return None

    def _monitor():
        last_signature = None
        while not stop_event.is_set():
            path = _find_hof_path()
            if path is not None:
                if path.exists():
                    fit_result["hof_exists_during_fit"] = True
                    fit_result["hof_path"] = str(path)
                snap = _read_pysr_hof_snapshot(path)
                if snap is not None:
                    signature = (
                        snap["source_mtime_ns"],
                        snap["source_size_bytes"],
                        snap["best_loss"],
                        snap["best_expression"],
                    )
                    if signature != last_signature:
                        last_signature = signature
                        snap["iteration"] = len(trajectory) + 1
                        snap["elapsed_seconds"] = float(time.time() - t0)
                        snap["label"] = label
                        trajectory.append(snap)
            stop_event.wait(poll_seconds)

    monitor = threading.Thread(target=_monitor, name=f"pysr-monitor-{label}", daemon=True)
    monitor.start()
    try:
        model.fit(X, y, variable_names=variable_names)
    except Exception as exc:
        fit_result["error"] = str(exc)
        fit_result["traceback"] = traceback.format_exc()
    finally:
        stop_event.set()
        monitor.join(timeout=max(2.0, poll_seconds * 3.0))

    # Always capture a final snapshot after fit returns, because the final
    # checkpoint can be written immediately before the backend exits and the
    # polling thread may not have observed it.
    path = _find_hof_path()
    if path is not None:
        fit_result["hof_path"] = str(path)
        fit_result["hof_exists_at_end"] = bool(path.exists() and path.is_file() and path.stat().st_size > 0)
        snap = _read_pysr_hof_snapshot(path)
        if snap is not None:
            signature = (
                snap["source_mtime_ns"],
                snap["source_size_bytes"],
                snap["best_loss"],
                snap["best_expression"],
            )
            last_signature = None
            if trajectory:
                last = trajectory[-1]
                last_signature = (
                    last["source_mtime_ns"],
                    last["source_size_bytes"],
                    last["best_loss"],
                    last["best_expression"],
                )
            if signature != last_signature:
                snap["iteration"] = len(trajectory) + 1
                snap["elapsed_seconds"] = float(time.time() - t0)
                snap["label"] = label
                trajectory.append(snap)

        # [ARCHIVE-HOF-CSV] Copy the final checkpoint out of PySR's
        # (possibly temp) run directory to a permanent, self-describing
        # filename before it can be lost to temp_equation_file=True cleanup.
        if seed is not None and nguyen_id is not None and archive_dir is not None:
            try:
                arm = "H" if str(label).startswith("H") else "P"
                archive_dir = pathlib.Path(archive_dir)
                archive_dir.mkdir(parents=True, exist_ok=True)
                dest = archive_dir / f"hall_of_fame_seed{seed}_{arm}_{nguyen_id}.csv"
                shutil.copy2(path, dest)
                fit_result["hof_archive_path"] = str(dest)
            except Exception as _archive_exc:
                # Archiving is best-effort — never let it fail the fit.
                fit_result["hof_archive_error"] = str(_archive_exc)

    # Make the failure mode explicit in the JSON rather than silently
    # returning an empty trajectory after a successful fit.
    if not fit_result["hof_exists_at_end"]:
        print(
            f"    ⚠  PySR fit completed but no non-empty hall-of-fame CSV was found "
            f"for {label}. Checked: {fit_result['hof_candidates_checked'][:5]}"
        )
    return trajectory, fit_result


def _trajectory_summary(trajectory, y=None, r2_threshold=0.9999):
    """Summarize the observed outer-iteration trajectory.

    If *y* is supplied, convert the PySR MSE loss into an approximate R² using
    ``R² = 1 - MSE / Var(y)``.  The exact final R² is still computed separately
    with sklearn in the experiment; trajectory R² values are therefore marked
    as estimates.
    """
    if not trajectory:
        return {
            "n_iterations_observed": 0,
            "first_threshold_iteration": None,
            "first_threshold_time_seconds": None,
            "final_best_loss": None,
            "final_best_expression": None,
            "final_best_complexity": None,
            "r2_from_loss_is_approximate": True,
        }

    y_var = None
    if y is not None:
        try:
            yy = np.asarray(y, dtype=float).reshape(-1)
            y_var = float(np.mean((yy - np.mean(yy)) ** 2))
            if not np.isfinite(y_var) or y_var <= 0:
                y_var = None
        except Exception:
            y_var = None

    enriched = []
    for row in trajectory:
        item = dict(row)
        loss = item.get("best_loss")
        if y_var is not None and loss is not None:
            try:
                r2_est = float(1.0 - float(loss) / y_var)
                item["best_r2_estimate"] = r2_est if np.isfinite(r2_est) else None
            except Exception:
                item["best_r2_estimate"] = None
        else:
            item["best_r2_estimate"] = None
        enriched.append(item)

    threshold_rows = [
        x for x in enriched
        if x.get("best_r2_estimate") is not None
        and x["best_r2_estimate"] >= r2_threshold
    ]
    first = threshold_rows[0] if threshold_rows else None
    last = enriched[-1]
    return {
        "n_iterations_observed": len(enriched),
        "first_threshold_iteration": first.get("iteration") if first else None,
        "first_threshold_time_seconds": first.get("elapsed_seconds") if first else None,
        "final_best_loss": last.get("best_loss"),
        "final_best_r2_estimate": last.get("best_r2_estimate"),
        "final_best_expression": last.get("best_expression"),
        "final_best_complexity": last.get("best_complexity"),
        "final_best_score": last.get("best_score"),
        "r2_from_loss_is_approximate": True,
    }


# ── CASE RANGE INJECTION (auto-generated by add_case_range_benchmark.py) ──
def _apply_case_range(seq):
    """Return the slice of *seq* selected by CASE_RANGE_START/CASE_RANGE_END.

    Uses 1-based inclusive indexing to match CI --case-range N-M syntax.
    Returns seq unchanged when neither variable is set (local runs).

    NOTE: must only be applied to test-case sequences, NOT to sys.path lists.
    See FIX-2 in the module docstring.
    """
    try:
        n     = len(seq)
        start = max(0, int(os.getenv("CASE_RANGE_START", "1")) - 1)
        end   = min(n, int(os.getenv("CASE_RANGE_END",   str(n))))
        return seq[start:end]
    except Exception:
        return seq
# ────────────────────────────────────────────────────────────────────────────

# ── TASK_IDS / SHARD_IDS / SEED injection ───────────────────────────────────
def _apply_task_ids_nguyen(seq):
    """Filter Nguyen case list to those whose nguyen_id appears in TASK_IDS.

    TASK_IDS format for exp3: "N1 N2 N5 N11"  (space- or comma-separated).
    SHARD_IDS is also checked when TASK_IDS is absent (CI forward-compat).
    Each element of *seq* is (desc, X, y, var_names, meta); meta["nguyen_id"]
    is the canonical ID.

    Returns seq unchanged when neither env var is set (full-12 local run).

    [FIX-1] Zero-match is now a hard exit, not a silent fallback-all.
    A 0-match means TASK_IDS contains IDs that do not exist in the protocol
    (e.g. wrong format, missing meta key) — silently running all 12 equations
    would corrupt checkpoint deduplication across shards.
    """
    # Priority: TASK_IDS > SHARD_IDS  (mirrors hybrid_system_llm_nn_all_domains.py)
    raw = ""
    for var in ("TASK_IDS", "SHARD_IDS"):
        raw = os.environ.get(var, "").replace(",", " ").strip()
        if raw:
            break

    if not raw:
        return seq  # local run — no filter

    allowed  = set(raw.split())
    filtered = [t for t in seq if t[4].get("nguyen_id") in allowed]

    if not filtered:
        # [FIX-1] Hard exit instead of silent fallback-all.
        # List which IDs were requested vs what the protocol actually provides
        # so the CI log immediately shows the mismatch.
        available = sorted(set(t[4].get("nguyen_id", "?") for t in seq))
        print(
            f"ERROR: TASK_IDS={sorted(allowed)!r} matched 0/{len(seq)} Nguyen tasks.\n"
            f"       Available nguyen_ids: {available}\n"
            f"       Check that meta['nguyen_id'] is set in NguYenProtocol and that\n"
            f"       the CI plan registry uses the same IDs (N1–N12).",
            file=sys.stderr,
        )
        sys.exit(1)

    print(
        f"ℹ️  TASK_IDS filter: {len(filtered)}/{len(seq)} tasks selected "
        f"({[t[4]['nguyen_id'] for t in filtered]})"
    )
    return filtered


def _resolve_seed():
    """Return seed: PYSR_SEED → EXPERIMENT_SEED → NN_SEED → CLI --seed → 42.

    Priority order ensures CI env-var always wins over the argparse default,
    while local runs with an explicit --seed still work correctly.
    """
    for var in ("PYSR_SEED", "EXPERIMENT_SEED", "NN_SEED"):
        v = os.environ.get(var, "").strip()
        if v:
            try:
                return int(v)
            except ValueError:
                pass
    return None   # sentinel → caller uses _args.seed (argparse default)


def _resolve_results_dir(repo_results_dir: pathlib.Path) -> pathlib.Path:
    """Return the output directory, preferring RESULTS_DIR env var.

    [FIX-4] CI sets RESULTS_DIR = OUT_BASE = hypatiax/data/results (absolute
    path inside the runner workspace).  Using it here keeps JSON output in the
    same tree the artifact upload step expects.  Falls back to the repo-local
    path for local runs where RESULTS_DIR is not set.
    """
    env_dir = os.environ.get("RESULTS_DIR", "").strip()
    if env_dir:
        return pathlib.Path(env_dir)
    return repo_results_dir
# ─────────────────────────────────────────────────────────────────────────────

# ── 1. Resolve repo root & set sys.path ───────────────────────────────────
# Script lives at:  <repo>/hypatiax/experiments/benchmarks/exp3_nguyen12_hybrid50v_02.py
# Repo root is 4 levels up (parents[3]):
#   parents[0] = benchmarks/
#   parents[1] = experiments/
#   parents[2] = hypatiax/      <- was incorrectly used as repo root
#   parents[3] = <repo>/        <- correct repo root
# [BUG-ROOT-FIX] parents[2] pointed at hypatiax/ not the repo root, so
# _REPRO_ROOT / "hypatiax" resolved to hypatiax/hypatiax/ (non-existent).
_SCRIPT_DIR = pathlib.Path(__file__).resolve().parent
_REPO_ROOT  = _SCRIPT_DIR.parents[3]   # benchmarks/ -> experiments/ -> hypatiax/ -> repo root

# Support override via environment variable (set by pipeline or notebook)
_REPRO_ROOT = pathlib.Path(os.environ.get("REPRO_ROOT", str(_REPO_ROOT)))

# [FIX-2] sys.path setup — _apply_case_range intentionally NOT applied here.
# The two path strings are not a test-case sequence; slicing them could silently
# drop the repo-root entry and break all subsequent protocol imports.
for _p in [str(_REPRO_ROOT), str(_REPRO_ROOT / "hypatiax")]:
    if _p not in sys.path:
        sys.path.insert(0, _p)

# ── 2. Argument parsing (early — SEED needed before env setup) ────────────
def _parse_args():
    parser = argparse.ArgumentParser(
        description="Exp 3 · Nguyen-12 SR suite (§10.8 primary)"
    )
    parser.add_argument(
        "--seed", type=int, default=42,
        help="Random seed for all RNG sources (default: 42)"
    )
    return parser.parse_args()

# Parse early so SEED is available for the seed block below.
# (argparse is safe to call at module level — it only reads sys.argv)
_args = _parse_args()
SEED  = _resolve_seed() or int(os.environ.get("EXPERIMENT_SEED", str(_args.seed)))

# ── 3. [PATCH A] Unified seed block — ALL sources seeded from SEED ────────
random.seed(SEED)
np.random.seed(SEED)
os.environ["PYTHONHASHSEED"] = str(SEED)
os.environ["JULIA_SEED"]     = str(SEED)   # PySR / Julia RNG

# [FIX-SEGFAULT] juliacall MUST be imported before torch.
# torch imported first causes segfault — PyTorch signal handlers clobber Julia's.
# PYTHON_JULIACALL_HANDLE_SIGNALS=yes is already set in CI global env.
# See: https://github.com/pytorch/pytorch/issues/78829
os.environ.setdefault("PYTHON_JULIACALL_HANDLE_SIGNALS", "yes")
try:
    import juliacall  # noqa: F401  — must precede torch import
except ImportError:
    pass  # juliacall absent — PySR subprocess handles Julia init

try:
    import torch
    torch.manual_seed(SEED)
    torch.cuda.manual_seed_all(SEED)
    torch.backends.cudnn.deterministic = True
    torch.backends.cudnn.benchmark     = False
except ImportError:
    pass
print(f"✅ All seeds set to {SEED}")

# ── 4. Dependency check (no !pip magic — deps managed by pipeline) ─────────
_REQUIRED = ["pysr", "anthropic", "sklearn", "scipy", "sympy", "numpy", "pandas", "matplotlib"]
_MISSING  = []
for _pkg in _REQUIRED:
    try:
        importlib.import_module(_pkg)
    except ImportError:
        _MISSING.append(_pkg)

if _MISSING:
    print(f"  ✗  Missing packages: {', '.join(_MISSING)}")
    print("     Install via:  pip install " + " ".join(_MISSING))
    print("     Or run the full pipeline first (it installs deps in Phase 0).")
    sys.exit(1)

# ── 5. Clear stale protocol cache lock (mirrors notebook Cell 27) ──────────
_repo_results_dir = _REPRO_ROOT / "hypatiax" / "data" / "results"
_locks = list(_repo_results_dir.glob(".lock_*")) if _repo_results_dir.exists() else []
if _locks:
    for _l in _locks:
        _l.unlink()
    print(f"  Cleared {len(_locks)} stale lock(s) — experiment will run fresh")
else:
    print("  No stale locks found")

# ── 6. Environment variables (mirrors notebook Cell 2 / %env block) ────────
os.environ["NN_SEED"]   = str(SEED)   # always propagate resolved SEED
os.environ["PYSR_SEED"] = str(SEED)
os.environ.setdefault("LLM_MODEL",   "claude-sonnet-4-6")
os.environ.setdefault("LLM_RETRIES", "3")
os.environ.setdefault("LLM_K_RUNS",  "1")
os.environ.setdefault("ENGINE",      "hybrid_system_v50_2")
os.environ.setdefault("REPRO_ROOT",  str(_REPRO_ROOT))

# ── 7. [PATCH E] Pipeline-safe API key loader (replaces Colab userdata) ───
ANTHROPIC_API_KEY = os.environ.get("ANTHROPIC_API_KEY", "")

if not ANTHROPIC_API_KEY:
    # Try Colab userdata only if actually running inside Colab
    try:
        from google.colab import userdata as _colab_userdata
        ANTHROPIC_API_KEY = _colab_userdata.get("ANTHROPIC_API_KEY") or ""
    except (ImportError, Exception):
        pass

if not ANTHROPIC_API_KEY:
    # Try .env file relative to repo root
    for _env_path in [
        _REPRO_ROOT / ".env",
        _REPRO_ROOT / "hypatiax" / ".env",
    ]:
        if _env_path.exists():
            for _line in _env_path.read_text().splitlines():
                if _line.startswith("ANTHROPIC_API_KEY="):
                    ANTHROPIC_API_KEY = _line.split("=", 1)[1].strip().strip('"').strip("'")
                    break
        if ANTHROPIC_API_KEY:
            break

USE_LLM = True
if ANTHROPIC_API_KEY:
    os.environ["ANTHROPIC_API_KEY"] = ANTHROPIC_API_KEY
    print("API key set ✓")
else:
    print("⚠  No API key found — LLM guidance disabled (USE_LLM forced False)")
    USE_LLM = False

# ── 8. Main experiment logic ───────────────────────────────────────────────
def run(seed: int = 42):
    """Run the Nguyen-12 benchmark directly (no subprocess recursion)."""
    import json
    import time

    # [FIX-4] Resolve output directory from RESULTS_DIR env var when set so
    # JSON lands under the CI artifact-upload path (OUT_BASE), not the
    # repo-local path that diverges inside the GitHub Actions runner workspace.
    _results_dir = _resolve_results_dir(_repo_results_dir)
    _results_dir.mkdir(parents=True, exist_ok=True)

    # ── Skip if result already exists for this seed (avoids redundant ────
    # ── subprocess re-run triggered by run_task after direct execution)  ──
    _out_path = _results_dir / f"exp3_nguyen12_seed{seed}.json"
    _force_rerun = os.environ.get("FORCE_RERUN", "0").strip() == "1"
    if _out_path.exists() and not _force_rerun:
        print(f"  ✓ Results already exist for seed={seed}, skipping re-run.")
        print("    Set FORCE_RERUN=1 to intentionally overwrite this result.")
        with open(_out_path) as _f:
            return json.load(_f)

    # [FIX-CHECKPOINT] The old version of this script only ever wrote
    # exp3_nguyen12_seed{seed}.json ONCE, after the full 12-equation loop
    # finished (2 PySR fits/equation x up to METHOD_TIMEOUT=1100s each =
    # worst case ~440 min). That exceeds the CI worker's 330-min job
    # timeout, so if the runner is SIGKILLed mid-loop, NOTHING is ever
    # written -- not even the equations that had already finished --
    # because the write only happens after the loop. This is what produced
    # the "No exp3_nguyen12_seed*.json files found" failure with zero
    # output files on disk despite the job apparently running for hours.
    #
    # Fix: (1) write a checkpoint after every equation so completed work is
    # never lost, and (2) honour JOB_DEADLINE (already exported by
    # run_all.sh/CI but previously never read by this script) to stop
    # gracefully with a partial-but-valid JSON instead of being killed
    # mid-write.
    _start_time    = time.time()
    _job_deadline  = int(os.environ.get("JOB_DEADLINE", 0)) or None  # seconds; 0/unset = no cap
    _CKPT_PATH     = _results_dir / f"_exp3_seed{seed}_partial.json"

    def _save(results_hypatia, results_pysr, n_total, complete):
        h_recovered = sum(1 for r in results_hypatia if r["evaluation"]["r2"] >= 0.9999)
        p_recovered = sum(1 for r in results_pysr    if r["evaluation"]["r2"] >= 0.9999)
        paired = []
        for h, p in zip(results_hypatia, results_pysr):
            hr = float(h["evaluation"]["r2"]); pr = float(p["evaluation"]["r2"])
            paired.append({"nguyen_id": h["metadata"].get("nguyen_id"), "h_r2": hr, "p_r2": pr, "delta_r2_h_minus_p": hr-pr, "h_success": hr >= 0.9999, "p_success": pr >= 0.9999, "same_expression": h.get("expression")==p.get("expression"), "h_is_copy_of_p": bool(h.get("h_is_copy_of_p", False))})
        h_independent=[r for r in results_hypatia if not r.get("h_is_copy_of_p", False)]
        h_recovered_independent=sum(1 for r in h_independent if r["evaluation"]["r2"] >= 0.9999)
        try:
            import pysr as _pysr_mod
            _pysr_version=getattr(_pysr_mod,"__version__","unknown")
        except Exception:
            _pysr_version="unknown"
        payload = {
            "config": {"name":"nguyen12_exp3","script_version":"v04-trajectory-instrumented","seed":seed,"n_tasks":n_total,"niterations":_niter,"populations":_pops,"timeout":_timeout,"method_timeout":_method_timeout,"use_llm":USE_LLM,"deterministic":True,"parallelism":"serial","random_state":seed,"r2_threshold":0.9999,"pysr_version":_pysr_version,
                    "trajectory_monitor": True, "trajectory_unit": "outer_iteration",
                    "trajectory_poll_seconds": _trajectory_poll_seconds},
            "results": {"hypatiax": results_hypatia, "pysr": results_pysr},
            "paired_comparison": paired,
            "summary": {"h_recovered":h_recovered,"p_recovered":p_recovered,"h_recovered_independent":h_recovered_independent,"n_total":n_total,"h_rate":h_recovered/n_total if n_total else 0.0,"p_rate":p_recovered/n_total if n_total else 0.0,"n_completed":len(results_hypatia),"n_independent_h":len(h_independent),"n_h_copy_of_p":len(results_hypatia)-len(h_independent),"n_same_final_expression":sum(1 for x in paired if x["same_expression"]),"n_completed_with_guesses":sum(1 for r in results_hypatia if r.get("warm_start_status")=="used"),"n_engine_rejected_guesses":sum(1 for r in results_hypatia if r.get("warm_start_status")=="engine_rejected"),"complete":complete},
        }
        _target = _out_path if complete else _CKPT_PATH
        _tmp = _target.with_suffix(".json.tmp")
        with open(_tmp, "w") as _f:
            json.dump(payload, _f, indent=2, default=str)
        os.replace(_tmp, _target)  # atomic — never leaves a truncated file if killed mid-write
        return payload

    # ── Config from env vars (smoke-test / paper-quality modes) ──────────
    _n_tasks        = int(os.environ.get("N_NGUYEN_TASKS", 12))
    _niter          = int(os.environ.get("N_ITERATIONS",   1000))
    _pops           = int(os.environ.get("POPULATIONS",    30))
    # FIX-WALLCLOCK: use PYSR_TIMEOUT (1100s) not a hardcoded 360s default.
    # No cap — repro.yaml values are authoritative.
    _pysr_timeout   = int(os.environ.get("PYSR_TIMEOUT",   1100))
    _method_timeout = int(os.environ.get("METHOD_TIMEOUT", _pysr_timeout))
    _timeout        = _pysr_timeout   # passed to PySR's timeout_in_seconds
    _trajectory_poll_seconds = float(os.environ.get("PYSR_TRAJECTORY_POLL_SECONDS", "0.25"))

    print(f"\n{'='*68}")
    print(f"  Exp 3 · Nguyen-12 SR suite  (§10.8)  SEED={seed}")
    print("  Reference expectations are NOT used as observed results.")
    print(f"  Config  : n_tasks={_n_tasks}  niterations={_niter}  populations={_pops}"
          f"  pysr_timeout={_timeout}s  method_timeout={_method_timeout}s")
    print(f"{'='*68}\n")

    # ── Import protocol data layer ────────────────────────────────────────
    try:
        from hypatiax.protocols.experiment_protocol_nguyen12 import NguYenProtocol
    except ImportError:
        # [FIX-IMPORT] 'protocols' is a subpackage of hypatiax/, not standalone.
        # Re-insert repo root and retry with the full dotted path.
        import pathlib as _pl
        _root = str(_pl.Path(__file__).resolve().parents[3])
        if _root not in sys.path:
            sys.path.insert(0, _root)
        from hypatiax.protocols.experiment_protocol_nguyen12 import NguYenProtocol

    # ── Import SR engine ──────────────────────────────────────────────────
    from pysr import PySRRegressor
    from sklearn.metrics import r2_score

    # ── Import LLM warm-start ─────────────────────────────────────────────
    # hypatia.py must be committed to the repo at:
    #   hypatiax/experiments/benchmarks/hypatia.py   (next to this script)
    # [BUG-HYPATIA-FIX] Previously the import silently failed in CI because
    # hypatia.py was not committed to the repository. The bench_dir sys.path
    # insertion is correct, but the file must actually exist there.
    # We raise an explicit ImportError with a remediation message so the
    # failure is actionable rather than a cryptic ModuleNotFoundError.
    _bench_dir = pathlib.Path(__file__).resolve().parent
    _hypatia_path = _bench_dir / "hypatia.py"
    if not _hypatia_path.exists():
        raise ImportError(
            f"hypatia.py not found at {_hypatia_path}\n"
            "  Fix: commit hypatia.py to hypatiax/experiments/benchmarks/ in the repo.\n"
            "  The file provides get_llm_prior() for the LLM warm-start prior."
        )
    if str(_bench_dir) not in sys.path:
        sys.path.insert(0, str(_bench_dir))
    from hypatia import get_llm_prior

    # ── [FIX-GUESSES-SYNTAX] LLM expr → PySR operator syntax converter ─────
    # hypatia.py's get_llm_prior() returns plain Python/numpy expressions
    # (e.g. "x**3 + x**2", "np.sin(x) + x") per its own docstring and
    # _build_prompt() rules — see hypatia.py's OUTPUT FORMAT section, which
    # explicitly instructs the LLM to emit "**" for power and "np."-prefixed
    # calls (np.sin, np.cos, np.log, np.exp, np.sqrt, np.abs).
    #
    # exp3's PySR config (below, _pysr_kwargs) uses a DIFFERENT operator set:
    #     binary_operators = ["+", "-", "*", "/", "^"]   # power is "^", not "**"
    #     unary_operators  = ["sin", "cos", "log", "sqrt", "exp"]  # bare names,
    #                                                                no "np." prefix,
    #                                                                and no "abs" at all
    # Passing hypatia.py's raw strings straight into PySRRegressor(guesses=...)
    # hands PySR tokens it doesn't recognize (** is not a configured binary
    # operator; np.sin/np.abs are not configured unary operators, and "abs"
    # isn't in the allowed list under any spelling) — this was silently
    # breaking the warm-start instead of fixing it.
    #
    # This converter rewrites each candidate into exp3's actual operator
    # syntax, and DROPS any candidate that uses "abs" (no PySR equivalent
    # configured here) rather than passing something PySR will reject.
    _NP_FUNC_MAP = {
        "np.sin":  "sin",
        "np.cos":  "cos",
        "np.log":  "log",
        "np.exp":  "exp",
        "np.sqrt": "sqrt",
    }
    # The only unary function *names* PySR is configured to accept for this
    # experiment (must match _pysr_kwargs["unary_operators"] below).
    _ALLOWED_PYSR_FUNCS = {"sin", "cos", "log", "sqrt", "exp"}

    # [FIX-GUESSES-CRASH] Root cause of "H FAILED / r2=-inf, elapsed~0.0004s
    # on 100% of equations": the old converter only ever *blacklisted* the
    # literal substring "abs". Every other function the LLM might emit that
    # isn't one of the 5 mapped np.* names — e.g. "tan", "np.tan", "sinh",
    # "cosh", "np.pi", "min", "max", "floor" — passed straight through
    # unrecognized. PySR hands guess strings almost directly to Julia's
    # parser inside SymbolicRegression.equation_search(); an unparsable /
    # unregistered-operator token there raises immediately, before any
    # evolutionary search work happens — which is exactly the near-instant,
    # 100%-failure pattern seen in the JSON (a real search takes minutes).
    # A blacklist can only ever catch names we thought to list; the LLM's
    # output vocabulary is not fully controlled by us. So flip to a
    # WHITELIST: after conversion, an expression is only used as a guess if
    # every identifier in it is either a known variable name or one of the
    # 5 configured PySR functions above. Anything else is dropped, the same
    # way "abs" candidates already were, rather than risking another
    # engine-side crash we can't see (see also the traceback capture added
    # around model_h.fit() below, so if this *does* still happen we get an
    # actual error message next time instead of a silent FAILED).
    def _is_safe_pysr_guess(expr, var_names):
        if any(tok in expr.lower() for tok in ("nan", "inf", "infinity")):
            return False
        tokens = re.findall(r"[A-Za-z_][A-Za-z_0-9]*", expr)
        for tok in tokens:
            if tok in _ALLOWED_PYSR_FUNCS or tok in var_names:
                continue
            return False  # unknown function / constant / stray identifier
        # Defense in depth: overall charset must be numbers/operators/parens/
        # whitespace/identifier characters only — nothing else should ever
        # reach PySR as a guess string.
        return bool(re.fullmatch(r"[A-Za-z_0-9\.\+\-\*/\^\(\)\s,]*", expr))

    def _llm_exprs_to_pysr_guesses(exprs, var_names):
        """Convert hypatia.py's Python/numpy expression strings into PySR's
        configured operator syntax (`^` for power, bare unary function names),
        then drop anything that still doesn't match PySR's configured
        vocabulary (see [FIX-GUESSES-CRASH] above) instead of passing a
        candidate PySR/Julia can't parse.
        """
        converted = []
        for e in exprs:
            try:
                if "abs" in e:
                    continue  # no configured PySR operator for abs — drop
                out = e
                for np_name, pysr_name in _NP_FUNC_MAP.items():
                    out = out.replace(np_name, pysr_name)
                # "**" (Python power) -> "^" (PySR power). Do this after the
                # np.* replacements so we don't touch anything inside names.
                out = re.sub(r"\*\*", "^", out)
                if not _is_safe_pysr_guess(out, var_names):
                    continue  # unrecognized function/constant/token — drop
                converted.append(out)
            except Exception:
                continue  # skip anything that doesn't convert cleanly
        unique = []
        seen = set()
        for expr in converted:
            if expr not in seen:
                seen.add(expr)
                unique.append(expr)
        return unique
    # ─────────────────────────────────────────────────────────────────────

    # ── Load all 12 Nguyen equations ──────────────────────────────────────
    all_cases = NguYenProtocol.load_all(num_samples=200, noise_level=0.0, seed=seed)

    # [FIX-2/FIX-5] Apply filters in the correct order:
    #   1. _apply_task_ids_nguyen — shard/CI filter (TASK_IDS / SHARD_IDS)
    #   2. _apply_case_range      — positional slice (CASE_RANGE_START/END)
    #   3. [:_n_tasks]            — smoke-test ceiling (N_NGUYEN_TASKS)
    #
    # Old order was [:_n_tasks] first, then _apply_task_ids_nguyen, which
    # could silently exclude shard-assigned IDs that fell beyond the ceiling.
    # _apply_case_range was previously and incorrectly applied to the sys.path
    # list; it is now applied here to the actual test-case sequence.
    all_cases = _apply_task_ids_nguyen(all_cases)  # CI shard filter  (FIX-1 / FIX-3)
    all_cases = _apply_case_range(all_cases)        # positional slice (FIX-2)
    all_cases = all_cases[:_n_tasks]                # smoke-test cap   (FIX-5)

    results_hypatia = []
    results_pysr    = []

    for i, (desc, X, y, var_names, meta) in enumerate(all_cases):
        nid = meta["nguyen_id"]
        print(f"\n  [{i+1}/{len(all_cases)}] {nid} — {meta['ground_truth']}")

        # ── Build eq_dict for get_llm_prior ──────────────────────────────
        eq_dict = {
            "id":           nid,
            "vars":         var_names,
            "formula_hint": meta["formula_hint"],
            "formula":      meta["ground_truth"],
        }

        # ── LLM warm-start candidates ─────────────────────────────────────
        # [FIX-LLM-DIAGNOSTICS] Track *why* warm-start did or didn't fire,
        # not just whether it did — a bare bool can't distinguish "LLM
        # disabled" from "LLM call raised" from "LLM returned 0 candidates"
        # from "candidates returned but all dropped by the syntax filter".
        # Each of those needs a different fix if it turns out to dominate a
        # rerun, so the status has to survive into the JSON, not just stdout.
        llm_exprs = []
        _llm_call_raised = False
        if USE_LLM:
            try:
                llm_exprs = get_llm_prior(
                    eq_dict, X, y,
                    n_candidates=8,
                    verbose=False,
                )
                print(f"    LLM candidates: {llm_exprs[:3]} ...")
            except Exception as _e:
                _llm_call_raised = True
                print(f"    ⚠  LLM warm-start failed: {_e} — running PySR-only")

        # ── Shared PySR config ────────────────────────────────────────────
        _pysr_kwargs = dict(
            niterations=_niter,
            populations=_pops,
            timeout_in_seconds=_timeout,
            random_state=seed,
            deterministic=True,
            parallelism="serial",
            verbosity=0,
            progress=False,
            # Keep the hall-of-fame checkpoint in a persistent, known output
            # tree.  The trajectory monitor polls this file while Julia searches.
            # Using the persistent run directory also leaves the CSV available
            # for CI artifact inspection after the fit.
            temp_equation_file=False,
            output_directory=str(_results_dir / "_pysr_trajectory_runs"),
            binary_operators=["+", "-", "*", "/", "^"],
            unary_operators=["sin", "cos", "log", "sqrt", "exp"],
        )

        # [FIX-HYPATIAX-WARMSTART] llm_exprs is converted to PySR's operator
        # syntax and passed via PySRRegressor(guesses=...) — confirmed valid
        # for the pinned pysr==2.0.0a1 (guesses is a constructor parameter
        # in this version; type list[str] for single-output regression,
        # which every Nguyen-12 equation is).
        _pysr_guesses = _llm_exprs_to_pysr_guesses(llm_exprs, var_names) if llm_exprs else []
        if llm_exprs and not _pysr_guesses:
            print("    ⚠  All LLM candidates dropped by syntax/vocabulary filter — no warm-start this eq")

        # [FIX-DEGENERATE-WARMSTART] Residual risk this closes: whenever
        # _pysr_guesses is empty (LLM disabled, LLM call failed, LLM
        # returned nothing, or every candidate got dropped by the syntax
        # filter), model_h's kwargs become byte-identical to model_p's —
        # same random_state, deterministic=True, parallelism="serial", no
        # guesses on either side. Running both anyway just re-derives the
        # exact same deterministic search twice and silently reproduces the
        # original H≡P bug this whole audit started from, except now it
        # LOOKS like two independent runs that happened to agree instead of
        # one run copied into two slots.
        #
        # Fix: when there's nothing to differentiate the two arms, run PySR
        # ONCE and copy that single result into both the H and P records,
        # with an explicit flag on the H record marking it as a copy. This
        # is strictly more honest than re-running (the two runs are
        # PROVABLY identical under this config, not coincidentally so) and
        # cuts wall-clock time for every equation where warm-start didn't
        # fire, instead of paying for a second guaranteed-identical search.
        if _pysr_guesses:
            _warm_start_status = "used"
        elif not USE_LLM:
            _warm_start_status = "llm_disabled"
        elif _llm_call_raised:
            _warm_start_status = "llm_call_failed"
        elif not llm_exprs:
            _warm_start_status = "no_candidates_returned"
        else:
            _warm_start_status = "all_candidates_filtered"

        _llm_candidates_raw = len(llm_exprs)
        _llm_candidates_used_after_syntax_filter = len(_pysr_guesses)

        # [FIX-TRAJECTORY-RUN-ID] Give every PySR fit its own persistent run
        # directory so H/P (and H cold-fallback) cannot overwrite one another.
        _trajectory_run_counter = 0

        def _new_pysr_kwargs(arm):
            nonlocal _trajectory_run_counter
            _trajectory_run_counter += 1
            kw = dict(_pysr_kwargs)
            safe_nid = re.sub(r"[^A-Za-z0-9_.-]+", "_", str(nid))
            kw["run_id"] = (
                f"exp3_seed{seed}_{safe_nid}_{arm}_"
                f"{_trajectory_run_counter}_{int(time.time() * 1000)}"
            )
            return kw

        # [FIX-ERROR-DIAGNOSTICS] Both arms now capture the *full* traceback
        # (not just str(_e)) into _h_error/_h_traceback / _p_error, and store
        # it on the JSON record. Previously the except blocks only printed
        # str(_e), and that print went to stdout only — never into the JSON.
        # That's why a 100%-instant-FAILED run left literally no trace of
        # *why* in the output file (see audit note): the real exception was
        # thrown away the moment it was caught.
        _h_error = None
        _h_traceback = None
        _guesses_rejected_by_engine = False
        trajectory_h = []
        trajectory_p = []
        # [FIX-UNBOUND-FIT-DIAG] Both are read unconditionally below via
        # `.get(...)` when building results_hypatia (hof_path,
        # hof_exists_at_end, hof_archive_path, etc.). They were previously
        # only ever assigned inside the try blocks below, so any path that
        # never reaches _fit_with_pysr_trajectory() -- the no-warm-start
        # branch (only ever sets _fit_diag_p, never _fit_diag_h), or a
        # PySRRegressor(**kwargs) constructor itself raising before that
        # call -- left _fit_diag_h/_fit_diag_p unbound, crashing with
        # UnboundLocalError instead of recording a failed/empty diagnostic.
        # Confirmed against a real run: USE_LLM=False takes the `elif not
        # USE_LLM` branch, which only sets _fit_diag_p, so building
        # results_hypatia's "hof_path": _fit_diag_h.get(...) crashed every
        # time LLM warm-start was disabled -- exactly the smoke test's
        # default configuration.
        _fit_diag_h = {}
        _fit_diag_p = {}

        if _pysr_guesses:
            # ── HypatiaX run (PySR + LLM warm-start) — genuinely differs
            # from PySR-only, so both arms are run independently. ──────────
            t0 = time.time()
            try:
                model_h = PySRRegressor(
                    **_new_pysr_kwargs("H"),
                    guesses=_pysr_guesses,
                    warm_start=False,
                )
                trajectory_h, _fit_diag_h = _fit_with_pysr_trajectory(model_h, X, y, var_names, "H", poll_seconds=_trajectory_poll_seconds, seed=seed, nguyen_id=nid, archive_dir=_results_dir / "hall_of_fame_archives")
                if _fit_diag_h["error"] is not None:
                    raise RuntimeError(_fit_diag_h["error"])
                y_pred_h    = model_h.predict(X)
                r2_h        = float(r2_score(y, y_pred_h))
                best_expr_h = str(model_h.sympy())
            except Exception as _e:
                _h_error     = str(_e)
                _h_traceback = traceback.format_exc()
                print(f"    ✗ HypatiaX run with guesses failed: {_e}")
                print(_h_traceback)
                # [FIX-GUESSES-CRASH] Don't let a bad warm-start string sink
                # the whole equation's H result. Retry once, PySR-only
                # (no guesses), so H still reflects a genuine, independent
                # PySR search rather than recording "FAILED"/-inf whenever
                # the guesses filter (or the LLM/converter) let something
                # through that PySR/Julia couldn't parse.
                _guesses_rejected_by_engine = True
                _warm_start_status = "engine_rejected"
                print("    ↻ Retrying HypatiaX without guesses (engine rejected the warm-start candidates)")
                try:
                    model_h = PySRRegressor(**_new_pysr_kwargs("Hcold"))
                    trajectory_h, _fit_diag_h = _fit_with_pysr_trajectory(model_h, X, y, var_names, "H-cold-fallback", poll_seconds=_trajectory_poll_seconds, seed=seed, nguyen_id=nid, archive_dir=_results_dir / "hall_of_fame_archives")
                    if _fit_diag_h["error"] is not None:
                        raise RuntimeError(_fit_diag_h["error"])
                    y_pred_h    = model_h.predict(X)
                    r2_h        = float(r2_score(y, y_pred_h))
                    best_expr_h = str(model_h.sympy())
                except Exception as _e2:
                    _h_traceback = _h_traceback + "\n--- retry without guesses also failed ---\n" + traceback.format_exc()
                    _h_error     = f"{_h_error} | retry_without_guesses: {_e2}"
                    print(f"    ✗ HypatiaX retry (no guesses) also failed: {_e2}")
                    r2_h        = float("-inf")
                    best_expr_h = "FAILED"
            elapsed_h = time.time() - t0

            # ── PySR-only run (no LLM) ────────────────────────────────────
            _p_error = None
            t0 = time.time()
            try:
                model_p     = PySRRegressor(**_new_pysr_kwargs("P"))
                trajectory_p, _fit_diag_p = _fit_with_pysr_trajectory(model_p, X, y, var_names, "P", poll_seconds=_trajectory_poll_seconds, seed=seed, nguyen_id=nid, archive_dir=_results_dir / "hall_of_fame_archives")
                if _fit_diag_p["error"] is not None:
                    raise RuntimeError(_fit_diag_p["error"])
                y_pred_p    = model_p.predict(X)
                r2_p        = float(r2_score(y, y_pred_p))
                best_expr_p = str(model_p.sympy())
            except Exception as _e:
                _p_error = str(_e)
                print(f"    ✗ PySR-only run failed: {_e}")
                print(traceback.format_exc())
                r2_p        = float("-inf")
                best_expr_p = "FAILED"
            elapsed_p = time.time() - t0
            _h_is_copy_of_p = False
        else:
            # ── No warm-start available: run PySR ONCE, copy into both. ───
            # (guesses is unset on both arms; _pysr_kwargs alone is
            # deterministic and identical either way — see comment above.)
            t0 = time.time()
            try:
                model_p     = PySRRegressor(**_new_pysr_kwargs("P"))
                trajectory_p, _fit_diag_p = _fit_with_pysr_trajectory(model_p, X, y, var_names, "P", poll_seconds=_trajectory_poll_seconds, seed=seed, nguyen_id=nid, archive_dir=_results_dir / "hall_of_fame_archives")
                if _fit_diag_p["error"] is not None:
                    raise RuntimeError(_fit_diag_p["error"])
                y_pred_p    = model_p.predict(X)
                r2_p        = float(r2_score(y, y_pred_p))
                best_expr_p = str(model_p.sympy())
            except Exception as _e:
                print(f"    ✗ PySR-only run failed: {_e}")
                r2_p        = float("-inf")
                best_expr_p = "FAILED"
            elapsed_p = time.time() - t0

            r2_h        = r2_p
            best_expr_h = best_expr_p
            elapsed_h   = elapsed_p
            trajectory_h = list(trajectory_p)
            _fit_diag_h  = dict(_fit_diag_p)
            _h_is_copy_of_p = True
            print(f"    ℹ  No warm-start ({_warm_start_status}) — H copied from P's single run, not re-derived")

        # ── Per-equation summary ──────────────────────────────────────────
        THRESH = 0.9999
        h_ok   = "✅" if r2_h >= THRESH else "✗"
        p_ok   = "✅" if r2_p >= THRESH else "✗"
        print(f"    H  {h_ok}  R²={r2_h:.7f}  expr={best_expr_h}  ({elapsed_h:.1f}s)")
        print(f"    P  {p_ok}  R²={r2_p:.7f}  expr={best_expr_p}  ({elapsed_p:.1f}s)")
        if _pysr_guesses and not _guesses_rejected_by_engine:
            print("    ↳ H/P same final expression:" , best_expr_h == best_expr_p, "(not evidence of identical trajectories)")

        results_hypatia.append({
            "system":     "hypatiax",
            "metadata":   meta,
            "expression": best_expr_h,
            "evaluation": {"r2": r2_h},
            "elapsed":    elapsed_h,
            # [FIX-HYPATIAX-WARMSTART] True only if a converted, PySR-syntax
            # candidate was actually passed via `guesses`.
            "llm_warm_start_used": bool(_pysr_guesses),
            # [FIX-DEGENERATE-WARMSTART] True whenever this record's
            # expression/R²/elapsed were copied directly from the P run
            # rather than derived from an independent PySR search. Any
            # table-generation code consuming this JSON MUST check this
            # flag before treating H and P as independent trials for that
            # equation (e.g. for the Mann-Whitney H>P comparison).
            "h_is_copy_of_p": _h_is_copy_of_p,
            # [FIX-LLM-DIAGNOSTICS] one of: "used", "llm_disabled",
            # "llm_call_failed", "no_candidates_returned",
            # "all_candidates_filtered". Explains _which_ of the several
            # possible reasons warm-start didn't fire, when it didn't.
            "warm_start_status": _warm_start_status,
            "effective_method": ("pysr_warm_start" if _warm_start_status == "used" and not _guesses_rejected_by_engine else "pysr_cold_fallback" if _guesses_rejected_by_engine else "pysr_cold_copy"),
            "llm_candidates_raw": _llm_candidates_raw,
            "llm_candidates_used_after_syntax_filter": _llm_candidates_used_after_syntax_filter,
            "llm_guesses_passed_to_pysr": list(_pysr_guesses),
            "h_error": _h_error,
            "h_traceback": _h_traceback,
            "hof_path": _fit_diag_h.get("hof_path"),
            "hof_exists_at_end": bool(_fit_diag_h.get("hof_exists_at_end", False)),
            "hof_exists_during_fit": bool(_fit_diag_h.get("hof_exists_during_fit", False)),
            "hof_candidates_checked": _fit_diag_h.get("hof_candidates_checked", []),
            "hof_archive_path": _fit_diag_h.get("hof_archive_path"),
            "hof_archive_error": _fit_diag_h.get("hof_archive_error"),
            "guesses_rejected_by_engine": bool(_guesses_rejected_by_engine),
            "same_final_expression_as_p": bool(best_expr_h == best_expr_p),
            "same_final_r2_as_p": bool(np.isclose(r2_h, r2_p, rtol=1e-10, atol=1e-12)),
            "delta_r2_h_minus_p": float(r2_h - r2_p),
            "independent_fit": bool(not _h_is_copy_of_p),
            "trajectory": trajectory_h,
            "trajectory_summary": _trajectory_summary(trajectory_h, y=y),
        })
        results_pysr.append({
            "system":     "pysr",
            "metadata":   meta,
            "expression": best_expr_p,
            "evaluation": {"r2": r2_p},
            "elapsed":    elapsed_p,
            "p_error": _p_error if "_p_error" in locals() else None,
            "hof_path": _fit_diag_p.get("hof_path") if "_fit_diag_p" in locals() else None,
            "hof_exists_at_end": bool(_fit_diag_p.get("hof_exists_at_end", False)) if "_fit_diag_p" in locals() else False,
            "hof_exists_during_fit": bool(_fit_diag_p.get("hof_exists_during_fit", False)) if "_fit_diag_p" in locals() else False,
            "hof_candidates_checked": _fit_diag_p.get("hof_candidates_checked", []) if "_fit_diag_p" in locals() else [],
            "hof_archive_path": _fit_diag_p.get("hof_archive_path") if "_fit_diag_p" in locals() else None,
            "hof_archive_error": _fit_diag_p.get("hof_archive_error") if "_fit_diag_p" in locals() else None,
            "random_state": seed,
            "deterministic": True,
            "parallelism": "serial",
            "trajectory": trajectory_p,
            "trajectory_summary": _trajectory_summary(trajectory_p, y=y),
        })

        # [FIX-CHECKPOINT-CALL] Save checkpoint after each equation ────────
        _save(results_hypatia, results_pysr, len(all_cases), complete=False)

        # ── Check JOB_DEADLINE and exit gracefully if running out of time ──
        if _job_deadline:
            elapsed = time.time() - _start_time
            if elapsed > _job_deadline * 0.9:  # exit at 90% of deadline
                print(f"\n⏰ Approaching job deadline ({elapsed:.0f}s/{_job_deadline}s)")
                print(f"   Saving partial results ({len(results_hypatia)}/{len(all_cases)} completed) and exiting gracefully...")
                break  # exit loop, save final checkpoint below

    # ── Aggregate summary ─────────────────────────────────────────────────
    THRESH      = 0.9999
    h_recovered = sum(1 for r in results_hypatia if r["evaluation"]["r2"] >= THRESH)
    p_recovered = sum(1 for r in results_pysr    if r["evaluation"]["r2"] >= THRESH)
    n           = len(all_cases)

    print(f"\n{'='*68}")
    print(f"  RESULTS  (strict R²≥{THRESH}, seed={seed})")
    print(f"  HypatiaX : {h_recovered}/{n}  ({100*h_recovered/n:.1f}%)")
    print(f"  PySR-only: {p_recovered}/{n}  ({100*p_recovered/n:.1f}%)")
    n_ind = sum(1 for r in results_hypatia if not r.get("h_is_copy_of_p", False))
    n_same = sum(1 for h, p in zip(results_hypatia, results_pysr) if h.get("expression") == p.get("expression"))
    print(f"  Independent H fits: {n_ind}/{n}")
    print(f"  H/P identical final expressions: {n_same}/{n}")
    print("  Reference expectation is not an observed result.")
    print(f"{'='*68}\n")

    # ── Save JSON output (final) ──────────────────────────────────────────
    # [FIX-4] _results_dir already resolved above via _resolve_results_dir().
    # [FIX-CHECKPOINT-CALL] Use _save() for final output too (complete=True).
    result = _save(results_hypatia, results_pysr, len(all_cases), complete=True)

    OUTPUT_JSON = str(_out_path)
    print("\n  Protocol returned: success")
    print(f"  JSON: {OUTPUT_JSON}")

    # Notebook download link (Colab/Jupyter only — skipped in CLI)
    try:
        _ipy = get_ipython()  # type: ignore[name-defined]
    except NameError:
        _ipy = None
    if _ipy is not None:
        import base64
        from IPython.display import HTML, display
        _jpath = pathlib.Path(OUTPUT_JSON)
        if _jpath.exists():
            _data = base64.b64encode(_jpath.read_bytes()).decode()
            display(HTML(
                '<div style="border:1px solid #ccc;border-radius:6px;padding:12px;background:#f9f9f9">'
                f'<b>⬇ Download experiment outputs</b><ul>'
                f'<li><a href="data:application/json;base64,{_data}" download="{_jpath.name}">'
                f'📄 JSON results</a> ({_jpath.stat().st_size / 1024:.1f} KB)</li>'
                '</ul></div>'
            ))

    return result


# ── 9. Entry point ─────────────────────────────────────────────────────────
if __name__ == "__main__":
    run(seed=SEED)
