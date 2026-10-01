"""Reproduce GEN-GBC's Phase 3–4 ablation, adapted from GEN-CIM Table 5.

Rows: Phase-2 Only, +Latent Opt (one CEM), Full (the same initial CEM + two
CEM-Refine loops with optional gold injection). Full restores the Latent Opt
checkpoint and does not repeat its initial CEM. All three returned k-sets
are scored together with the same exact internal-node ordered-pair GBC
C++ evaluator throughout.

This adapts the design of GEN-CIM Table 5 to GBC; it does not reproduce
GEN-CIM's F(S) numbers. In that paper ca-GrQc uses k=20 and the Full entry
is unreported. GEN-GBC deliberately evaluates Full for ca-GrQc/k=10 too.
The separate runtime_full_exact.csv follows Table 4's Training/Inference
stage layout for the Full GEN-GBC variant.

Phase 2 uses one CentRA, one AdaAlg and one HEDGE group by default. Their counts
and source files are carried through GIMConfig so all three ablation variants
share exactly the same Phase-2 starting dataset.
Graph direction follows GIMConfig: Wiki-Vote/p2p-Gnutella08 are directed
by default; ca-GrQc/LastFM Asia are undirected. --directed/--undirected
overrides apply to all variants and the independent final evaluation.

Run once per dataset/k/seed/expert configuration; the CSV is updated by that key:
    python run_ablation.py --dataset ca-grqc --data-root /content/data \
        --k 10 --exact-source exact_gbc.cpp --threads 4

Training time sums the original Phase 1/2/3/ScoreNet/Phase 4 runtimes; Full
includes the initial CEM time inherited from Latent Opt. It excludes graph loading and C++
compilation. Existing checkpoints without timing metadata produce a blank
training time (training_time_complete=False); use --no-resume for fresh timings.
That option creates an isolated checkpoint directory for the ablation run,
then reuses only its newly trained Phase 1/2/3 checkpoints across variants.
Inference uses an empty exact-score cache; the final independent batch check
is measured separately in final_evaluation_time_s.
"""
from __future__ import annotations

import argparse
import csv
import hashlib
import json
import subprocess
import tempfile
import time
from dataclasses import replace
from pathlib import Path
from typing import Dict, Optional

from train_gim import GIMConfig, main
from exact_gbc_scorer import compile_exact_gbc

VARIANTS = ("phase2_only", "latent_opt", "full")
FIELDS = ("dataset", "k", "seed", "directed", "centra_count", "adaalg_count", "hedge_count",
          "centra_sha256", "adaalg_sha256", "hedge_sha256", "exact_sha256", "score_enabled",
          "device", "exact_threads",
          "checkpoint_dir",
          "phase2_only_raw_gbc", "latent_opt_raw_gbc",
          "full_raw_gbc", "latent_opt_delta_pct", "full_delta_pct",
          "phase2_only_online_exact", "latent_opt_online_exact", "full_online_exact",
          "phase2_only_training_time_s", "phase2_only_training_time_complete",
          "phase2_only_newly_trained_time_s", "phase2_only_inference_time_s",
          "latent_opt_training_time_s", "latent_opt_training_time_complete",
          "latent_opt_newly_trained_time_s", "latent_opt_inference_time_s",
          "full_training_time_s", "full_training_time_complete",
          "full_newly_trained_time_s", "full_inference_time_s",
          "final_evaluation_time_s",
          "loop0_exact", "loop1_exact", "loop2_exact",
          "refine_injections", "evaluation")
RUNTIME_FIELDS = ("dataset", "k", "seed", "directed", "method", "stage", "time_s",
                  "time_complete", "centra_count", "adaalg_count", "hedge_count",
                  "centra_sha256", "adaalg_sha256", "hedge_sha256", "exact_sha256",
                  "score_enabled", "device", "exact_threads", "checkpoint_dir")
LEGACY_FIELDS = tuple(key for key in FIELDS if key not in ("hedge_count", "hedge_sha256"))
LEGACY_RUNTIME_FIELDS = tuple(key for key in RUNTIME_FIELDS
                              if key not in ("hedge_count", "hedge_sha256"))


def exact_evaluate(binary: Path, graph_path: Path,
                   seed_sets: Dict[str, list[int]], threads: int = 1, *,
                   directed: bool = False) -> Dict[str, float]:
    """Use one graph load/one evaluator invocation for all three methods."""
    cmd = [str(binary), "--graph", str(graph_path), "--group-ids", "internal",
           "--threads", str(threads), "--quiet"]
    if directed:
        cmd.append("--directed")
    for name, nodes in seed_sets.items():
        if not nodes:
            raise ValueError("Cannot evaluate an empty seed group")
        cmd += ["--group", name + ":" + ",".join(map(str, sorted(nodes)))]
    payload = json.loads(subprocess.run(cmd, check=True, capture_output=True,
                                        text=True).stdout)
    if payload.get("pair_domain") != "all_distinct_ordered_pairs" or payload.get(
            "coverage") != "at_least_one_internal_group_node" or payload.get(
            "directed") != directed:
        raise ValueError("Exact evaluator uses a different GBC convention")
    scores = {item["method"]: float(item["raw_gbc"]) for item in payload["results"]}
    if set(scores) != set(seed_sets):
        raise ValueError("Exact evaluator returned the wrong set of methods")
    return scores


def _percent_gain(after: float, baseline: float) -> Optional[float]:
    return 100.0 * (after - baseline) / baseline if baseline > 0 else None


def _expert_hash(source: str, count: int) -> str:
    return hashlib.sha256(Path(source).read_bytes()).hexdigest() if count else "disabled"


def run_ablation(cfg: GIMConfig, *, csv_path: Optional[Path] = None,
                 exact_source: Optional[Path] = None,
                 threads: int = 1) -> dict:
    """Run all variants with the same Phase 1/2 and exact GBC evaluator."""
    if threads < 1:
        raise ValueError("threads must be positive")
    # A fresh ablation must not reuse older P3/P4 checkpoints, even though
    # variants 2/3 must share newly trained upstream phases. Use an isolated
    # directory so existing checkpoints remain available to the user.
    # Table 5 isolates the training phases. Extra CVAE samples at inference
    # would add a separate search method to the two CEM variants.
    cfg = replace(cfg, exact_threads=threads,
                  exact_source=str(exact_source or cfg.exact_source))
    if not cfg.resume:
        checkpoint_root = Path(cfg.checkpoint_dir)
        checkpoint_root.mkdir(parents=True, exist_ok=True)
        fresh_dir = tempfile.mkdtemp(prefix="ablation_fresh_", dir=checkpoint_root)
        cfg = replace(cfg, checkpoint_dir=fresh_dir)
        print(f"[Ablation] Fresh checkpoints: {fresh_dir}", flush=True)
    expert_identity = {
        "directed": cfg.get_directed(),
        "centra_count": cfg.p2_centra_count,
        "adaalg_count": cfg.p2_adaalg_count,
        "hedge_count": cfg.p2_hedge_count,
        "centra_sha256": _expert_hash(cfg.centra_source, cfg.p2_centra_count),
        "adaalg_sha256": _expert_hash(cfg.adaalg_source, cfg.p2_adaalg_count),
        "hedge_sha256": _expert_hash(cfg.hedge_source, cfg.p2_hedge_count),
        "exact_sha256": hashlib.sha256(Path(cfg.exact_source).read_bytes()).hexdigest(),
        "score_enabled": cfg.score_enabled,
        "device": cfg.device,
        "exact_threads": threads,
    }
    results = {}
    for i, name in enumerate(VARIANTS):
        print(f"[Ablation] Bắt đầu biến thể {i + 1}/{len(VARIANTS)}: {name}.",
              flush=True)
        results[name] = main(replace(cfg, variant=name,
                                     reuse_latent_cem=name == "full",
                                     inference_samples=0, inference_shortlist=0,
                                     resume=cfg.resume or i > 0))
        print(f"[Ablation] {name} xong; GBC exact tốt nhất="
              f"{results[name].best_exact:.6f}.", flush=True)
    binary = compile_exact_gbc(cfg.exact_source, Path(cfg.checkpoint_dir) / "exact_gbc_binary")
    print("[Ablation] Chấm lại nghiệm cuối của ba biến thể bằng exact GBC...",
          flush=True)
    evaluation_start = time.perf_counter()
    scores = exact_evaluate(binary, Path(cfg.data_root) / f"{cfg.dataset.lower()}.txt",
        {name: sorted(result.best_seed_set.nodes) for name, result in results.items()},
        threads=threads, directed=cfg.get_directed())
    final_evaluation_time_s = time.perf_counter() - evaluation_start
    for name in VARIANTS:
        if abs(scores[name] - results[name].best_exact) > 1e-4:
            raise ValueError(f"Online and independent exact GBC disagree for {name}")
    # Each call to main() writes one result JSON with the wall times measured
    # immediately before and during inference. Read all three after training.
    run_logs = {}
    for name in VARIANTS:
        path = replace(cfg, variant=name).result_path()
        record = json.loads(path.read_text(encoding="utf-8"))
        if (record["dataset"] != cfg.dataset or record["k"] != cfg.k
                or record["variant"] != name or record["seed"] != cfg.seed
                or record.get("directed", False) != cfg.get_directed()):
            raise ValueError(f"Ablation result belongs to another experiment: {path}")
        run_logs[name] = record
    loops = run_logs["full"]["loops"]
    row = {"dataset": cfg.dataset, "k": cfg.k, "seed": cfg.seed,
           **expert_identity,
           "checkpoint_dir": cfg.checkpoint_dir,
           "phase2_only_raw_gbc": scores["phase2_only"],
           "latent_opt_raw_gbc": scores["latent_opt"],
           "full_raw_gbc": scores["full"],
           "latent_opt_delta_pct": _percent_gain(scores["latent_opt"],
                                                   scores["phase2_only"]),
           "full_delta_pct": _percent_gain(scores["full"], scores["phase2_only"]),
           "phase2_only_online_exact": results["phase2_only"].best_exact,
           "latent_opt_online_exact": results["latent_opt"].best_exact,
           "full_online_exact": results["full"].best_exact,
           "final_evaluation_time_s": final_evaluation_time_s,
           "refine_injections": sum(bool(item["injected"]) for item in loops),
           "evaluation": "exact_raw_ordered_internal_node_gbc"}
    for i in range(3):
        row[f"loop{i}_exact"] = loops[i]["cem_GBC"] if i < len(loops) else None
    for name, record in run_logs.items():
        training = record["training_time_s"]
        row[f"{name}_training_time_s"] = (float(training) if training is not None else None)
        row[f"{name}_training_time_complete"] = bool(record["training_time_complete"])
        row[f"{name}_newly_trained_time_s"] = float(record["newly_trained_time_s"])
        row[f"{name}_inference_time_s"] = float(record["inference_time_s"])
    output = csv_path or Path(cfg.results_dir) / "ablation_phase3_phase4_exact.csv"
    output.parent.mkdir(parents=True, exist_ok=True)
    prior = []
    if output.is_file():
        with output.open(newline="", encoding="utf-8") as handle:
            reader = csv.DictReader(handle)
            old_fields = tuple(reader.fieldnames or ())
            if old_fields != FIELDS and not (set(old_fields) <= set(FIELDS)
                                              and {"dataset", "k", "seed"} <= set(old_fields)):
                raise ValueError(f"Existing CSV has a different schema: {output}")
            existing = list(reader)
            # Every result from the previous runner used directed=False,
            # including older Wiki-Vote/Gnutella rows. Preserve that meaning.
            for item in existing:
                item.setdefault("directed", False)
                # Historical rows predate HEDGE and remain separate experiments.
                item.setdefault("hedge_count", 0)
                item.setdefault("hedge_sha256", "disabled")
            prior = [item for item in existing if not (
                item["dataset"] == cfg.dataset and int(item["k"]) == cfg.k
                and int(item.get("seed", 42)) == cfg.seed
                and all(str(item.get(key, "")) == str(value)
                        for key, value in expert_identity.items()))]
            known_timing_schemas = (set(FIELDS), set(FIELDS) - {"directed"},
                                    set(LEGACY_FIELDS), set(LEGACY_FIELDS) - {"directed"})
            if set(old_fields) not in known_timing_schemas:
                # Earlier timing columns mixed checkpoint loading with training.
                # Their historical durations cannot be repaired retroactively.
                for item in prior:
                    for key in expert_identity:
                        item.setdefault(key, "")
                    item.setdefault("checkpoint_dir", "")
                    for name in VARIANTS:
                        item[f"{name}_training_time_s"] = ""
                        item[f"{name}_training_time_complete"] = False
                        item[f"{name}_newly_trained_time_s"] = ""
                    item["final_evaluation_time_s"] = ""
    with output.open("w", newline="", encoding="utf-8") as handle:
        writer = csv.DictWriter(handle, fieldnames=FIELDS)
        writer.writeheader()
        writer.writerows(prior + [row])
    # Paper Table 4 is a separate two-stage runtime table for the full model.
    # The final independent three-set ablation check is not an inference query.
    runtime_path = Path(cfg.results_dir) / "runtime_full_exact.csv"
    runtime_prior = []
    if runtime_path.is_file():
        with runtime_path.open(newline="", encoding="utf-8") as handle:
            reader = csv.DictReader(handle)
            old_runtime_fields = tuple(reader.fieldnames or ())
            if old_runtime_fields not in (RUNTIME_FIELDS, LEGACY_RUNTIME_FIELDS,
                    tuple(key for key in RUNTIME_FIELDS if key != "directed"),
                    tuple(key for key in LEGACY_RUNTIME_FIELDS if key != "directed")):
                raise ValueError(f"Existing runtime CSV has another schema: {runtime_path}")
            existing = list(reader)
            for item in existing:
                item.setdefault("directed", False)
                item.setdefault("hedge_count", 0)
                item.setdefault("hedge_sha256", "disabled")
            runtime_prior = [item for item in existing if not (
                item["dataset"] == cfg.dataset and int(item["k"]) == cfg.k
                and int(item["seed"]) == cfg.seed
                and all(str(item.get(key, "")) == str(value)
                        for key, value in expert_identity.items()))]
    full = run_logs["full"]
    common = {"dataset": cfg.dataset, "k": cfg.k, "seed": cfg.seed,
              "method": "GEN-GBC Full", **expert_identity,
              "checkpoint_dir": cfg.checkpoint_dir}
    runtime_rows = [
        {**common, "stage": "Training", "time_s": full["training_time_s"],
         "time_complete": full["training_time_complete"]},
        {**common, "stage": "Inference", "time_s": full["inference_time_s"],
         "time_complete": True},
    ]
    with runtime_path.open("w", newline="", encoding="utf-8") as handle:
        writer = csv.DictWriter(handle, fieldnames=RUNTIME_FIELDS)
        writer.writeheader()
        writer.writerows(runtime_prior + runtime_rows)
    print(f"[Ablation] Phase2={scores['phase2_only']:.6f}, "
          f"+Latent={scores['latent_opt']:.6f}, Full={scores['full']:.6f} "
          f"(exact raw GBC); saved {output} and {runtime_path}")
    return row


def _smoke_test() -> None:
    import torch
    from unittest.mock import patch
    from rl_policy import CEMTrainer
    torch.set_num_threads(1)
    with tempfile.TemporaryDirectory() as tmp:
        root = Path(tmp)
        path = root / "tiny.txt"
        path.write_text("0 1\n1 2\n2 3\n3 4\n4 5\n5 0\n0 3\n", encoding="utf-8")
        # Keep adaptive CentRA/AdaAlg runs out of the tiny ablation smoke test.
        cfg = GIMConfig(dataset="tiny", data_root=str(root), k=2,
            checkpoint_dir=str(root / "ckpt"),
            results_dir=str(root / "results"), device="cpu", p1_hidden=8,
            p1_heads=2, p1_epochs=1, p2_H=1, p2_neighbors=2,
            p2_value_epochs=1, p2_centra_count=0, p2_adaalg_count=0, p2_hedge_count=0,
            p3_latent_dim=4, p3_hidden=16, p3_iters=2,
            score_epochs=1, cem_runs=3, cem_pop=4, cem_iter=2,
            refine_p3_iters=2, refine_score_epochs=1,
            langevin_steps=1, inference_samples=3, inference_shortlist=2)
        original_fit = CEMTrainer.fit
        fit_calls = 0

        def counted_fit(self, *args, **kwargs):
            nonlocal fit_calls
            fit_calls += 1
            return original_fit(self, *args, **kwargs)

        with patch.object(CEMTrainer, "fit", counted_fit):
            row = run_ablation(cfg, threads=1)
        assert fit_calls == cfg.cem_runs  # 1 Latent Opt + 2 new Full fits.
        assert row["phase2_only_raw_gbc"] >= 0 and row["full_raw_gbc"] >= 0
        assert row["evaluation"] == "exact_raw_ordered_internal_node_gbc"
        for name in VARIANTS:
            assert row[f"{name}_training_time_complete"]
            assert row[f"{name}_training_time_s"] >= 0
            assert row[f"{name}_inference_time_s"] >= 0
        assert row["full_training_time_s"] >= row["latent_opt_training_time_s"]
        latent_json = json.loads((root / "results" /
            "gbc_tiny_k2_seed42_latent_opt_exact.json").read_text())
        full_json = json.loads((root / "results" /
            "gbc_tiny_k2_seed42_full_exact.json").read_text())
        assert len(full_json["cem_scores"]) == cfg.cem_runs
        assert full_json["cem_scores"][0] == latent_json["cem_scores"][0]
        assert full_json["loops"][0]["refined"]
        assert (full_json["training_phase_times_s"]["p4_full"] >=
                latent_json["training_phase_times_s"]["p4_latent_opt"])
        again = run_ablation(cfg, threads=1)
        assert row["full_raw_gbc"] == again["full_raw_gbc"]
        with (root / "results" / "ablation_phase3_phase4_exact.csv").open(
                newline="", encoding="utf-8") as handle:
            assert len(list(csv.DictReader(handle))) == 1
        with (root / "results" / "runtime_full_exact.csv").open(
                newline="", encoding="utf-8") as handle:
            runtime = list(csv.DictReader(handle))
            assert [item["stage"] for item in runtime] == ["Training", "Inference"]
            assert all(item["time_complete"] == "True" for item in runtime)
    print("run_ablation.py smoke test: PASS")


def parse_args() -> argparse.Namespace:
    parser = argparse.ArgumentParser(description="GEN-GBC Table 5 ablation")
    parser.add_argument("--dataset", default="ca-grqc")
    parser.add_argument("--data-root", default="data")
    direction = parser.add_mutually_exclusive_group()
    direction.add_argument("--directed", dest="directed", action="store_true",
                           help="Keep input edge orientation")
    direction.add_argument("--undirected", dest="directed", action="store_false",
                           help="Add reverse arcs for an undirected graph")
    parser.set_defaults(directed=None)
    parser.add_argument("--k", type=int, default=10)
    parser.add_argument("--exact-source", default=str(Path(__file__).with_name("exact_gbc.cpp")))
    parser.add_argument("--centra-source", default=str(Path(__file__).with_name("centra.cpp")))
    parser.add_argument("--adaalg-source", default=str(Path(__file__).with_name("adaalg.cpp")))
    parser.add_argument("--hedge-source", default=str(Path(__file__).with_name("hedge.cpp")))
    parser.add_argument("--checkpoint-dir", default="experiments/checkpoints")
    parser.add_argument("--results-dir", default="experiments/results")
    parser.add_argument("--output-csv", type=Path)
    parser.add_argument("--device", default="auto")
    parser.add_argument("--seed", type=int, default=42)
    parser.add_argument("--threads", type=int, default=1)
    parser.add_argument("--no-resume", action="store_true")
    parser.add_argument("--no-score-net", action="store_true")
    parser.add_argument("--p1-epochs", type=int, default=1000)
    parser.add_argument("--p2-value-epochs", type=int, default=500)
    parser.add_argument("--p2-top-trajectories", type=int, default=45)
    parser.add_argument("--p2-centra-count", type=int, default=1)
    parser.add_argument("--p2-adaalg-count", type=int, default=1)
    parser.add_argument("--p2-hedge-count", type=int, default=1)
    parser.add_argument("--p3-iters", type=int, default=3000)
    parser.add_argument("--p3-beta-max", type=float, default=1.0)
    parser.add_argument("--p3-lambda-vp", type=float, default=0.1)
    parser.add_argument("--p3-gamma", type=float, default=0.05)
    parser.add_argument("--p2-elite-top-k", type=int, default=5)
    parser.add_argument("--p2-elite-weight", type=float, default=4.0)
    parser.add_argument("--score-epochs", type=int, default=300)
    parser.add_argument("--cem-pop", type=int, default=60)
    parser.add_argument("--cem-iter", type=int, default=25)
    parser.add_argument("--cem-sigma-scale", type=float, default=1.0)
    parser.add_argument("--refine-p3-iters", type=int,
                        help="Default: max(500, p3_iters // 3) as in GEN-CIM")
    parser.add_argument("--refine-score-epochs", type=int,
                        help="Default: use score_epochs as in GEN-CIM")
    parser.add_argument("--smoke-test", action="store_true")
    return parser.parse_args()


if __name__ == "__main__":
    args = parse_args()
    if args.smoke_test:
        _smoke_test()
    else:
        run_ablation(GIMConfig(dataset=args.dataset, data_root=args.data_root,
            directed=args.directed,
            k=args.k, exact_source=args.exact_source,
            centra_source=args.centra_source, adaalg_source=args.adaalg_source,
            hedge_source=args.hedge_source,
            checkpoint_dir=args.checkpoint_dir, results_dir=args.results_dir,
            device=args.device, seed=args.seed, resume=not args.no_resume,
            score_enabled=not args.no_score_net, p1_epochs=args.p1_epochs,
            p2_value_epochs=args.p2_value_epochs,
            p2_top_trajectories=args.p2_top_trajectories,
            p2_centra_count=args.p2_centra_count,
            p2_adaalg_count=args.p2_adaalg_count,
            p2_hedge_count=args.p2_hedge_count,
            p2_elite_top_k=args.p2_elite_top_k,
            p2_elite_weight=args.p2_elite_weight,
            p3_iters=args.p3_iters, p3_beta_max=args.p3_beta_max,
            p3_lambda_vp=args.p3_lambda_vp, p3_gamma=args.p3_gamma,
            score_epochs=args.score_epochs, cem_pop=args.cem_pop,
            cem_iter=args.cem_iter, cem_sigma_scale=args.cem_sigma_scale,
            refine_p3_iters=args.refine_p3_iters,
            refine_score_epochs=args.refine_score_epochs),
            csv_path=args.output_csv, threads=args.threads)
