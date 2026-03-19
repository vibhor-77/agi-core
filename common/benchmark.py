"""
Benchmark infrastructure for the Universal Learning Loop.

Provides:
- TeeWriter (stdout -> console + log file)
- ProgressTracker (live per-task streaming + scoreboard)
- Signal handling (Ctrl-C kills immediately)
- Presets (quick/default/contest)
- Output formatting and results saving
- Pipeline orchestration (train -> save culture -> eval)

Domain-specific scripts only need to provide tasks + the 4 interfaces
(or a DomainAdapter).
"""

from __future__ import annotations

import argparse
import json
import os
import platform
import signal
import statistics
import sys
import time
from contextlib import contextmanager
from dataclasses import dataclass
from datetime import datetime
from io import TextIOBase

from dataclasses import asdict as _asdict, fields as _dc_fields

from core.types import Task
from core.interfaces import Environment, Grammar, DriveSignal
from core.config import SearchConfig, SleepConfig, CurriculumConfig
from core.results import WakeResult
from core.learner import Learner
from core.memory import InMemoryStore
from common.metrics import extract_metrics, print_compounding_table, save_metrics_json, save_metrics_csv


def expand_program(prog, library_map=None) -> str:
    """Format a Program with learned entries expanded inline.

    learned_14 → learned_14=crop_half_top(crop_to_content)
    Recursive: if learned_14 contains learned_3, that gets expanded too.
    """
    if library_map is None:
        library_map = {}
    root = prog.root
    if root.startswith(("learned_", "promoted_")) and root in library_map:
        inner = expand_program(library_map[root], library_map)
        root = f"{prog.root}={inner}"
    if not prog.children:
        return root
    args = ", ".join(expand_program(c, library_map) for c in prog.children)
    return f"{root}({args})"


class _SafeEncoder(json.JSONEncoder):
    """JSON encoder that handles non-serializable objects gracefully.

    Converts dataclass instances to dicts and falls back to str() for
    anything else (e.g. domain-specific types like GameState).
    """
    def default(self, o):
        if hasattr(o, '__dataclass_fields__'):
            return _asdict(o)
        try:
            return super().default(o)
        except TypeError:
            return str(o)


def _safe_dumps(obj, **kwargs):
    """json.dumps with safe fallback for non-serializable objects."""
    return json.dumps(obj, cls=_SafeEncoder, **kwargs)


# =============================================================================
# Presets — the ONLY knob most users need
# =============================================================================

PRESETS = {
    # Quick: fast dev loop. 50 tasks, auto-derived search from 1M budget.
    # 50 tasks: 14/50 train (28%), 4/50 eval (8%), ~18s pipeline.
    # All 400: 94/400 train (23.5%), 30/400 eval (7.5%), ~2min pipeline.
    "quick": {
        "compute_cap": 1_000_000,
        "max_tasks": 50,
    },
    # Default: full dataset, auto-derived search from 3M budget.
    "default": {
        "compute_cap": 3_000_000,
    },
    # Contest: maximum accuracy. 50M budget auto-derives wide pools + beam.
    "contest": {
        "compute_cap": 50_000_000,
    },
}

DEFAULT_SEED = 42
DEFAULT_RUNS_DIR = "runs"


# =============================================================================
# Tee writer — duplicates stdout to both console and a log file
# =============================================================================

class TeeWriter(TextIOBase):
    """Write to both the original stdout and a log file simultaneously."""

    def __init__(self, log_path: str, original_stdout):
        super().__init__()
        self._original = original_stdout
        os.makedirs(os.path.dirname(log_path) or ".", exist_ok=True)
        self._log = open(log_path, "w", buffering=1)

    def write(self, s):
        self._original.write(s)
        self._log.write(s)
        return len(s)

    def flush(self):
        self._original.flush()
        self._log.flush()

    def close(self):
        self._log.close()

    @property
    def encoding(self):
        return self._original.encoding


# =============================================================================
# Formatting helpers
# =============================================================================

def hline(char="\u2500", width=72):
    print(char * width)


def fmt_duration(seconds: float) -> str:
    """Format seconds as '1h23m', '4m32s', or '12.3s'."""
    s = seconds
    if s >= 3600:
        return f"{int(s) // 3600}h{(int(s) % 3600) // 60:02d}m"
    if s >= 60:
        return f"{int(s) // 60}m{int(s) % 60:02d}s"
    return f"{s:.1f}s"


# =============================================================================
# Machine auto-detection
# =============================================================================

def detect_machine() -> dict:
    """Detect machine characteristics for metadata."""
    info = {
        "platform": platform.system(),
        "arch": platform.machine(),
        "cpu_count": os.cpu_count() or 1,
        "performance_cores": Learner.performance_core_count(),
        "python": platform.python_version(),
    }
    if info["platform"] == "Darwin" and info["arch"] == "arm64":
        info["chip"] = "Apple Silicon"
    return info


# =============================================================================
# Signal handling — Ctrl-C kills the whole process tree immediately
# =============================================================================

_interrupted = False


def _handle_sigint(signum, frame):
    """First Ctrl-C raises KeyboardInterrupt. Second force-kills."""
    global _interrupted
    if _interrupted:
        os.kill(os.getpid(), signal.SIGKILL)
    _interrupted = True
    raise KeyboardInterrupt


def install_signal_handler():
    """Install the Ctrl-C signal handler. Call this early in main()."""
    signal.signal(signal.SIGINT, _handle_sigint)


# =============================================================================
# Human-readable number parsing
# =============================================================================

def parse_human_int(s: str) -> int:
    """Parse a human-readable integer with optional suffix or commas.

    Examples: "50M" -> 50_000_000, "500K" -> 500_000, "8,000,000" -> 8_000_000
    """
    s = s.strip().replace(",", "").replace("_", "")
    if not s:
        raise argparse.ArgumentTypeError("empty value")

    suffixes = {"k": 1_000, "m": 1_000_000, "b": 1_000_000_000, "t": 1_000_000_000_000}
    last = s[-1].lower()
    if last in suffixes:
        try:
            return int(float(s[:-1]) * suffixes[last])
        except ValueError:
            raise argparse.ArgumentTypeError(
                f"invalid number: {s!r}. Examples: 50M, 8,000,000, 500K, 0")

    try:
        return int(float(s))
    except ValueError:
        raise argparse.ArgumentTypeError(
            f"invalid number: {s!r}. Examples: 50M, 8,000,000, 500K, 0")


# =============================================================================
# Standard argument parser (reusable by any domain)
# =============================================================================

def make_parser(description: str, domain_name: str = "experiment") -> argparse.ArgumentParser:
    """Create a standard argument parser with presets + common flags."""
    perf_cores = Learner.performance_core_count()

    parser = argparse.ArgumentParser(
        description=description,
        formatter_class=argparse.ArgumentDefaultsHelpFormatter,
        epilog=f"""
Presets (the only knob most users need):
  quick     Fast dev loop (~25s, 50 tasks, 500K compute cap)
  default   Full dataset (all tasks, 3M compute cap)
  contest   Maximum accuracy (all tasks, 50M compute cap)

All search parameters (beam width, pair/triple pool sizes, rounds) are
auto-derived from the compute budget. Use --exhaustive-pair-top-k or
--exhaustive-triple-top-k to override specific values.

Compute cap examples:
  --compute-cap 50M          # 50 million (cell-normalized per task)
  --compute-cap 500K         # 500 thousand
  --compute-cap 0            # unlimited (no cap)

Examples:
  python -m experiments.{domain_name}                    # sensible defaults
  python -m experiments.{domain_name} --mode quick       # fast iteration
  python -m experiments.{domain_name} --mode contest     # full benchmark
""",
    )
    parser.add_argument("--mode", type=str, default="default",
                        choices=list(PRESETS.keys()), help="Preset configuration")
    parser.add_argument("--max-tasks", type=int, default=None,
                        help="Limit number of tasks (0 = all, default: from preset)")
    parser.add_argument("--rounds", type=int, default=None,
                        help="Wake-sleep rounds (auto-derived from compute budget if not set)")
    parser.add_argument("--workers", type=int, default=0,
                        help=f"Parallel workers (0 = performance cores = {perf_cores})")
    parser.add_argument("--seed", type=int, default=DEFAULT_SEED,
                        help="Random seed for reproducibility")
    parser.add_argument("--compute-cap", type=parse_human_int,
                        default=str(0),
                        help="Override preset compute cap (0=use preset default). Accepts: 50M, 500K, 0")
    parser.add_argument("--runs-dir", type=str, default=DEFAULT_RUNS_DIR,
                        help="Directory for all run artifacts")
    parser.add_argument("--no-log", action="store_true",
                        help="Disable log file (console only)")
    parser.add_argument("--batch", action="store_true",
                        help="Batch mode: skip visualization and per-task console output "
                             "(for hyperparameter sweeps). Data files still saved.")
    parser.add_argument("--exhaustive-depth", type=int, default=3,
                        help="Exhaustive enumeration depth (0=disabled, 2=pairs, 3=triples)")
    parser.add_argument("--exhaustive-pair-top-k", type=int, default=None,
                        help="Top-K singles for pair exhaustion (auto-derived from compute cap)")
    parser.add_argument("--exhaustive-triple-top-k", type=int, default=None,
                        help="Top-K singles for triple exhaustion (auto-derived from compute cap)")
    parser.add_argument("--sequential-compounding", action="store_true",
                        help="Process tasks sequentially with immediate concept promotion")
    parser.add_argument("--culture", type=str, default="",
                        help="Path to culture file to load (cross-run knowledge transfer)")
    parser.add_argument("--save-culture", type=str, default="",
                        help="Override auto culture save path (e.g. culture_train.json)")
    parser.add_argument("--task-ids", type=str, default="",
                        help="Comma-separated task IDs to run (e.g. '0dfd9992,1190e5a7'). "
                             "Overrides --max-tasks. Prefix match supported.")
    return parser


# =============================================================================
# Live progress tracker with scoreboard
# =============================================================================

class ProgressTracker:
    """Live progress tracker with rolling scoreboard.

    Streams per-task results to console + JSONL file. Prints a rolling
    scoreboard summary every N tasks.
    """

    SCOREBOARD_INTERVAL = 10

    def __init__(self, jsonl_path: str, t0: float, split_label: str = "",
                 library_map: dict = None, round_offset: int = 0,
                 quiet: bool = False):
        self._file = open(jsonl_path, "w")
        self._t0 = t0
        self._split_label = split_label  # e.g. "TRAIN" or "EVAL"
        self.library_map = library_map or {}  # name → Program for expansion
        self._round_offset = round_offset  # pipeline round offset
        self._quiet = quiet  # batch mode: suppress per-task console output

        # Cumulative (across all rounds)
        self.done = 0
        self.solved = 0
        self.overfit = 0
        self.total_evals = 0
        self.total_gens = 0
        self.scores: list[float] = []
        self.times: list[float] = []
        self.all_records: list[dict] = []

        # Per-round tracking (reset each round)
        self._current_round = -1
        self._round_done = 0
        self._round_solved = 0
        self._round_overfit = 0

    def on_task_done(
        self, round_num: int, task_index: int, total_tasks: int, wr: WakeResult,
    ) -> None:
        """Called after each task completes. Streams live output."""
        round_num = round_num + self._round_offset  # pipeline round
        # Reset per-round counters on new round
        if round_num != self._current_round:
            self._current_round = round_num
            self._round_done = 0
            self._round_solved = 0
            self._round_overfit = 0

        self.done += 1
        self._round_done += 1
        if wr.solved:  # test-verified (falls back to train when no test data)
            self.solved += 1
            self._round_solved += 1
        elif wr.train_solved and wr.test_solved is False:
            self.overfit += 1
            self._round_overfit += 1
        self.total_evals += wr.evaluations
        self.total_gens += wr.generations_used
        if wr.best:
            self.scores.append(wr.best.energy)
        self.times.append(wr.wall_time)

        elapsed = time.time() - self._t0

        # Per-task console output (suppressed in batch/quiet mode)
        if not self._quiet:
            icon = "\u2713" if wr.solved else "\u2717"
            energy_str = f"{wr.best.energy:.4f}" if wr.best else "    N/A"
            program_str = expand_program(wr.best.program, self.library_map) if wr.best else ""

            # Overfit tag: matched training but failed test
            overfit_tag = ""
            if wr.train_solved and wr.test_solved is False:
                overfit_tag = " [overfit]"

            slow_tag = ""
            if len(self.times) >= 5:
                med = statistics.median(self.times)
                if wr.wall_time > med * 10:
                    slow_tag = "  *** SLOW ***"

            split_tag = f" {self._split_label}" if self._split_label else ""
            print(
                f"  {icon}{split_tag} R{round_num} [{task_index:>3}/{total_tasks}] "
                f"{wr.task_id:<20s} "
                f"E={energy_str}  gens={wr.generations_used:<4d} "
                f"evals={wr.evaluations:<6d} {wr.wall_time:.1f}s"
                f"{overfit_tag}{slow_tag}",
                flush=True,
            )
            if wr.solved and program_str:
                print(f"       program: {program_str}")
            overfit_str = f"  overfit={self._round_overfit}" if self._round_overfit else ""
            print(
                f"       R{round_num}: solved={self._round_solved}/{self._round_done}"
                f"{overfit_str}  "
                f"evals={self.total_evals:,}  "
                f"[{fmt_duration(elapsed)} elapsed]",
            )

        record = {
            "round": round_num,
            "task_index": task_index,
            "task_id": wr.task_id,
            "solved": wr.solved,           # test-verified (the real metric)
            "train_solved": wr.train_solved,
            "test_solved": wr.test_solved,
            "test_error": round(wr.test_error, 6) if wr.test_error is not None else None,
            "energy": wr.best.energy if wr.best else None,
            "_program_obj": wr.best.program if wr.best else None,  # for re-expansion
            "prediction_error": wr.best.prediction_error if wr.best else None,
            "generations": wr.generations_used,
            "evaluations": wr.evaluations,
            "wall_time": round(wr.wall_time, 3),
            "program": expand_program(wr.best.program, self.library_map) if wr.best else None,
            "n_train_perfect": wr.n_train_perfect,
            "solving_rank": wr.solving_rank,
            "elapsed": round(elapsed, 1),
            "train_predictions": wr.train_predictions,
            "test_predictions": wr.test_predictions,
        }
        # Include learned rule descriptions if available
        # (populated during wake phase execution)
        try:
            from domains.arc.primitives import _PRIM_RULES
            if _PRIM_RULES:
                prog_name = record.get("program", "")
                if prog_name:
                    root = prog_name.split("(")[0] if "(" in prog_name else prog_name
                    rule_desc = _PRIM_RULES.get(prog_name) or _PRIM_RULES.get(root)
                    if rule_desc:
                        record["learned_rules"] = rule_desc
        except ImportError:
            pass
        self.all_records.append(record)

        # Exclude predictions from JSONL (large grids bloat streaming output)
        jsonl_record = {k: v for k, v in record.items()
                        if k not in ("train_predictions", "test_predictions", "_program_obj")}
        self._file.write(json.dumps(jsonl_record) + "\n")
        self._file.flush()

        if self.done % self.SCOREBOARD_INTERVAL == 0:
            self._print_scoreboard(round_num, total_tasks, elapsed)

    def _print_scoreboard(
        self, round_num: int, total_tasks: int, elapsed: float,
    ) -> None:
        rate = self.done / max(elapsed, 0.001)
        pending = total_tasks - (self.done % total_tasks or total_tasks)
        eta = pending / rate if rate > 0 else 0
        mean_energy = statistics.mean(self.scores) if self.scores else float("inf")
        med_time = statistics.median(self.times) if self.times else 0

        print()
        print(
            f"  \u250c\u2500\u2500 Progress: {self.done} tasks  "
            f"{fmt_duration(elapsed)} elapsed  "
            f"ETA {fmt_duration(eta)}  "
            f"{rate:.1f} tasks/s \u2500\u2500"
        )
        overfit_str = (f"  ~ overfit={self._round_overfit}"
                       if self._round_overfit else "")
        unsolved = self._round_done - self._round_solved - self._round_overfit
        print(
            f"  \u2502  R{round_num}: \u2713 solved={self._round_solved}/{self._round_done}  "
            f"\u2717 unsolved={unsolved}/{self._round_done}"
            f"{overfit_str}"
        )
        print(
            f"  \u2502  Energy: mean={mean_energy:.4f}  "
            f"Time: median={med_time:.1f}s  "
            f"Evals: {self.total_evals:,}"
        )
        if len(self.all_records) >= 5:
            by_time = sorted(self.all_records, key=lambda r: -r["wall_time"])
            top3 = by_time[:3]
            slowest_str = "  ".join(
                f"{r['task_id'][:8]}({r['wall_time']:.1f}s)" for r in top3
            )
            print(f"  \u2502  Slowest: {slowest_str}")
        print(f"  \u2514{'\u2500' * 60}")
        print()

    def close(self):
        self._file.close()


# =============================================================================
# The generic experiment runner
# =============================================================================

@dataclass
class ExperimentConfig:
    """Everything needed to run a domain-agnostic experiment."""
    title: str
    domain_tag: str  # short tag for output filenames, e.g. "arc", "symreg"
    tasks: list[Task]

    environment: Environment
    grammar: Grammar
    drive: DriveSignal

    # Search parameters (resolved from preset + overrides)
    rounds: int = 1
    pipeline_round: int = 0  # >0 when run as part of an interleaved pipeline
    workers: int = 0
    seed: int = DEFAULT_SEED
    compute_cap: int = 0

    # Search tuning
    energy_alpha: float = 1.0
    energy_beta: float = 0.001
    solve_threshold: float = 0.001

    # Exhaustive enumeration
    exhaustive_depth: int = 3
    exhaustive_pair_top_k: int = 40
    exhaustive_triple_top_k: int = 15

    # Beam search (contest mode enables these; quick/default use 1×1 = off)
    beam_width: int = 1
    max_generations: int = 1

    # Sequential compounding
    sequential_compounding: bool = False

    # Culture file (load pre-trained library)
    culture_path: str = ""
    save_culture: str = ""  # override auto-generated culture output path

    # Output
    runs_dir: str = DEFAULT_RUNS_DIR
    no_log: bool = False
    batch: bool = False  # batch mode: skip viz + per-task console output
    mode: str = "default"

    # Task filtering
    task_ids: str = ""  # comma-separated task IDs (prefix match supported)

    # Shared timestamp (for pipeline mode — reuse across train+eval)
    timestamp: str = ""

    # Suppress result/metric file output (for pipeline mode where the
    # pipeline script writes its own combined output files)
    suppress_files: bool = False

    # Split label for progress output (e.g. "TRAIN", "EVAL").
    # When set, used directly instead of parsing the title string.
    split_label: str = ""

    # Default cell size for compute cap normalization.
    # 800 = median ARC grid size. Other domains can override.
    default_cell_size: int = 800

    # Sleep phase: per-example solve score exponent (None = use SleepConfig default)
    example_solve_exponent: float = None


def resolve_from_preset(args, preset: dict, n_prims: int = 48,
                        base_cell_size: int = 800) -> dict:
    """Resolve: compute_cap → auto-derive all search params. CLI overrides win."""
    from core.config import derive_search_params, derive_rounds

    preset_cap = preset.get("compute_cap", 0)
    args_cap = getattr(args, "compute_cap", 0)
    compute_cap = args_cap if args_cap > 0 else preset_cap

    eval_budget = max(compute_cap // base_cell_size, 500) if compute_cap > 0 else 0
    derived = derive_search_params(eval_budget, n_prims)

    # CLI overrides (None = not explicitly set by user)
    if getattr(args, "exhaustive_pair_top_k", None) is not None:
        derived["exhaustive_pair_top_k"] = args.exhaustive_pair_top_k
    if getattr(args, "exhaustive_triple_top_k", None) is not None:
        derived["exhaustive_triple_top_k"] = args.exhaustive_triple_top_k

    return {
        "rounds": args.rounds if args.rounds is not None else derive_rounds(compute_cap),
        "max_tasks": args.max_tasks if args.max_tasks is not None else preset.get("max_tasks", 0),
        "workers": args.workers if args.workers > 0 else Learner.performance_core_count(),
        "compute_cap": compute_cap,
        **derived,
    }


@dataclass
class ExperimentResult:
    """Result returned by run_experiment for pipeline chaining."""
    culture_path: str
    results_path: str
    jsonl_path: str
    results_data: dict  # the full results dict (meta + summary + tasks + library)


def _ensure_deterministic_hashing():
    """Ensure PYTHONHASHSEED=0 for reproducible results.

    Python randomizes string hashing by default (PYTHONHASHSEED=random),
    which makes dict/set iteration order non-deterministic for string keys.
    This causes beam search results to vary between runs even with the
    same seed, because semantic dedup and program ranking depend on
    dict ordering when energies are tied.
    """
    if os.environ.get("PYTHONHASHSEED") != "0":
        import subprocess
        env = os.environ.copy()
        env["PYTHONHASHSEED"] = "0"
        # Must restart the process for PYTHONHASHSEED to take effect
        # (it's read at interpreter startup, so mid-process changes don't help).
        # Relaunch using -m with the module name derived from the script path,
        # since the original -m context is lost in sys.argv.
        print("  Re-launching with PYTHONHASHSEED=0 for reproducibility...")
        script = sys.argv[0]
        cwd = os.getcwd()
        # Convert absolute script path to module name (relative to CWD)
        if os.path.isabs(script):
            script = os.path.relpath(script, cwd)
        module = script.replace(".py", "").replace(os.sep, ".")
        result = subprocess.run(
            [sys.executable, "-m", module] + sys.argv[1:], env=env
        )
        sys.exit(result.returncode)


def run_experiment(cfg: ExperimentConfig) -> ExperimentResult:
    """Run a complete wake-sleep experiment on any domain.

    Returns an ExperimentResult with culture path, results path, and data.

    This is the top-level entry point. It:
    1. Sets up output files (log, jsonl, json, metrics, library)
    2. Tees stdout to log file
    3. Creates the Learner with the domain's 4 interfaces
    4. Runs the curriculum with live progress tracking
    5. Prints final results and saves all artifacts
    """
    _ensure_deterministic_hashing()
    install_signal_handler()

    run_timestamp = cfg.timestamp or datetime.now().strftime("%Y%m%d_%H%M%S")
    prefix = f"{cfg.domain_tag}_{run_timestamp}"

    runs_dir = cfg.runs_dir
    os.makedirs(runs_dir, exist_ok=True)

    log_path = os.path.join(runs_dir, f"{prefix}.log")
    jsonl_path = os.path.join(runs_dir, f"{prefix}.jsonl")
    results_path = os.path.join(runs_dir, f"{prefix}.json")
    metrics_json_path = os.path.join(runs_dir, f"{prefix}_metrics.json")
    metrics_csv_path = os.path.join(runs_dir, f"{prefix}_metrics.csv")

    culture_path = (cfg.save_culture if cfg.save_culture
                     else os.path.join(runs_dir, f"{prefix}_culture.json"))
    # Culture JSONL defaults to alongside culture JSON, but can be
    # overridden by pipeline runner to share a single file across rounds
    culture_jsonl_path = getattr(cfg, '_culture_jsonl_path', None)
    if culture_jsonl_path is None:
        culture_jsonl_path = culture_path.replace(".json", ".jsonl")

    tee = None
    # Batch mode auto-suppresses log file (no verbose console output to tee)
    if not cfg.no_log and not cfg.batch and not cfg.suppress_files:
        tee = TeeWriter(log_path, sys.stdout)
        sys.stdout = tee

    results_data = {}
    try:
        results_data = _run_experiment(cfg, run_timestamp, log_path, jsonl_path,
                                       results_path,
                                       metrics_json_path, metrics_csv_path,
                                       culture_path, culture_jsonl_path)
    except KeyboardInterrupt:
        print("\n\nAborted by user \u2014 partial results above.\n")
        raise  # propagate so pipeline mode stops too
    finally:
        if tee:
            sys.stdout = tee._original
            tee.close()

    return ExperimentResult(
        culture_path=culture_path,
        results_path=results_path,
        jsonl_path=jsonl_path,
        results_data=results_data,
    )


def _run_experiment(cfg, run_timestamp, log_path, jsonl_path, results_path,
                    metrics_json_path, metrics_csv_path, culture_path,
                    culture_jsonl_path=None):
    """Core run logic, separated so tee cleanup always happens."""
    machine = detect_machine()
    workers = cfg.workers if cfg.workers > 0 else Learner.performance_core_count()
    rounds = cfg.rounds
    tasks = cfg.tasks
    compute_cap = cfg.compute_cap

    # Filter by task IDs if specified (prefix match)
    if cfg.task_ids:
        id_prefixes = [t.strip() for t in cfg.task_ids.split(",") if t.strip()]
        tasks = [t for t in tasks
                 if any(t.task_id.startswith(p) for p in id_prefixes)]
        if not tasks:
            print(f"  ERROR: No tasks matched --task-ids '{cfg.task_ids}'")
            sys.exit(1)

    # --- Header ---
    in_pipeline = cfg.pipeline_round > 0
    if cfg.batch:
        # Batch mode: minimal one-line header
        cap_str = f"{compute_cap:,}" if compute_cap > 0 else "unlimited"
        print(f"  [batch] {cfg.title}  tasks={len(tasks)}  cap={cap_str}  "
              f"depth={cfg.exhaustive_depth}", flush=True)
    else:
        hline("\u2550")
        print(f"  {cfg.title}")
        print(f"  {datetime.now().strftime('%Y-%m-%d %H:%M:%S')}")
        hline("\u2550")

        print(f"\n  Mode:       {cfg.mode}")
        print(f"  Primitives: {len(cfg.grammar.base_primitives())}")
        if not in_pipeline:
            print(f"  Rounds:     {rounds}")
        print(f"  Workers:    {workers} / {machine['cpu_count']} cores "
              f"({machine.get('chip', machine['arch'])})")
        print(f"  Seed:       {cfg.seed}")
        if compute_cap > 0:
            print(f"  Compute cap: {compute_cap:,} ops (cell-normalized)")
        else:
            print(f"  Compute cap: unlimited")
        print(f"  Exhaustive: depth={cfg.exhaustive_depth}, "
              f"pair_top_k={cfg.exhaustive_pair_top_k}, "
              f"triple_top_k={cfg.exhaustive_triple_top_k}")
        if cfg.sequential_compounding:
            print(f"  Sequential compounding: ON")

        print()
        hline("\u2500")
        print("  Output files (available now for tail -f):")
        hline("\u2500")
        print(f"  Results (live):   {jsonl_path}")
        if not cfg.suppress_files:
            print(f"  Results (final):  {results_path}")
            print(f"  Metrics:          {metrics_json_path}")
            if not cfg.no_log and not cfg.batch:
                print(f"  Console log:      {log_path}")
        print()

    if not tasks:
        print("  ERROR: No tasks loaded.")
        sys.exit(1)

    # --- Create Learner ---
    _sleep_defaults = SleepConfig()
    memory = InMemoryStore(
        capacity=_sleep_defaults.max_library_size,
        reuse_bonus=_sleep_defaults.reuse_bonus,
    )

    evals_per_task = 1  # exhaustive enumeration only (no beam search)
    total_budget = evals_per_task * len(tasks) * rounds

    # Cell-normalized compute cap.
    # Instead of globally reducing max_gens, compute a per-task eval budget
    # proportional to grid size. Small grids get more evals (they're cheap),
    # large grids get fewer. Budget is enforced per-task in wake_on_task.
    #
    # Formula: min(max(compute_cap / avg_cells, 500), compute_cap / default_cell_size)
    #   default_cell_size comes from ExperimentConfig (800 for ARC, domain-specific).
    #   Floor of 500 evals ensures even huge grids get basic search.
    eval_budget = 0  # 0 = unlimited (passed per-task via SearchConfig)
    default_cell_size = cfg.default_cell_size
    if compute_cap > 0:
        # Per-task budget uses domain cell size as baseline
        max_evals = max(compute_cap // default_cell_size, 500)
        eval_budget = max_evals  # default for tasks without grid info
        if not cfg.batch:
            print(f"\n  Compute cap: {compute_cap:,} ops \u2192 ~{max_evals:,} evals/task (cell-normalized)")

    # Load culture file if specified (cross-run knowledge transfer)
    if cfg.culture_path and os.path.isfile(cfg.culture_path):
        memory.load_culture(cfg.culture_path)
        if not cfg.batch:
            print(f"\n  Culture loaded: {len(memory.get_library())} library entries, "
                  f"{len(memory.get_solutions())} solutions")

    sleep_cfg = SleepConfig()
    # Allow exponent override from config or environment
    if hasattr(cfg, 'example_solve_exponent') and cfg.example_solve_exponent is not None:
        sleep_cfg.example_solve_exponent = cfg.example_solve_exponent
    env_exp = os.environ.get("EXAMPLE_SOLVE_EXPONENT")
    if env_exp:
        sleep_cfg.example_solve_exponent = float(env_exp)

    learner = Learner(
        environment=cfg.environment,
        grammar=cfg.grammar,
        drive=cfg.drive,
        memory=memory,
        search_config=SearchConfig(
            beam_width=cfg.beam_width,
            max_generations=cfg.max_generations,
            energy_alpha=cfg.energy_alpha,
            energy_beta=cfg.energy_beta,
            solve_threshold=cfg.solve_threshold,
            seed=cfg.seed,
            exhaustive_depth=cfg.exhaustive_depth,
            exhaustive_pair_top_k=cfg.exhaustive_pair_top_k,
            exhaustive_triple_top_k=cfg.exhaustive_triple_top_k,
            eval_budget=eval_budget,
            verbose=not cfg.batch,
        ),
        sleep_config=sleep_cfg,
    )

    if not cfg.batch:
        print(f"\n  Tasks:      {len(tasks)}")
        print(f"  Primitives: {len(cfg.grammar.base_primitives())}")
        print(f"  Budget:     ~{evals_per_task:,} evals/task, ~{total_budget:,} total")

    # --- Run ---
    # Use explicit split_label if provided, else derive from title
    if cfg.split_label:
        _split = cfg.split_label
    else:
        _title_upper = cfg.title.upper()
        if "EVAL" in _title_upper:
            _split = "EVAL"
        elif "TRAIN" in _title_upper:
            _split = "TRAIN"
        else:
            _split = ""
    tracker = ProgressTracker(jsonl_path, time.time(), split_label=_split,
                              round_offset=cfg.pipeline_round - 1 if in_pipeline else 0,
                              quiet=cfg.batch)

    if not cfg.batch:
        hline("\u2500")
        if in_pipeline:
            print(f"  Running {len(tasks)} tasks on {workers} workers")
        else:
            print(f"  Running {len(tasks)} tasks \u00d7 {rounds} rounds on {workers} workers")
        hline("\u2500")
        print()

    # Culture JSONL: log learning events after each round (tail -f friendly)
    # Use append mode so pipeline rounds accumulate in one file
    _culture_jsonl_file = (open(culture_jsonl_path, "a")
                           if culture_jsonl_path else None)

    _round_offset = getattr(cfg, '_pipeline_round_offset', 0)
    _round_results_so_far: list = []

    def _on_round_done(round_num, round_result, memory):
        """Print cumulative compounding table + write culture snapshot."""
        _round_results_so_far.append(round_result)

        # Show cumulative table after each round (non-pipeline, multi-round only)
        if not cfg.batch and not in_pipeline and rounds > 1:
            metrics_so_far = extract_metrics(_round_results_so_far)
            print()
            print_compounding_table(metrics_so_far)
            print(flush=True)

        if not _culture_jsonl_file:
            return
        from datetime import datetime
        ts = datetime.now().isoformat()
        round_num = round_num + _round_offset  # pipeline round number
        for entry in memory.get_library():
            _culture_jsonl_file.write(_safe_dumps({
                "event": "library", "round": round_num, "timestamp": ts,
                "name": entry.name, "program": repr(entry.program),
                "usefulness": round(entry.usefulness, 3),
                "reuse_count": entry.reuse_count,
                "source_tasks": entry.source_tasks,
            }) + "\n")
        for tid, sp in memory.get_solutions().items():
            _culture_jsonl_file.write(_safe_dumps({
                "event": "solution", "round": round_num, "timestamp": ts,
                "task_id": tid, "program": repr(sp.program),
                "prediction_error": round(sp.prediction_error, 6),
            }) + "\n")
        for tid, sp in memory.get_best_attempts().items():
            _culture_jsonl_file.write(_safe_dumps({
                "event": "best_attempt", "round": round_num, "timestamp": ts,
                "task_id": tid, "program": repr(sp.program),
                "prediction_error": round(sp.prediction_error, 6),
            }) + "\n")
        _culture_jsonl_file.flush()

    t0 = time.time()
    results = learner.run_curriculum(
        tasks,
        CurriculumConfig(
            sort_by_difficulty=cfg.sequential_compounding,  # sort for compounding, shuffle for parallel
            wake_sleep_rounds=rounds,
            workers=workers,
            sequential_compounding=cfg.sequential_compounding,
        ),
        on_task_done=tracker.on_task_done,
        on_round_done=_on_round_done,
    )
    total_time = time.time() - t0
    tracker.close()
    if _culture_jsonl_file:
        _culture_jsonl_file.close()

    # --- Final results ---
    metrics = extract_metrics(results)
    total_evals = sum(wr.evaluations for rr in results for wr in rr.wake_results)

    last = metrics[-1] if metrics else None
    n_tasks = len(tasks)
    throughput = tracker.done / max(total_time, 0.001)

    library = memory.get_library()
    lib_map = {e.name: e.program for e in library}

    if cfg.batch:
        # Batch mode: one-line summary with key metrics
        solved = last.tasks_solved if last else 0
        rate = last.solve_rate if last else 0
        print(f"  [batch] solved={solved}/{n_tasks} ({rate:.1%})  "
              f"library={len(library)}  "
              f"time={fmt_duration(total_time)}  "
              f"throughput={throughput:.1f} tasks/s", flush=True)
    else:
        # Interactive mode: full verbose output
        # Compounding table
        if len(metrics) >= 1:
            print()
            print_compounding_table(metrics)
            print()

        # Use a phase label if the title contains TRAINING or EVALUATION
        phase_label = ""
        title_upper = cfg.title.upper()
        if "TRAINING" in title_upper:
            phase_label = " \u2014 TRAINING"
        elif "EVALUATION" in title_upper:
            phase_label = " \u2014 EVALUATION"

        if in_pipeline:
            # Brief summary — the pipeline prints the full compounding curve at the end
            if last:
                print(f"  \u2713 Solved: {last.tasks_solved}/{n_tasks} ({last.solve_rate:.1%}), "
                      f"library={len(library)}, "
                      f"time={fmt_duration(total_time)}")
        else:
            hline("\u2550")
            print(f"  FINAL RESULTS{phase_label}")
            hline("\u2550")

            print(f"  Tasks:             {n_tasks}")
            if last:
                print(f"  \u2713 Solved:          {last.tasks_solved}/{n_tasks}  "
                      f"({last.solve_rate:.1%})")
                if last.train_solved > last.tasks_solved:
                    overfits = last.train_solved - last.tasks_solved
                    print(f"    (+ {overfits} overfit: matched training examples "
                          f"but failed held-out test)")

            print(f"  Rounds:            {rounds}")
            print(f"  Total evaluations: {total_evals:,}")
            if tracker.times:
                print(f"  Median task time:  {statistics.median(tracker.times):.2f}s")
            print(f"  Wall-clock time:   {fmt_duration(total_time)}")
            throughput = tracker.done / max(total_time, 0.001)
            print(f"  Throughput:        {throughput:.1f} tasks/s ({workers} workers)")

            if len(metrics) >= 2:
                first_rate = metrics[0].solve_rate
                last_rate = metrics[-1].solve_rate
                if last_rate > first_rate:
                    print(f"\n  >>> COMPOUNDING DETECTED: {first_rate:.1%} \u2192 {last_rate:.1%}")
                elif last_rate == first_rate:
                    print(f"\n  >>> PLATEAU: solve rate stayed at {first_rate:.1%}")
                else:
                    print(f"\n  >>> REGRESSION: {first_rate:.1%} \u2192 {last_rate:.1%}")

        print(f"\n  Library: {len(library)} learned abstractions")
        for entry in library[:20]:
            expanded = expand_program(entry.program, lib_map)
            print(f"    {entry.name}: {expanded} "
                  f"(useful={entry.usefulness:.1f}, reused={entry.reuse_count}x, "
                  f"from {len(entry.source_tasks)} tasks)")
        if len(library) > 20:
            print(f"    ... and {len(library) - 20} more")

        if len(tracker.all_records) >= 5:
            by_time = sorted(tracker.all_records, key=lambda r: -r["wall_time"])
            print(f"\n  Slowest tasks:")
            for r in by_time[:5]:
                icon = "\u2713" if r["solved"] else "\u2717"
                print(f"    {icon} {r['task_id']}  {r['wall_time']:.1f}s  "
                      f"evals={r['evaluations']:,}  E={r['energy']}")

        # --- Solved tasks summary (for verification) ---
        # Re-expand program strings with the final library map (entries
        # may have been added during the run after programs were recorded).
        def _re_expand(record):
            """Re-expand program string using final library map."""
            from core.types import Program
            prog = record.get("_program_obj")
            if prog and isinstance(prog, Program):
                return expand_program(prog, lib_map)
            return record.get("program", "")

        solved_records = [r for r in tracker.all_records if r["solved"]]
        overfit_records = [r for r in tracker.all_records
                           if r.get("train_solved") and not r["solved"]]
        if solved_records:
            print()
            hline("\u2500")
            print(f"  SOLVED TASKS ({len(solved_records)} total)")
            hline("\u2500")
            for r in sorted(solved_records, key=lambda r: r["task_id"]):
                print(f"    \u2713 {r['task_id']:<24s} program: {_re_expand(r)}")
        if overfit_records:
            print()
            hline("\u2500")
            print(f"  OVERFIT TASKS ({len(overfit_records)} matched training but failed test)")
            hline("\u2500")
            for r in sorted(overfit_records, key=lambda r: r["task_id"]):
                err_str = f" err={r.get('test_error', '?')}" if r.get("test_error") else ""
                print(f"    ~ {r['task_id']:<24s} program: {_re_expand(r)}{err_str}")

        # --- Close attempts (for debugging unsolved tasks) ---
        close = [r for r in tracker.all_records
                 if not r["solved"] and not r.get("train_solved")
                 and r.get("prediction_error") is not None
                 and r["prediction_error"] < 0.1]
        if close:
            close.sort(key=lambda r: r["prediction_error"])
            print()
            hline("\u2500")
            print(f"  CLOSE ATTEMPTS ({len(close)} tasks with error < 0.1)")
            hline("\u2500")
            for r in close[:20]:
                print(f"    \u2717 {r['task_id']:<24s} err={r['prediction_error']:.4f}  "
                      f"program: {r['program']}")
            if len(close) > 20:
                print(f"    ... and {len(close) - 20} more")

    # --- Save artifacts ---
    results_data = {
        "meta": {
            "timestamp": run_timestamp,
            "datetime": datetime.now().isoformat(),
            "title": cfg.title,
            "domain": cfg.domain_tag,
            "mode": cfg.mode,
            "rounds": rounds,
            "evals_per_task": evals_per_task,
            "workers": workers,
            "seed": cfg.seed,
            "n_tasks": len(tasks),
            "n_primitives": len(cfg.grammar.base_primitives()),
            "compute_cap": compute_cap,
            "exhaustive_depth": cfg.exhaustive_depth,
            "exhaustive_pair_top_k": cfg.exhaustive_pair_top_k,
            "exhaustive_triple_top_k": cfg.exhaustive_triple_top_k,
            "sequential_compounding": cfg.sequential_compounding,
            "machine": machine,
        },
        "summary": {
            "n_tasks": len(tasks),
            "rounds": rounds,
            "last_round_solved": last.tasks_solved if last else 0,
            "last_round_solve_rate": round(last.solve_rate, 4) if last else 0,
            "last_round_train_solved": last.train_solved if last else 0,
            "last_round_train_solve_rate": round(last.train_solve_rate, 4) if last else 0,
            "total_task_instances": tracker.done,
            "mean_energy": round(statistics.mean(tracker.scores), 4) if tracker.scores else None,
            "total_evaluations": total_evals,
            "total_generations": tracker.total_gens,
            "median_task_time": round(statistics.median(tracker.times), 3) if tracker.times else None,
            "mean_task_time": round(statistics.mean(tracker.times), 3) if tracker.times else None,
            "wall_clock_seconds": round(total_time, 1),
            "throughput_tasks_per_sec": round(throughput, 2),
            "library_size": len(library),
            "compounding": [
                {
                    "round": m.round_number,
                    "solve_rate": round(m.solve_rate, 4),
                    "tasks_solved": m.tasks_solved,
                    "train_solve_rate": round(m.train_solve_rate, 4),
                    "train_solved": m.train_solved,
                    "tasks_total": m.tasks_total,
                    "library_size": m.library_size,
                    "new_abstractions": m.new_abstractions,
                    "avg_reuse": round(m.avg_reuse_per_entry, 2),
                    "avg_energy": round(m.avg_energy_of_solutions, 4) if m.avg_energy_of_solutions != float("inf") else None,
                    "wake_time": round(m.wall_time_wake, 1),
                    "sleep_time": round(m.wall_time_sleep, 1),
                }
                for m in metrics
            ],
        },
        "tasks": {
            r["task_id"]: {
                "round": r["round"],
                "solved": r["solved"],
                "train_solved": r.get("train_solved"),
                "test_solved": r.get("test_solved"),
                "test_error": r.get("test_error"),
                "energy": r["energy"],
                "prediction_error": r["prediction_error"],
                "generations": r["generations"],
                "evaluations": r["evaluations"],
                "wall_time": r["wall_time"],
                "program": r["program"],
                "n_train_perfect": r.get("n_train_perfect", 0),
                "solving_rank": r.get("solving_rank"),
                "train_predictions": r.get("train_predictions"),
                "test_predictions": r.get("test_predictions"),
            }
            for r in tracker.all_records
        },
        "all_records": tracker.all_records,
        "library": [
            {
                "name": entry.name,
                "program": repr(entry.program),
                "usefulness": round(entry.usefulness, 2),
                "reuse_count": entry.reuse_count,
                "source_tasks": list(entry.source_tasks),
            }
            for entry in library
        ],
    }

    if not cfg.suppress_files:
        # Exclude all_records from JSON (it's only for pipeline JSONL assembly)
        json_data = {k: v for k, v in results_data.items() if k != "all_records"}
        with open(results_path, "w") as f:
            f.write(_safe_dumps(json_data, indent=2))

        save_metrics_json(metrics, metrics_json_path)
        save_metrics_csv(metrics, metrics_csv_path)

    # Always save culture file (needed for pipeline eval transfer)
    memory.save_culture(culture_path)

    if not cfg.batch:
        print()
        hline("\u2500")
        print("  Artifacts:")
        hline("\u2500")
        print(f"  Results (live):   {jsonl_path}")
        if not cfg.suppress_files:
            print(f"  Results (final):  {results_path}")
            print(f"  Metrics JSON:     {metrics_json_path}")
            print(f"  Metrics CSV:      {metrics_csv_path}")
        print(f"  Culture:          {culture_path}")
        print(f"  Culture (live):   {culture_jsonl_path}")
        if not cfg.no_log:
            print(f"  Console log:      {log_path}")

        hline("\u2550")
        print("  Done.")
        hline("\u2550")
        print()

    return results_data


# =============================================================================
# Pipeline utilities
# =============================================================================

@contextmanager
def pipeline_tee(log_path: str):
    """Context manager that tees stdout to a pipeline log file."""
    tee = TeeWriter(log_path, sys.stdout)
    sys.stdout = tee
    try:
        yield log_path
    finally:
        sys.stdout = tee._original
        tee.close()


def save_pipeline_results(
    train_result: ExperimentResult,
    eval_result: ExperimentResult,
    *,
    prefix: str,
    runs_dir: str,
    title: str,
    domain: str,
    args,
    resolved: dict,
    extra_meta: dict | None = None,
    round_summaries: list[dict] | None = None,
) -> tuple[str, str]:
    """Save combined pipeline JSON + JSONL files.

    Returns (json_path, jsonl_path).
    """
    json_path = os.path.join(runs_dir, f"{prefix}.json")
    jsonl_path = os.path.join(runs_dir, f"{prefix}.jsonl")

    # Combined JSONL: full per-task records from ProgressTracker with phase tags
    with open(jsonl_path, "w") as f:
        for record in train_result.results_data.get("all_records", []):
            f.write(_safe_dumps({"phase": "train", **record}) + "\n")
        for record in eval_result.results_data.get("all_records", []):
            f.write(_safe_dumps({"phase": "eval", **record}) + "\n")

    # Combined JSON
    train_data = train_result.results_data
    eval_data = eval_result.results_data
    train_summary = train_data.get("summary", {})
    eval_summary = eval_data.get("summary", {})
    train_meta = train_data.get("meta", {})

    meta = {
        "timestamp": prefix.split("_")[-2] + "_" + prefix.split("_")[-1]
            if "_" in prefix else datetime.now().strftime("%Y%m%d_%H%M%S"),
        "datetime": datetime.now().isoformat(),
        "title": title,
        "domain": domain,
        "mode": train_meta.get("mode", getattr(args, "mode", "?")),
        "rounds": train_meta.get("rounds", resolved.get("rounds")),
        "workers": train_meta.get("workers", resolved.get("workers")),
        "seed": train_meta.get("seed", getattr(args, "seed", None)),
        "compute_cap": train_meta.get("compute_cap", resolved.get("compute_cap")),
        "n_primitives": train_meta.get("n_primitives"),
        "exhaustive_depth": getattr(args, "exhaustive_depth", None),
        "exhaustive_pair_top_k": getattr(args, "exhaustive_pair_top_k", None),
        "exhaustive_triple_top_k": getattr(args, "exhaustive_triple_top_k", None),
        "machine": train_meta.get("machine", {}),
    }
    if extra_meta:
        meta.update(extra_meta)

    def _phase_summary(summary):
        return {
            "n_tasks": summary.get("n_tasks", 0),
            "solved": summary.get("last_round_solved", 0),
            "solve_rate": summary.get("last_round_solve_rate", 0),
            "train_solved": summary.get("last_round_train_solved", 0),
            "train_solve_rate": summary.get("last_round_train_solve_rate", 0),
            "total_evaluations": summary.get("total_evaluations", 0),
            "wall_clock_seconds": summary.get("wall_clock_seconds", 0),
            "median_task_time": summary.get("median_task_time"),
            "throughput_tasks_per_sec": summary.get("throughput_tasks_per_sec"),
        }

    pipeline_data = {
        "meta": meta,
        "compounding_curve": round_summaries or [],
        "train": {**_phase_summary(train_summary),
                  "library_size": train_summary.get("library_size", 0)},
        "eval": _phase_summary(eval_summary),
        "train_tasks": train_data.get("tasks", {}),
        "eval_tasks": eval_data.get("tasks", {}),
        "library": train_data.get("library", []),
    }

    with open(json_path, "w") as f:
        f.write(_safe_dumps(pipeline_data, indent=2))

    return json_path, jsonl_path


def print_pipeline_summary(
    train_result: ExperimentResult,
    eval_result: ExperimentResult,
    *,
    title: str,
    args,
    json_path: str,
    jsonl_path: str,
    log_path: str = "",
    eval_label: str = "Evaluation Results (with culture transfer)",
    viz_paths: list[str] | None = None,
    culture_jsonl_path: str = "",
    round_summaries: list[dict] | None = None,
):
    """Print a formatted pipeline summary to stdout."""
    train_data = train_result.results_data
    eval_data = eval_result.results_data
    train_summary = train_data.get("summary", {})
    eval_summary = eval_data.get("summary", {})
    train_meta = train_data.get("meta", {})

    print()
    print("=" * 72)
    print(f"  {title}")
    print("=" * 72)

    n_rounds = len(round_summaries) if round_summaries else 1

    # Compounding curve (the key metric)
    if round_summaries and len(round_summaries) >= 1:
        print()
        print("  COMPOUNDING CURVE (train / eval per round):")
        # Fixed-width columns: Round(5) Train(15) Overfit(7) Library(7) Eval(15) Overfit(7) TrainT(10) EvalT(10)
        hdr = (f"  {'Round':>5}  {'Train':>15}  {'Overfit':>7}  {'Library':>7}"
               f"  {'Eval':>15}  {'Overfit':>7}  {'Train t':>10}  {'Eval t':>10}")
        sep = (f"  {'─'*5}  {'─'*15}  {'─'*7}  {'─'*7}"
               f"  {'─'*15}  {'─'*7}  {'─'*10}  {'─'*10}")
        print(hdr)
        print(sep)
        for rs in round_summaries:
            t_total = rs["train_total"]
            e_total = rs["eval_total"]
            t_rate = rs["train_solved"] / max(t_total, 1)
            e_rate = rs["eval_solved"] / max(e_total, 1)
            t_cell = f"{rs['train_solved']}/{t_total} ({t_rate:.1%})"
            e_cell = f"{rs['eval_solved']}/{e_total} ({e_rate:.1%})"
            t_wall = fmt_duration(rs.get("train_wall", 0))
            e_wall = fmt_duration(rs.get("eval_wall", 0))
            print(f"  {rs['round']:>5}  {t_cell:>15}  {rs['train_overfit']:>7}  {rs['train_library']:>7}"
                  f"  {e_cell:>15}  {rs['eval_overfit']:>7}  {t_wall:>10}  {e_wall:>10}")
        if len(round_summaries) > 1:
            if round_summaries[-1]["eval_solved"] > round_summaries[0]["eval_solved"]:
                r1 = round_summaries[0]["eval_solved"]
                rn = round_summaries[-1]["eval_solved"]
                print(f"\n  >>> EVAL COMPOUNDING: {r1} \u2192 {rn} eval solves across rounds")
            if round_summaries[-1]["train_solved"] > round_summaries[0]["train_solved"]:
                r1 = round_summaries[0]["train_solved"]
                rn = round_summaries[-1]["train_solved"]
                print(f"  >>> TRAIN COMPOUNDING: {r1} \u2192 {rn} train solves across rounds")

    # Final results summary
    print()
    total_train_wall = sum(rs.get("train_wall", 0) for rs in (round_summaries or []))
    total_eval_wall = sum(rs.get("eval_wall", 0) for rs in (round_summaries or []))
    total_wall = total_train_wall + total_eval_wall

    t_solved = train_summary.get("last_round_solved", 0)
    t_total = train_summary.get("n_tasks", 0)
    t_rate = train_summary.get("last_round_solve_rate", 0)
    e_solved = eval_summary.get("last_round_solved", 0)
    e_total = eval_summary.get("n_tasks", 0)
    e_rate = eval_summary.get("last_round_solve_rate", 0)
    lib_size = train_summary.get("library_size", 0)

    print(f"  Final (round {n_rounds}):")
    print(f"    Training:          {t_solved}/{t_total} ({t_rate:.1%})")
    print(f"    Eval:              {e_solved}/{e_total} ({e_rate:.1%})")
    print(f"    Library:           {lib_size} learned abstractions")
    print()
    print(f"  Wall time:")
    print(f"    Training total:    {fmt_duration(total_train_wall)}")
    print(f"    Eval total:        {fmt_duration(total_eval_wall)}")
    print(f"    Pipeline total:    {fmt_duration(total_wall)}")

    print()
    print("  Pipeline artifacts:")
    print(f"    Pipeline JSON:     {json_path}")
    print(f"    Pipeline JSONL:    {jsonl_path}")
    print(f"    Culture file:      {train_result.culture_path}")
    if culture_jsonl_path:
        print(f"    Culture (live):    {culture_jsonl_path}")
    if log_path:
        print(f"    Console log:       {log_path}")
    if viz_paths:
        for vp in viz_paths:
            print(f"    Visualization:     {vp}")

    print()
    print("=" * 72)
    print("  PIPELINE COMPLETE")
    print("=" * 72)


def _print_live_compounding(round_summaries: list[dict]) -> None:
    """Print the cumulative compounding curve after each pipeline round."""
    hdr = (f"  {'Round':>5}  {'Train':>15}  {'Overfit':>7}  {'Library':>7}"
           f"  {'Eval':>15}  {'Overfit':>7}  {'Train t':>10}  {'Eval t':>10}")
    sep = (f"  {'─'*5}  {'─'*15}  {'─'*7}  {'─'*7}"
           f"  {'─'*15}  {'─'*7}  {'─'*10}  {'─'*10}")
    print()
    print("  COMPOUNDING CURVE (so far):")
    print(hdr)
    print(sep)
    for rs in round_summaries:
        t_total = rs["train_total"]
        e_total = rs["eval_total"]
        t_rate = rs["train_solved"] / max(t_total, 1)
        e_rate = rs["eval_solved"] / max(e_total, 1)
        t_cell = f"{rs['train_solved']}/{t_total} ({t_rate:.1%})"
        e_cell = f"{rs['eval_solved']}/{e_total} ({e_rate:.1%})"
        t_wall = fmt_duration(rs.get("train_wall", 0))
        e_wall = fmt_duration(rs.get("eval_wall", 0))
        print(f"  {rs['round']:>5}  {t_cell:>15}  {rs['train_overfit']:>7}  {rs['train_library']:>7}"
              f"  {e_cell:>15}  {rs['eval_overfit']:>7}  {t_wall:>10}  {e_wall:>10}")
    print(flush=True)


# =============================================================================
# Generic pipeline runner (train -> save culture -> eval)
# =============================================================================

def run_pipeline(
    *,
    make_train_config,
    make_eval_config,
    load_train_tasks,
    load_eval_tasks,
    args,
    resolved: dict,
    max_tasks: int,
    pipeline_prefix: str,
    pipeline_title: str,
    domain_name: str,
    try_generate_viz=None,
    extra_meta: dict | None = None,
    eval_label: str = "Evaluation Results (with culture transfer)",
):
    """Generic train -> save culture -> eval pipeline.

    Args:
        make_train_config: callable(args, resolved, max_tasks, tasks, timestamp) -> ExperimentConfig
        make_eval_config: callable(args, resolved, max_tasks, tasks, culture_path, timestamp) -> ExperimentConfig
        load_train_tasks: callable(max_tasks) -> list[Task]
        load_eval_tasks: callable(max_tasks) -> list[Task]
        args: parsed CLI args
        resolved: dict from resolve_from_preset
        max_tasks: max tasks per split
        pipeline_prefix: e.g. "phase1_arc_pipeline"
        pipeline_title: e.g. "ARC-AGI-1 FULL PIPELINE (Train -> Eval)"
        domain_name: e.g. "phase1_arc"
        try_generate_viz: optional callable(json_path) -> list[str]
        extra_meta: optional extra metadata for pipeline JSON
        eval_label: label for eval section in summary
    """
    shared_ts = datetime.now().strftime("%Y%m%d_%H%M%S")
    prefix = f"{pipeline_prefix}_{shared_ts}"
    log_path = os.path.join(args.runs_dir, f"{prefix}.log")
    os.makedirs(args.runs_dir, exist_ok=True)

    total_rounds = resolved["rounds"]

    with pipeline_tee(log_path):
        print("=" * 72)
        print(f"  PIPELINE MODE: Train \u2192 Eval \u00d7 {total_rounds} rounds (compounding)")
        print("=" * 72)
        print()

        train_tasks = load_train_tasks(max_tasks)
        eval_tasks = load_eval_tasks(max_tasks)

        # Override rounds to 1 per step — we handle rounds manually
        round_resolved = dict(resolved)
        round_resolved["rounds"] = 1

        # Single culture JSONL for the whole pipeline (grows across rounds)
        pipeline_culture_jsonl = os.path.join(
            args.runs_dir, f"{prefix}_culture.jsonl")

        culture_path = ""
        train_result = None
        eval_result = None
        round_summaries = []  # per-round train+eval metrics

        for round_num in range(1, total_rounds + 1):
            # Train round N (loading culture from previous round)
            print(f"  ROUND {round_num}/{total_rounds}: Training...")
            print()
            train_cfg = make_train_config(
                args, round_resolved, max_tasks, train_tasks, shared_ts)
            train_cfg.pipeline_round = round_num
            # Load culture from previous round for compounding
            if culture_path:
                train_cfg.culture_path = culture_path
            # Share a single culture JSONL across all training rounds
            train_cfg._culture_jsonl_path = pipeline_culture_jsonl
            train_cfg._pipeline_round_offset = round_num - 1
            train_result = run_experiment(train_cfg)
            culture_path = train_result.culture_path
            print(f"\n  Culture saved: {culture_path}")

            # Eval round N (using culture from this training round)
            print()
            print(f"  ROUND {round_num}/{total_rounds}: Evaluating with learned culture...")
            print()
            eval_cfg = make_eval_config(
                args, round_resolved, max_tasks, eval_tasks,
                culture_path, shared_ts)
            eval_cfg.pipeline_round = round_num
            # Eval doesn't learn — suppress culture files
            eval_cfg._culture_jsonl_path = ""
            eval_cfg.save_culture = os.devnull
            eval_result = run_experiment(eval_cfg)
            print()

            # Collect per-round metrics
            t_summary = train_result.results_data.get("summary", {})
            e_summary = eval_result.results_data.get("summary", {})
            round_summaries.append({
                "round": round_num,
                "train_solved": t_summary.get("last_round_solved", 0),
                "train_total": t_summary.get("n_tasks", 0),
                "train_overfit": max(0, t_summary.get("last_round_train_solved", 0)
                                     - t_summary.get("last_round_solved", 0)),
                "train_library": t_summary.get("library_size", 0),
                "train_wall": t_summary.get("wall_clock_seconds", 0),
                "eval_solved": e_summary.get("last_round_solved", 0),
                "eval_total": e_summary.get("n_tasks", 0),
                "eval_wall": e_summary.get("wall_clock_seconds", 0),
                "eval_overfit": max(0, e_summary.get("last_round_train_solved", 0)
                                    - e_summary.get("last_round_solved", 0)),
            })

            # Print cumulative compounding table after each round
            _print_live_compounding(round_summaries)

        # Save combined pipeline artifacts (uses last train + eval results)
        json_path, jsonl_path = save_pipeline_results(
            train_result, eval_result,
            prefix=prefix, runs_dir=args.runs_dir,
            title=pipeline_title,
            domain=domain_name, args=args, resolved=resolved,
            extra_meta=extra_meta,
            round_summaries=round_summaries,
        )

        # Generate HTML visualization
        viz_paths = []
        if try_generate_viz:
            viz_paths = try_generate_viz(json_path)

        print_pipeline_summary(
            train_result, eval_result,
            title="PIPELINE SUMMARY", args=args,
            json_path=json_path, jsonl_path=jsonl_path,
            log_path=log_path,
            eval_label=eval_label,
            viz_paths=viz_paths,
            culture_jsonl_path=pipeline_culture_jsonl,
            round_summaries=round_summaries,
        )
