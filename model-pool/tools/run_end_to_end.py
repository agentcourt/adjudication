#!/usr/bin/env -S uv run
# /// script
# requires-python = ">=3.11"
# dependencies = []
# ///
import argparse
import csv
import datetime as dt
import json
import os
import shutil
import subprocess
import sys
from pathlib import Path
from typing import Any

ROOT = Path(__file__).resolve().parents[1]

STAGES = ["inventory", "eval", "filter", "genes", "pca", "clusters", "aggregate", "pool"]


def utc_now() -> str:
    return dt.datetime.now(dt.UTC).replace(microsecond=0).isoformat().replace("+00:00", "Z")


def timestamp() -> str:
    return dt.datetime.now(dt.UTC).strftime("%Y%m%dT%H%M%SZ")


def resolve_path(path_text: str) -> Path:
    path = Path(path_text)
    if path.is_absolute():
        return path
    return ROOT / path


def display_path(path: Path) -> str:
    if path.is_relative_to(ROOT):
        return str(path.relative_to(ROOT))
    return str(path)


def load_json(path: Path) -> dict[str, Any]:
    return json.loads(path.read_text())


def load_jsonl(path: Path) -> list[dict[str, Any]]:
    with path.open() as handle:
        return [json.loads(line) for line in handle if line.strip()]


def write_json(path: Path, payload: dict[str, Any]) -> None:
    path.write_text(json.dumps(payload, indent=2, ensure_ascii=False, sort_keys=True) + "\n")


def write_jsonl(path: Path, rows: list[dict[str, Any]]) -> None:
    with path.open("w") as handle:
        for row in rows:
            handle.write(json.dumps(row, ensure_ascii=False, sort_keys=True) + "\n")


def line_count(path: Path) -> int:
    try:
        with path.open() as handle:
            return sum(1 for line in handle if line.strip())
    except FileNotFoundError:
        return 0


def event(kind: str, **data: Any) -> None:
    print(json.dumps({"at": utc_now(), "kind": kind, **data}, ensure_ascii=False, sort_keys=True), flush=True)


def command_env() -> dict[str, str]:
    env = os.environ.copy()
    env.setdefault("UV_CACHE_DIR", "/tmp/uv-cache")
    return env


def append_command_record(commands_path: Path, record: dict[str, Any]) -> None:
    with commands_path.open("a") as handle:
        handle.write(json.dumps(record, ensure_ascii=False, sort_keys=True) + "\n")


def run_command(
    cmd: list[str],
    *,
    cwd: Path,
    commands_path: Path,
    stage: str,
    dry_run: bool,
    stdout_path: Path | None = None,
) -> None:
    record = {
        "at": utc_now(),
        "stage": stage,
        "cmd": cmd,
        "cwd": display_path(cwd),
        "dry_run": dry_run,
        "stdout_path": display_path(stdout_path) if stdout_path else None,
    }
    append_command_record(commands_path, record)
    event("command_started", stage=stage, cmd=cmd)
    if dry_run:
        event("command_skipped", stage=stage, reason="dry_run")
        return

    stdout_handle = None
    if stdout_path is not None:
        stdout_path.parent.mkdir(parents=True, exist_ok=True)
        stdout_handle = stdout_path.open("w")

    try:
        process = subprocess.Popen(
            cmd,
            cwd=cwd,
            env=command_env(),
            stdout=subprocess.PIPE,
            stderr=subprocess.STDOUT,
            text=True,
            bufsize=1,
        )
        assert process.stdout is not None
        tail: list[str] = []
        for line in process.stdout:
            print(line, end="")
            if stdout_handle is not None:
                stdout_handle.write(line)
            tail.append(line.rstrip())
            tail = tail[-20:]
        code = process.wait()
    finally:
        if stdout_handle is not None:
            stdout_handle.close()

    append_command_record(
        commands_path,
        {
            "at": utc_now(),
            "stage": stage,
            "cmd": cmd,
            "exit_code": code,
            "tail": tail[-8:],
        },
    )
    if code != 0:
        raise RuntimeError(f"{stage} command failed with exit code {code}: {' '.join(cmd)}")
    event("command_finished", stage=stage, exit_code=code)


def stage_done(path: Path, resume: bool) -> bool:
    return resume and path.exists()


def completed_gene_summary(summary_path: Path, args: argparse.Namespace, expected_records: int) -> bool:
    if not args.resume or not summary_path.exists():
        return False
    summary = load_json(summary_path)
    if summary.get("records_written") != expected_records:
        return False
    if not summary.get("completion_error_count") and not summary.get("embedding_error_count"):
        return True
    return not args.strict_gene_completions and bool(summary.get("partial_records_allowed"))


def run_inventory(args: argparse.Namespace, run_dir: Path, commands_path: Path) -> Path:
    out_dir = run_dir / "inventory"
    summary = out_dir / "summary.json"
    variants = out_dir / "endpoint_variants.jsonl"
    if stage_done(summary, args.resume) and variants.exists():
        event("stage_skipped", stage="inventory", reason="resume", output=display_path(out_dir))
        return out_dir

    cmd = [
        "uv",
        "run",
        "--script",
        "tools/model_inventory.py",
        "--out-root",
        display_path(run_dir),
        "--run-id",
        "inventory",
        "--sample-seed",
        str(args.root_seed),
        "--request-timeout",
        str(args.inventory_request_timeout),
        "--retries",
        str(args.inventory_retries),
    ]
    if args.model_id:
        for model_id in args.model_id:
            cmd.extend(["--model-id", model_id])
    else:
        cmd.extend(["--sample-models", str(args.root_count)])
    if args.inventory_sleep:
        cmd.extend(["--sleep", str(args.inventory_sleep)])
    run_command(cmd, cwd=ROOT, commands_path=commands_path, stage="inventory", dry_run=args.dry_run)
    return out_dir


def run_eval(args: argparse.Namespace, run_dir: Path, inventory_dir: Path, commands_path: Path) -> Path:
    out_dir = run_dir / "eval"
    summary = out_dir / "summary.json"
    if stage_done(summary, args.resume):
        event("stage_skipped", stage="eval", reason="resume", output=display_path(out_dir))
        return out_dir

    cmd = [
        "uv",
        "run",
        "--script",
        "tools/run_variant_batch.py",
        "--variants",
        display_path(inventory_dir / "endpoint_variants.jsonl"),
        "--out",
        display_path(out_dir),
        "--questions",
        args.questions,
        "--trials",
        str(args.eval_trials),
        "--timeout",
        str(args.timeout),
        "--no-progress-timeout",
        str(args.eval_no_progress_timeout),
    ]
    if args.eval_variant_timeout is not None:
        cmd.extend(["--variant-timeout", str(args.eval_variant_timeout)])
    run_command(cmd, cwd=ROOT, commands_path=commands_path, stage="eval", dry_run=args.dry_run)
    return out_dir


def row_index(row: dict[str, Any], fallback: int) -> int:
    value = row.get("combined_index") or row.get("index") or fallback
    return int(value)


def int_field(row: dict[str, Any], key: str) -> int:
    value = row.get(key)
    return int(value) if value not in (None, "") else 0


def float_field(row: dict[str, Any], key: str) -> float | None:
    value = row.get(key)
    if value in (None, ""):
        return None
    return float(value)


def load_eval_summary(path: Path) -> list[dict[str, Any]]:
    if path.suffix == ".csv":
        with path.open(newline="") as handle:
            return [dict(row) for row in csv.DictReader(handle)]
    return load_jsonl(path)


def copy_spec_for_index(specs_dir: Path, out_specs_dir: Path, index: int) -> None:
    matches = sorted(specs_dir.glob(f"{index:02d}-*.json"))
    if len(matches) != 1:
        raise RuntimeError(f"expected one spec for variant index {index}, found {len(matches)}")
    shutil.copy2(matches[0], out_specs_dir / matches[0].name)


def filter_variants(args: argparse.Namespace, run_dir: Path, inventory_dir: Path, eval_dir: Path) -> Path:
    out_dir = run_dir / "filtered"
    summary_path = out_dir / "summary.json"
    variants_out = out_dir / "endpoint_variants.jsonl"
    if stage_done(summary_path, args.resume) and variants_out.exists():
        event("stage_skipped", stage="filter", reason="resume", output=display_path(out_dir))
        return out_dir
    if args.dry_run:
        event("stage_skipped", stage="filter", reason="dry_run")
        return out_dir

    variant_path = inventory_dir / "endpoint_variants.jsonl"
    eval_summary_path = eval_dir / "variant_summary.csv"
    specs_dir = eval_dir / "specs"
    out_specs_dir = out_dir / "specs"
    out_specs_dir.mkdir(parents=True, exist_ok=True)

    variants = load_jsonl(variant_path)
    summaries = load_eval_summary(eval_summary_path)
    summary_by_index = {row_index(row, position): row for position, row in enumerate(summaries, start=1)}

    survivor_variants: list[dict[str, Any]] = []
    survivor_summaries: list[dict[str, Any]] = []
    survivor_manifest: list[dict[str, Any]] = []
    removed_variants: list[dict[str, Any]] = []
    for position, variant in enumerate(variants, start=1):
        index = row_index(variant, position)
        eval_row = summary_by_index.get(index)
        if eval_row is None:
            raise RuntimeError(f"missing eval summary for variant index {index}")
        run_exit_code = int_field(eval_row, "run_exit_code")
        if run_exit_code != 0:
            removed_variants.append(
                {
                    "combined_index": index,
                    "openrouter_model_id": variant.get("openrouter_model_id"),
                    "provider_name": variant.get("provider_name"),
                    "endpoint_tag": variant.get("endpoint_tag"),
                    "quantization": variant.get("quantization"),
                    "reason": "run_exit_code",
                    "run_exit_code": run_exit_code,
                    "variant_status": eval_row.get("variant_status"),
                    "timeout_kind": eval_row.get("timeout_kind"),
                }
            )
            continue
        provider_errors = int_field(eval_row, "provider_error_count")
        score = float_field(eval_row, "deliberation_score")
        if provider_errors != args.filter_provider_error_count:
            removed_variants.append(
                {
                    "combined_index": index,
                    "openrouter_model_id": variant.get("openrouter_model_id"),
                    "provider_name": variant.get("provider_name"),
                    "endpoint_tag": variant.get("endpoint_tag"),
                    "quantization": variant.get("quantization"),
                    "reason": "provider_error_count",
                    "provider_error_count": provider_errors,
                }
            )
            continue
        if score is None or score < args.filter_min_deliberation_score:
            removed_variants.append(
                {
                    "combined_index": index,
                    "openrouter_model_id": variant.get("openrouter_model_id"),
                    "provider_name": variant.get("provider_name"),
                    "endpoint_tag": variant.get("endpoint_tag"),
                    "quantization": variant.get("quantization"),
                    "reason": "deliberation_score",
                    "deliberation_score": score,
                }
            )
            continue

        survivor = dict(variant)
        survivor["combined_index"] = index
        survivor["filter_provider_error_count"] = provider_errors
        survivor["filter_deliberation_score"] = score
        survivor_variants.append(survivor)

        summary_row = dict(eval_row)
        summary_row["combined_index"] = index
        summary_row["provider_error_count"] = provider_errors
        summary_row["deliberation_score"] = score
        survivor_summaries.append(summary_row)
        survivor_manifest.append(
            {
                "combined_index": index,
                "endpoint_variant_id": survivor.get("endpoint_variant_id"),
                "openrouter_model_id": survivor.get("openrouter_model_id"),
                "provider_name": survivor.get("provider_name"),
                "endpoint_tag": survivor.get("endpoint_tag"),
                "quantization": survivor.get("quantization"),
                "run_dir": eval_row.get("variant_run_dir") or eval_row.get("run_dir"),
            }
        )
        copy_spec_for_index(specs_dir, out_specs_dir, index)

    if not survivor_variants:
        raise RuntimeError("filter produced zero survivor variants")

    write_jsonl(out_dir / "endpoint_variants.jsonl", survivor_variants)
    write_jsonl(out_dir / "variant_summary.jsonl", survivor_summaries)
    write_jsonl(out_dir / "manifest.jsonl", survivor_manifest)
    write_jsonl(out_dir / "removed_variants.jsonl", removed_variants)

    fields = [
        "combined_index",
        "openrouter_model_id",
        "provider_name",
        "endpoint_tag",
        "quantization",
        "endpoint_variant_id",
        "filter_provider_error_count",
        "filter_deliberation_score",
    ]
    with (out_dir / "endpoint_variants.csv").open("w", newline="") as handle:
        writer = csv.DictWriter(handle, fieldnames=fields, extrasaction="ignore")
        writer.writeheader()
        writer.writerows(survivor_variants)

    summary = {
        "created_at": utc_now(),
        "source_variant_file": display_path(variant_path),
        "source_eval_summary_file": display_path(eval_summary_path),
        "source_specs_dir": display_path(specs_dir),
        "filter_criteria": {
            "provider_error_count": args.filter_provider_error_count,
            "deliberation_score_minimum": args.filter_min_deliberation_score,
        },
        "total_variants": len(variants),
        "survivor_count": len(survivor_variants),
        "survivor_combined_indexes": [row["combined_index"] for row in survivor_summaries],
        "removed_count": len(removed_variants),
        "removed_variant_indexes": [row["combined_index"] for row in removed_variants],
        "outputs": [
            "endpoint_variants.jsonl",
            "endpoint_variants.csv",
            "variant_summary.jsonl",
            "manifest.jsonl",
            "removed_variants.jsonl",
            "specs/*.json",
            "summary.json",
        ],
    }
    write_json(summary_path, summary)
    event("filter_finished", survivor_count=len(survivor_variants), output=display_path(out_dir))
    return out_dir


def selected_gene_indexes(args: argparse.Namespace) -> list[int]:
    if args.gene_index:
        seen: set[int] = set()
        indexes: list[int] = []
        for value in args.gene_index:
            if value not in seen:
                indexes.append(value)
                seen.add(value)
        return indexes
    return list(range(args.gene_count))


def run_genes(args: argparse.Namespace, run_dir: Path, filtered_dir: Path, commands_path: Path) -> dict[int, Path]:
    out: dict[int, Path] = {}
    survivor_count = line_count(filtered_dir / "endpoint_variants.jsonl")
    expected_records = survivor_count * args.samples_per_gene
    for gene_index in selected_gene_indexes(args):
        gene_dir = run_dir / "genes" / f"gene-{gene_index}"
        inference_dir = gene_dir / "inference"
        summary_path = inference_dir / "summary.json"
        records_path = inference_dir / "records.jsonl"
        out[gene_index] = inference_dir
        if completed_gene_summary(summary_path, args, expected_records):
            event("stage_skipped", stage="genes", gene_index=gene_index, reason="resume", output=display_path(inference_dir))
            continue
        cmd = [
            "uv",
            "run",
            "--script",
            "tools/run_first_gene_inference_embeddings.py",
            "--variants",
            display_path(filtered_dir / "endpoint_variants.jsonl"),
            "--genes",
            args.genes,
            "--persona",
            args.persona,
            "--samples",
            str(args.samples_per_gene),
            "--gene-index",
            str(gene_index),
            "--out",
            display_path(inference_dir),
            "--timeout",
            str(args.timeout),
            "--embedding-model",
            args.embedding_model,
            "--temperature",
            str(args.temperature),
            "--top-p",
            str(args.top_p),
            "--max-tokens",
            str(args.max_tokens),
            "--completion-attempts",
            str(args.completion_attempts),
            "--retry-sleep",
            str(args.retry_sleep),
        ]
        if args.resume and records_path.exists():
            cmd.append("--resume")
        run_command(cmd, cwd=ROOT, commands_path=commands_path, stage=f"genes:{gene_index}", dry_run=args.dry_run)
    return out


def validate_gene_summaries(args: argparse.Namespace, gene_dirs: dict[int, Path], survivor_count: int) -> int:
    expected = survivor_count * args.samples_per_gene
    embedding_counts: list[int] = []
    for gene_index, inference_dir in sorted(gene_dirs.items()):
        summary = load_json(inference_dir / "summary.json")
        completion_errors = int(summary.get("completion_error_count") or 0)
        embedding_errors = int(summary.get("embedding_error_count") or 0)
        if args.strict_gene_completions and (completion_errors or embedding_errors):
            raise RuntimeError(f"gene {gene_index}: completion or embedding errors present")
        if summary.get("records_written") != expected:
            raise RuntimeError(f"gene {gene_index}: expected {expected} records, found {summary.get('records_written')}")
        embedding_count = int(summary.get("embedding_count") or 0)
        if args.strict_gene_completions and embedding_count != expected:
            raise RuntimeError(f"gene {gene_index}: expected {expected} embeddings, found {summary.get('embedding_count')}")
        if embedding_count < 1:
            raise RuntimeError(f"gene {gene_index}: no usable embeddings")
        if completion_errors or embedding_errors:
            event(
                "gene_errors_allowed",
                gene_index=gene_index,
                completion_error_count=completion_errors,
                embedding_error_count=embedding_errors,
                embedding_count=embedding_count,
                expected_records=expected,
            )
        embedding_counts.append(embedding_count)
    if not embedding_counts:
        raise RuntimeError("no gene runs selected")
    min_embeddings = min(embedding_counts)
    if args.strict_pca_dimensions and args.pca_dimensions > min_embeddings:
        raise RuntimeError(f"--pca-dimensions {args.pca_dimensions} exceeds minimum embedding count {min_embeddings}")
    return min(args.pca_dimensions, min_embeddings)


def run_pca(args: argparse.Namespace, run_dir: Path, gene_dirs: dict[int, Path], pca_dimensions: int, commands_path: Path) -> dict[int, Path]:
    out: dict[int, Path] = {}
    for gene_index, inference_dir in sorted(gene_dirs.items()):
        pca_dir = run_dir / "genes" / f"gene-{gene_index}" / "pca"
        summary_path = pca_dir / "summary.json"
        out[gene_index] = pca_dir
        if stage_done(summary_path, args.resume):
            event("stage_skipped", stage="pca", gene_index=gene_index, reason="resume", output=display_path(pca_dir))
            continue
        cmd = [
            "uv",
            "run",
            "--script",
            "tools/run_embedding_pca.py",
            "--records",
            display_path(inference_dir / "records.jsonl"),
            "--out",
            display_path(pca_dir),
            "--dimensions",
            str(pca_dimensions),
        ]
        run_command(cmd, cwd=ROOT, commands_path=commands_path, stage=f"pca:{gene_index}", dry_run=args.dry_run)
    return out


def run_clustering(
    args: argparse.Namespace,
    run_dir: Path,
    pca_dirs: dict[int, Path],
    survivor_count: int,
    pca_dimensions: int,
    commands_path: Path,
) -> Path:
    out_dir = run_dir / "clusters"
    summary_path = out_dir / "summary.json"
    if stage_done(summary_path, args.resume):
        event("stage_skipped", stage="clusters", reason="resume", output=display_path(out_dir))
        return out_dir
    expected_rows = survivor_count * args.samples_per_gene
    cmd = [
        "uv",
        "run",
        "--script",
        "tools/run_gene_pca_clustering.py",
        "--out",
        display_path(out_dir),
        "--pca-dimensions",
        str(pca_dimensions),
        "--min-k",
        str(args.min_k),
        "--max-k",
        str(args.max_k),
    ]
    if args.strict_gene_completions:
        cmd.extend(
            [
                "--expected-rows-per-gene",
                str(expected_rows),
                "--expected-variants-per-gene",
                str(survivor_count),
                "--expected-samples-per-variant",
                str(args.samples_per_gene),
            ]
        )
    for _, pca_dir in sorted(pca_dirs.items()):
        cmd.extend(["--pca-records", display_path(pca_dir / "pca-records.jsonl")])
    run_command(cmd, cwd=ROOT, commands_path=commands_path, stage="clusters", dry_run=args.dry_run)
    return out_dir


def run_aggregate(args: argparse.Namespace, run_dir: Path, filtered_dir: Path, clusters_dir: Path, commands_path: Path) -> Path:
    out_dir = run_dir / "variant-persona-clusters"
    summary_path = out_dir / "summary.json"
    if stage_done(summary_path, args.resume):
        event("stage_skipped", stage="aggregate", reason="resume", output=display_path(out_dir))
        return out_dir
    cmd = [
        "uv",
        "run",
        "--script",
        "tools/aggregate_variant_persona_clusters.py",
        "--clusters",
        display_path(clusters_dir / "clusters.jsonl"),
        "--cluster-fit",
        display_path(clusters_dir / "cluster-fit.json"),
        "--variants",
        display_path(filtered_dir / "endpoint_variants.jsonl"),
        "--out",
        display_path(out_dir),
    ]
    if args.strict_gene_completions:
        cmd.extend(["--expected-samples-per-gene", str(args.samples_per_gene)])
    else:
        cmd.append("--allow-missing-gene-samples")
    run_command(cmd, cwd=ROOT, commands_path=commands_path, stage="aggregate", dry_run=args.dry_run)
    return out_dir


def run_pool(args: argparse.Namespace, run_dir: Path, aggregate_dir: Path, commands_path: Path) -> Path:
    out_dir = run_dir / "pool"
    pool_path = out_dir / "pool.jsonl"
    if stage_done(pool_path, args.resume):
        event("stage_skipped", stage="pool", reason="resume", output=display_path(out_dir))
        return out_dir
    cmd = [
        "uv",
        "run",
        "--script",
        "tools/sample-tuple-pool.py",
        display_path(aggregate_dir / "variant-persona-clusters.jsonl"),
        "--out",
        display_path(pool_path),
        "--diagnostics-out",
        display_path(out_dir / "diagnostics.jsonl"),
        "--equivalence-out",
        display_path(out_dir / "equivalence.jsonl"),
        "--pool-size",
        str(args.pool_size),
        "--seed",
        str(args.pool_seed),
    ]
    if args.no_dedupe_equivalent_endpoints:
        cmd.append("--no-dedupe-equivalent-endpoints")
    run_command(cmd, cwd=ROOT, commands_path=commands_path, stage="pool", dry_run=args.dry_run, stdout_path=out_dir / "sample.log")
    return out_dir


def should_stop(args: argparse.Namespace, stage: str) -> bool:
    return args.stop_after == stage


def collect_summary(run_dir: Path, pca_dimensions: int | None = None) -> dict[str, Any]:
    summary: dict[str, Any] = {
        "run_dir": display_path(run_dir),
        "updated_at": utc_now(),
    }
    paths = {
        "inventory": run_dir / "inventory" / "summary.json",
        "eval": run_dir / "eval" / "summary.json",
        "filtered": run_dir / "filtered" / "summary.json",
        "clusters": run_dir / "clusters" / "summary.json",
        "aggregate": run_dir / "variant-persona-clusters" / "summary.json",
    }
    for key, path in paths.items():
        if path.exists():
            summary[key] = load_json(path)
    pool_path = run_dir / "pool" / "pool.jsonl"
    diagnostics_path = run_dir / "pool" / "diagnostics.jsonl"
    equivalence_path = run_dir / "pool" / "equivalence.jsonl"
    if pool_path.exists():
        summary["pool"] = {
            "pool_path": display_path(pool_path),
            "diagnostics_path": display_path(diagnostics_path),
            "equivalence_path": display_path(equivalence_path),
            "pool_rows": line_count(pool_path),
            "diagnostic_rows": line_count(diagnostics_path),
            "equivalence_rows": line_count(equivalence_path),
        }
    gene_summaries = []
    for path in sorted((run_dir / "genes").glob("gene-*/inference/summary.json")):
        gene_summaries.append(load_json(path))
    if gene_summaries:
        summary["genes"] = gene_summaries
    pca_summaries = []
    for path in sorted((run_dir / "genes").glob("gene-*/pca/summary.json")):
        pca_summaries.append(load_json(path))
    if pca_summaries:
        summary["pca"] = pca_summaries
    if pca_dimensions is not None:
        summary["selected_pca_dimensions"] = pca_dimensions
    return summary


def build_manifest(args: argparse.Namespace, run_id: str, run_dir: Path) -> dict[str, Any]:
    return {
        "created_at": utc_now(),
        "run_id": run_id,
        "run_dir": display_path(run_dir),
        "stages": STAGES,
        "parameters": {
            "root_count": args.root_count,
            "root_seed": args.root_seed,
            "model_id": args.model_id,
            "questions": args.questions,
            "eval_trials": args.eval_trials,
            "filter_provider_error_count": args.filter_provider_error_count,
            "filter_min_deliberation_score": args.filter_min_deliberation_score,
            "genes": args.genes,
            "gene_count": args.gene_count,
            "gene_index": args.gene_index,
            "persona": args.persona,
            "samples_per_gene": args.samples_per_gene,
            "completion_attempts": args.completion_attempts,
            "retry_sleep": args.retry_sleep,
            "strict_gene_completions": args.strict_gene_completions,
            "pca_dimensions": args.pca_dimensions,
            "strict_pca_dimensions": args.strict_pca_dimensions,
            "min_k": args.min_k,
            "max_k": args.max_k,
            "pool_size": args.pool_size,
            "pool_seed": args.pool_seed,
            "no_dedupe_equivalent_endpoints": args.no_dedupe_equivalent_endpoints,
            "timeout": args.timeout,
            "eval_no_progress_timeout": args.eval_no_progress_timeout,
            "eval_variant_timeout": args.eval_variant_timeout,
        },
    }


def parse_args(argv: list[str]) -> argparse.Namespace:
    parser = argparse.ArgumentParser(description="Run the adjudication-evals endpoint-variant pool pipeline.")
    parser.add_argument("--run-id", default=None, help="Run id under --out-root. Default: e2e-<UTC timestamp>.")
    parser.add_argument("--out-root", default="results")
    parser.add_argument("--root-count", type=int, default=5)
    parser.add_argument("--root-seed", type=int, default=0)
    parser.add_argument("--model-id", action="append", help="Specific OpenRouter model id. May be repeated. Overrides --root-count sampling.")
    parser.add_argument("--inventory-request-timeout", type=int, default=60)
    parser.add_argument("--inventory-retries", type=int, default=2)
    parser.add_argument("--inventory-sleep", type=float, default=0.0)
    parser.add_argument("--questions", default="sets/core20/questions.jsonl")
    parser.add_argument("--eval-trials", type=int, default=1)
    parser.add_argument("--filter-provider-error-count", type=int, default=0)
    parser.add_argument("--filter-min-deliberation-score", type=float, default=0.90)
    parser.add_argument("--genes", default="sampled-genes.json")
    parser.add_argument("--gene-count", type=int, default=2)
    parser.add_argument("--gene-index", action="append", type=int, help="Specific gene index. May be repeated. Overrides --gene-count.")
    parser.add_argument("--persona", default="../common/etc/personas/generic.md")
    parser.add_argument("--samples-per-gene", type=int, default=1)
    parser.add_argument("--embedding-model", default="text-embedding-3-small")
    parser.add_argument("--temperature", type=float, default=0.7)
    parser.add_argument("--top-p", type=float, default=1.0)
    parser.add_argument("--max-tokens", type=int, default=512)
    parser.add_argument("--completion-attempts", type=int, default=3)
    parser.add_argument("--retry-sleep", type=float, default=2.0)
    parser.add_argument("--strict-gene-completions", action="store_true")
    parser.add_argument("--pca-dimensions", type=int, default=3)
    parser.add_argument("--strict-pca-dimensions", action="store_true")
    parser.add_argument("--min-k", type=int, default=2)
    parser.add_argument("--max-k", type=int, default=10)
    parser.add_argument("--pool-size", type=int, default=20)
    parser.add_argument("--pool-seed", type=int, default=0)
    parser.add_argument("--no-dedupe-equivalent-endpoints", action="store_true")
    parser.add_argument("--timeout", type=int, default=120)
    parser.add_argument("--eval-no-progress-timeout", type=int)
    parser.add_argument("--eval-variant-timeout", type=int)
    parser.add_argument("--resume", action="store_true")
    parser.add_argument("--dry-run", action="store_true")
    parser.add_argument("--stop-after", choices=STAGES)
    args = parser.parse_args(argv)

    if args.root_count < 1:
        raise SystemExit("--root-count must be positive")
    if args.eval_trials < 1:
        raise SystemExit("--eval-trials must be positive")
    if args.filter_provider_error_count < 0:
        raise SystemExit("--filter-provider-error-count cannot be negative")
    if args.gene_count < 1:
        raise SystemExit("--gene-count must be positive")
    if args.gene_index and any(index < 0 for index in args.gene_index):
        raise SystemExit("--gene-index values cannot be negative")
    if args.samples_per_gene < 1:
        raise SystemExit("--samples-per-gene must be positive")
    if args.completion_attempts < 1:
        raise SystemExit("--completion-attempts must be positive")
    if args.retry_sleep < 0:
        raise SystemExit("--retry-sleep cannot be negative")
    if args.pca_dimensions < 1:
        raise SystemExit("--pca-dimensions must be positive")
    if args.min_k < 2:
        raise SystemExit("--min-k must be at least 2")
    if args.max_k < args.min_k:
        raise SystemExit("--max-k must be greater than or equal to --min-k")
    if args.pool_size < 1:
        raise SystemExit("--pool-size must be positive")
    if args.timeout < 1:
        raise SystemExit("--timeout must be positive")
    if args.eval_no_progress_timeout is None:
        args.eval_no_progress_timeout = max(args.timeout * 2, 180)
    if args.eval_no_progress_timeout < 1:
        raise SystemExit("--eval-no-progress-timeout must be positive")
    if args.eval_variant_timeout is not None and args.eval_variant_timeout < args.eval_no_progress_timeout:
        raise SystemExit("--eval-variant-timeout must be greater than or equal to --eval-no-progress-timeout")
    return args


def main(argv: list[str]) -> int:
    args = parse_args(argv)
    run_id = args.run_id or f"e2e-{timestamp()}"
    run_dir = resolve_path(args.out_root) / run_id
    commands_path = run_dir / "commands.jsonl"
    summary_path = run_dir / "summary.json"

    if run_dir.exists() and not args.resume:
        raise SystemExit(f"{display_path(run_dir)} already exists; use --resume or a different --run-id")
    run_dir.mkdir(parents=True, exist_ok=True)
    write_json(run_dir / "manifest.json", build_manifest(args, run_id, run_dir))
    event("run_started", run_id=run_id, run_dir=display_path(run_dir), dry_run=args.dry_run)

    pca_dimensions: int | None = None
    try:
        inventory_dir = run_inventory(args, run_dir, commands_path)
        if should_stop(args, "inventory") or args.dry_run:
            write_json(summary_path, collect_summary(run_dir))
            return 0

        eval_dir = run_eval(args, run_dir, inventory_dir, commands_path)
        if should_stop(args, "eval"):
            write_json(summary_path, collect_summary(run_dir))
            return 0

        filtered_dir = filter_variants(args, run_dir, inventory_dir, eval_dir)
        if should_stop(args, "filter"):
            write_json(summary_path, collect_summary(run_dir))
            return 0

        survivor_count = int(load_json(filtered_dir / "summary.json")["survivor_count"])
        gene_dirs = run_genes(args, run_dir, filtered_dir, commands_path)
        if should_stop(args, "genes"):
            write_json(summary_path, collect_summary(run_dir))
            return 0

        pca_dimensions = validate_gene_summaries(args, gene_dirs, survivor_count)
        if pca_dimensions != args.pca_dimensions:
            event("pca_dimensions_capped", requested=args.pca_dimensions, selected=pca_dimensions)
        pca_dirs = run_pca(args, run_dir, gene_dirs, pca_dimensions, commands_path)
        if should_stop(args, "pca"):
            write_json(summary_path, collect_summary(run_dir, pca_dimensions))
            return 0

        clusters_dir = run_clustering(args, run_dir, pca_dirs, survivor_count, pca_dimensions, commands_path)
        if should_stop(args, "clusters"):
            write_json(summary_path, collect_summary(run_dir, pca_dimensions))
            return 0

        aggregate_dir = run_aggregate(args, run_dir, filtered_dir, clusters_dir, commands_path)
        if should_stop(args, "aggregate"):
            write_json(summary_path, collect_summary(run_dir, pca_dimensions))
            return 0

        run_pool(args, run_dir, aggregate_dir, commands_path)
        write_json(summary_path, collect_summary(run_dir, pca_dimensions))
        event("run_finished", run_id=run_id, run_dir=display_path(run_dir), summary=display_path(summary_path))
        return 0
    except Exception as exc:
        write_json(
            summary_path,
            {
                **collect_summary(run_dir, pca_dimensions),
                "failed_at": utc_now(),
                "error_type": type(exc).__name__,
                "error": str(exc),
            },
        )
        event("run_failed", run_id=run_id, error_type=type(exc).__name__, error=str(exc))
        raise


if __name__ == "__main__":
    raise SystemExit(main(sys.argv[1:]))
