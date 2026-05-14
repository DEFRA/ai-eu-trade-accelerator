import json
from datetime import UTC, datetime
from pathlib import Path
from typing import Any, Literal

import typer
from judit_domain import ReviewStatus
from rich.console import Console
from rich.panel import Panel

from .cli_progress import pipeline_progress, print_completion_summary_table
from .cli_run_summary import build_cli_completion_summary
from .corpus_run_estimate import estimate_corpus_run_from_case
from .demo import build_demo_bundle
from .equine_corpus_workflow import prepare_case_data_for_equine_corpus, run_equine_corpus_export
from .extraction_batch import (
    AnthropicBatchLLMClient,
    BatchJobStore,
    import_frontier_batch_results,
    plan_frontier_batch_for_case,
    PlannedExtractionRequest,
)
from .equine_source_universe import (
    estimate_summary_from_universe_offline,
    load_equine_source_universe,
    materialize_case_from_universe_path,
)
from .file_input import load_case_file
from .linting import lint_export_dir
from .operations import OperationalStore
from .operations_clear import (
    ClearOperationsConfirmationError,
    UnsafeExportDirError,
    execute_clear_operations_all,
    execute_clear_operations_runs_only,
    format_clear_report,
)
from .pipeline_reviews import append_pipeline_review_decision
from .reviews import parse_edited_fields_payload
from .run_comparison import compare_export_dirs, write_comparison_summary
from .run_quality import build_run_quality_summary
from .runner import (
    apply_assessment_review_decision,
    export_case_file,
    run_case_file,
    run_registry_sources,
)
from judit_llm.settings import LLMSettings
from .sources import SourceRegistryService

app = typer.Typer(help="Run file-backed Judit pipeline cases.")
console = Console()


def _effective_extraction_mode(case_data: dict, cli_mode: str | None) -> str:
    if cli_mode:
        return str(cli_mode).strip()
    cx = case_data.get("extraction") if isinstance(case_data.get("extraction"), dict) else {}
    return str(cx.get("mode") or "heuristic").strip()


def _large_legislation_universe_case(case_data: dict) -> bool:
    g = case_data.get("corpus_run_guard")
    if isinstance(g, dict) and str(g.get("tier") or "") == "full_universe":
        return True
    srcs = case_data.get("sources") or []
    if len(srcs) < 18:
        return False
    return all(
        isinstance(s, dict) and str(s.get("authority") or "") == "legislation_gov_uk" for s in srcs
    )


def _maybe_confirm_large_corpus_run(
    *,
    case_data: dict,
    use_llm: bool,
    extraction_mode: str | None,
    accept_large: bool,
    offline_chars_per_instrument: int = 95_000,
) -> None:
    if not use_llm or accept_large:
        return
    if _effective_extraction_mode(case_data, extraction_mode) != "frontier":
        return
    if not _large_legislation_universe_case(case_data):
        return
    est = estimate_corpus_run_from_case(
        case_data,
        extraction_mode="frontier",
        offline_chars_per_instrument=offline_chars_per_instrument,
    )
    console.print(
        Panel.fit(
            "[bold yellow]Large corpus run[/bold yellow]\n"
            "This case queues many full statutory bodies for frontier extraction — expect high cost "
            "and noise. Prefer staged profiles under examples/equine_*_case.json.\n\n"
            f"Offline sizing heuristic: ~{est['estimated_llm_invocations']} LLM calls (lower bound), "
            f"cost class: {est['cost_class']}, legislation sources: {est['source_count']}.",
            style="yellow",
        )
    )
    if not typer.confirm("Proceed with frontier extraction on this corpus?", default=False):
        raise typer.Abort()


@app.command("demo")
def demo(
    use_llm: bool = typer.Option(False, help="Route extraction/reasoning via LiteLLM."),
) -> None:
    bundle = build_demo_bundle(use_llm=use_llm)
    console.print(Panel.fit("Judit demo bundle", style="green"))
    console.print_json(json.dumps(bundle))


@app.command("run-case")
def run_case(
    case_path: str = typer.Argument(..., help="Path to the input case JSON file."),
    use_llm: bool = typer.Option(False, help="Route extraction/reasoning via LiteLLM."),
    extraction_mode: str | None = typer.Option(
        None,
        "--extraction-mode",
        help="Proposition extraction: heuristic | local | frontier (default: heuristic, or local with --use-llm).",
    ),
    extraction_execution_mode: str | None = typer.Option(
        None,
        "--extraction-execution-mode",
        help="interactive | batch (batch valid with extraction_mode=frontier).",
    ),
    extraction_fallback: str = typer.Option(
        "fallback",
        "--extraction-fallback",
        help="fallback | fail_closed | mark_needs_review",
    ),
    divergence_reasoning: str | None = typer.Option(
        None,
        "--divergence-reasoning",
        help="Divergence rationale: none | frontier (default: frontier with --use-llm).",
    ),
    source_cache_dir: str | None = typer.Option(
        None,
        "--source-cache-dir",
        help="Explicit source snapshot cache directory.",
    ),
    derived_cache_dir: str | None = typer.Option(
        None,
        "--derived-cache-dir",
        help="Explicit derived artifact cache directory.",
    ),
    quiet: bool = typer.Option(False, "--quiet", "-q", help="Suppress progress, summary table, and banner."),
    verbose: bool = typer.Option(
        False, "--verbose", "-v", help="Print extra per-source diagnostic lines during extraction."
    ),
    accept_large_corpus_run: bool = typer.Option(
        False,
        "--i-accept-large-corpus-run",
        help="Acknowledge frontier extraction over a very large legislation universe (skips confirmation).",
    ),
) -> None:
    case_payload = load_case_file(case_path)
    _maybe_confirm_large_corpus_run(
        case_data=case_payload,
        use_llm=use_llm,
        extraction_mode=extraction_mode,
        accept_large=accept_large_corpus_run,
    )
    with pipeline_progress(console, quiet=quiet, verbose=verbose) as progress:
        bundle = run_case_file(
            case_path=case_path,
            use_llm=use_llm,
            extraction_mode=extraction_mode,
            extraction_execution_mode=extraction_execution_mode,
            extraction_fallback=extraction_fallback,
            divergence_reasoning=divergence_reasoning,
            source_cache_dir=source_cache_dir,
            derived_cache_dir=derived_cache_dir,
            progress=progress,
        )
    if not quiet:
        quality = build_run_quality_summary(bundle)
        summary = build_cli_completion_summary(
            bundle, quality_summary=quality, output_dir=None
        )
        print_completion_summary_table(console, summary)
        console.print(Panel.fit(f"Ran case: {case_path}", style="green"))
    console.print_json(json.dumps(bundle))


@app.command("export-case")
def export_case(
    case_path: str = typer.Argument(..., help="Path to the input case JSON file."),
    output_dir: str = typer.Option(
        "dist/static-report",
        help="Directory for static bundle output.",
    ),
    use_llm: bool = typer.Option(False, help="Route extraction/reasoning via LiteLLM."),
    extraction_mode: str | None = typer.Option(
        None,
        "--extraction-mode",
        help="Proposition extraction: heuristic | local | frontier.",
    ),
    extraction_execution_mode: str | None = typer.Option(
        None,
        "--extraction-execution-mode",
        help="interactive | batch (batch valid with extraction_mode=frontier).",
    ),
    extraction_fallback: str = typer.Option(
        "fallback",
        "--extraction-fallback",
        help="fallback | fail_closed | mark_needs_review",
    ),
    divergence_reasoning: str | None = typer.Option(
        None,
        "--divergence-reasoning",
        help="none | frontier",
    ),
    source_cache_dir: str | None = typer.Option(
        None,
        "--source-cache-dir",
        help="Explicit source snapshot cache directory.",
    ),
    derived_cache_dir: str | None = typer.Option(
        None,
        "--derived-cache-dir",
        help="Explicit derived artifact cache directory.",
    ),
    quiet: bool = typer.Option(False, "--quiet", "-q", help="Suppress progress, summary table, and banner."),
    verbose: bool = typer.Option(
        False, "--verbose", "-v", help="Print extra per-source diagnostic lines during extraction."
    ),
    accept_large_corpus_run: bool = typer.Option(
        False,
        "--i-accept-large-corpus-run",
        help="Acknowledge frontier extraction over a very large legislation universe (skips confirmation).",
    ),
) -> None:
    case_payload = load_case_file(case_path)
    _maybe_confirm_large_corpus_run(
        case_data=case_payload,
        use_llm=use_llm,
        extraction_mode=extraction_mode,
        accept_large=accept_large_corpus_run,
    )
    with pipeline_progress(console, quiet=quiet, verbose=verbose) as progress:
        bundle = export_case_file(
            case_path=case_path,
            output_dir=output_dir,
            use_llm=use_llm,
            extraction_mode=extraction_mode,
            extraction_execution_mode=extraction_execution_mode,
            extraction_fallback=extraction_fallback,
            divergence_reasoning=divergence_reasoning,
            source_cache_dir=source_cache_dir,
            derived_cache_dir=derived_cache_dir,
            progress=progress,
        )
    if not quiet:
        rq = bundle.get("run_quality_summary")
        if not isinstance(rq, dict):
            rq = build_run_quality_summary(bundle)
        summary = build_cli_completion_summary(
            bundle, quality_summary=rq, output_dir=output_dir
        )
        print_completion_summary_table(console, summary)
        console.print(Panel.fit(f"Exported case: {case_path}", style="green"))
        console.print(f"Output directory: [bold]{output_dir}[/bold]")
        console.print(
            f"Assessments exported: [bold]{len(bundle['divergence_assessments'])}[/bold]"
        )


@app.command("estimate-corpus-run")
def estimate_corpus_run_cmd(
    universe_path: str = typer.Argument(..., help="Path to examples/equine_source_universe.json (or compatible)."),
    profile: str = typer.Option(
        ...,
        "--profile",
        help="Corpus profile id (e.g. equine_passport_identification_v0_1).",
    ),
    extraction_mode: str = typer.Option(
        "frontier",
        "--extraction-mode",
        help="frontier | local (for chunk / token planning).",
    ),
    offline_only: bool = typer.Option(
        False,
        "--offline-only",
        help="Universe member-count heuristic only (no ingest, no network).",
    ),
    fetch: bool = typer.Option(
        False,
        "--fetch",
        help="Fetch legislation.gov.uk XML for sizing (still no LLM). Default uses synthetic body sizing.",
    ),
    offline_chars: int = typer.Option(
        120_000,
        "--offline-chars-per-instrument",
        help="When not using --fetch: synthetic body characters per legislation source for ingest planning.",
    ),
) -> None:
    """Estimate fragments and LLM invocations — does not call model providers."""
    if offline_only:
        uni = load_equine_source_universe(universe_path)
        console.print_json(json.dumps(estimate_summary_from_universe_offline(uni, profile)))
        return
    case_data = materialize_case_from_universe_path(universe_path, profile)
    em = extraction_mode if extraction_mode in ("frontier", "local") else "frontier"
    est = estimate_corpus_run_from_case(
        case_data,
        extraction_mode=em,
        offline_chars_per_instrument=None if fetch else offline_chars,
    )
    console.print_json(json.dumps(est))


@app.command("plan-extraction-batch")
def plan_extraction_batch(
    case_path: str = typer.Argument(..., help="Path to case JSON."),
    export_dir: str = typer.Option("dist/static-report", "--export-dir"),
) -> None:
    case_data = load_case_file(case_path)
    settings = LLMSettings()
    extraction_cfg = case_data.get("extraction") if isinstance(case_data.get("extraction"), dict) else {}
    mode = str(extraction_cfg.get("mode") or "frontier")
    if mode != "frontier":
        raise typer.BadParameter("batch planning requires extraction.mode=frontier")
    planned = plan_frontier_batch_for_case(
        case_data=case_data,
        model_alias=settings.frontier_extract_model,
        source_cache_dir=None,
        derived_cache_dir=None,
        max_input_tokens=settings.max_extract_input_tokens,
        extract_model_context_limit=settings.extract_model_context_limit,
    )
    plan_id = f"plan-{Path(case_path).stem}"
    store = BatchJobStore(export_dir=export_dir)
    store.write_job(
        batch_job_id=plan_id,
        metadata={
            "batch_job_id": plan_id,
            "status": "planned",
            "submitted_at": None,
            "completed_at": None,
            "provider": "anthropic",
            "model_alias": settings.frontier_extract_model,
            "request_count": len(planned.requests),
            "estimated_input_tokens_total": sum(r.estimated_input_tokens for r in planned.requests),
            "source_count": planned.source_count,
            "fragment_count": planned.fragment_count,
        },
        requests=planned.requests,
    )
    console.print_json(
        json.dumps(
            {
                "batch_job_id": plan_id,
                "status": "planned",
                "request_count": len(planned.requests),
                "estimated_input_tokens_total": sum(r.estimated_input_tokens for r in planned.requests),
                "storage_dir": str(store.job_dir(plan_id)),
            }
        )
    )


@app.command("submit-extraction-batch")
def submit_extraction_batch(
    batch_job_id: str = typer.Argument(..., help="Batch job id from plan-extraction-batch."),
    export_dir: str = typer.Option("dist/static-report", "--export-dir"),
) -> None:
    store = BatchJobStore(export_dir=export_dir)
    job_dir = store.job_dir(batch_job_id)
    req_path = job_dir / "requests.json"
    if not req_path.is_file():
        raise typer.BadParameter(f"requests.json not found for {batch_job_id}")
    requests_raw = json.loads(req_path.read_text(encoding="utf-8"))
    requests = [PlannedExtractionRequest(**item) for item in requests_raw if isinstance(item, dict)]
    client = AnthropicBatchLLMClient()
    provider_batch_id = client.submit_batch(requests)
    meta = {
        "batch_job_id": batch_job_id,
        "provider_batch_job_id": provider_batch_id,
        "status": "submitted",
        "provider": "anthropic",
        "model_alias": requests[0].model_alias if requests else "",
        "request_count": len(requests),
        "estimated_input_tokens_total": sum(r.estimated_input_tokens for r in requests),
        "submitted_at": datetime.now(UTC).isoformat().replace("+00:00", "Z"),
    }
    (job_dir / "batch_job.json").write_text(json.dumps(meta, indent=2), encoding="utf-8")
    console.print_json(json.dumps(meta))


@app.command("poll-extraction-batch")
def poll_extraction_batch(
    batch_job_id: str = typer.Argument(..., help="Batch job id."),
    export_dir: str = typer.Option("dist/static-report", "--export-dir"),
    fetch_results: bool = typer.Option(True, "--fetch-results/--no-fetch-results"),
) -> None:
    store = BatchJobStore(export_dir=export_dir)
    job_dir = store.job_dir(batch_job_id)
    meta_path = job_dir / "batch_job.json"
    if not meta_path.is_file():
        raise typer.BadParameter(f"batch_job.json not found for {batch_job_id}")
    meta = json.loads(meta_path.read_text(encoding="utf-8"))
    provider_batch_id = str(meta.get("provider_batch_job_id") or "").strip()
    if not provider_batch_id:
        raise typer.BadParameter("provider_batch_job_id missing, submit first")
    client = AnthropicBatchLLMClient()
    status = client.get_batch_status(provider_batch_id)
    result_payload: dict[str, Any] = {"status": status}
    meta["provider_status"] = status.get("processing_status")
    if fetch_results and str(status.get("processing_status") or "").lower() == "ended":
        rows = client.fetch_batch_results(provider_batch_id)
        store.write_results(batch_job_id=batch_job_id, results=rows)
        meta["status"] = "results_available"
        meta["result_count"] = len(rows)
        meta["completed_at"] = datetime.now(UTC).isoformat().replace("+00:00", "Z")
        result_payload["result_count"] = len(rows)
    meta_path.write_text(json.dumps(meta, indent=2), encoding="utf-8")
    console.print_json(json.dumps(result_payload))


def _anthropic_result_text_by_request(rows: list[dict[str, Any]]) -> dict[str, str]:
    out: dict[str, str] = {}
    for row in rows:
        rid = str(row.get("custom_id") or "").strip()
        result = row.get("result") if isinstance(row.get("result"), dict) else {}
        message = result.get("message") if isinstance(result.get("message"), dict) else {}
        content = message.get("content") if isinstance(message.get("content"), list) else []
        text_parts: list[str] = []
        for item in content:
            if isinstance(item, dict) and str(item.get("type") or "") == "text":
                text_parts.append(str(item.get("text") or ""))
        if rid and text_parts:
            out[rid] = "\n".join(text_parts).strip()
    return out


@app.command("import-extraction-batch")
def import_extraction_batch(
    batch_job_id: str = typer.Argument(..., help="Batch job id with results.jsonl"),
    case_path: str = typer.Argument(..., help="Case JSON used for planning."),
    export_dir: str = typer.Option("dist/static-report", "--export-dir"),
    extraction_fallback: str = typer.Option("mark_needs_review", "--extraction-fallback"),
) -> None:
    store = BatchJobStore(export_dir=export_dir)
    job_dir = store.job_dir(batch_job_id)
    req_path = job_dir / "requests.json"
    results_path = job_dir / "results.jsonl"
    if not req_path.is_file() or not results_path.is_file():
        raise typer.BadParameter("requests.json and results.jsonl are required")
    req_rows = json.loads(req_path.read_text(encoding="utf-8"))
    requests = [PlannedExtractionRequest(**row) for row in req_rows if isinstance(row, dict)]
    results_raw = [
        json.loads(line)
        for line in results_path.read_text(encoding="utf-8").splitlines()
        if line.strip()
    ]
    provider_results = _anthropic_result_text_by_request([r for r in results_raw if isinstance(r, dict)])
    planned_case = plan_frontier_batch_for_case(
        case_data=load_case_file(case_path),
        model_alias=LLMSettings().frontier_extract_model,
    )
    usable_requests = [r for r in requests if r.request_id in planned_case.source_by_request_id]
    imported = import_frontier_batch_results(
        requests=usable_requests,
        provider_results=provider_results,
        source_by_request_id=planned_case.source_by_request_id,
        topic=planned_case.topic,
        cluster=planned_case.cluster,
        extraction_fallback=extraction_fallback,
    )
    console.print_json(
        json.dumps(
            {
                "batch_job_id": batch_job_id,
                "imported_proposition_count": len(imported.propositions),
                "failed_result_count": imported.failed_result_count,
                "validation_error_count": len(imported.validation_errors),
            }
        )
    )


@app.command("build-equine-corpus")
def build_equine_corpus(
    corpus_config: str = typer.Option(
        "examples/corpus_equine_law.json",
        "--corpus-config",
        help="Path to equine corpus configuration JSON.",
    ),
    output_dir: str = typer.Option(
        "dist/static-report",
        "--output-dir",
        help="Directory for static bundle and coverage artifacts.",
    ),
    use_llm: bool = typer.Option(
        False,
        help="Route extraction via LiteLLM (frontier mode requires a client; offline CI uses heuristic).",
    ),
    extraction_mode: str | None = typer.Option(
        None,
        "--extraction-mode",
        help="heuristic | local | frontier (default: corpus/case extraction.mode).",
    ),
    extraction_execution_mode: str | None = typer.Option(
        None,
        "--extraction-execution-mode",
        help="interactive | batch (batch valid with extraction_mode=frontier).",
    ),
    extraction_fallback: str | None = typer.Option(
        None,
        "--extraction-fallback",
        help="fallback | fail_closed | mark_needs_review (default: corpus/case fallback_policy).",
    ),
    divergence_reasoning: str | None = typer.Option(
        None,
        "--divergence-reasoning",
        help="none | frontier (default: frontier when use_llm).",
    ),
    source_cache_dir: str | None = typer.Option(None, "--source-cache-dir"),
    derived_cache_dir: str | None = typer.Option(None, "--derived-cache-dir"),
    quiet: bool = typer.Option(False, "--quiet", "-q"),
    verbose: bool = typer.Option(False, "--verbose", "-v"),
    accept_large_corpus_run: bool = typer.Option(
        False,
        "--i-accept-large-corpus-run",
        help="Acknowledge frontier extraction over a very large legislation universe (skips confirmation).",
    ),
) -> None:
    """Build equine law corpus export: discovery merge, extraction, bundle, coverage matrices."""
    case_data_preview, _cc, _cp = prepare_case_data_for_equine_corpus(corpus_config)
    _maybe_confirm_large_corpus_run(
        case_data=case_data_preview,
        use_llm=use_llm,
        extraction_mode=extraction_mode,
        accept_large=accept_large_corpus_run,
    )
    with pipeline_progress(console, quiet=quiet, verbose=verbose) as progress:
        bundle, cov_summary = run_equine_corpus_export(
            corpus_config_path=corpus_config,
            output_dir=output_dir,
            use_llm=use_llm,
            extraction_mode=extraction_mode,
            extraction_execution_mode=extraction_execution_mode,
            extraction_fallback=extraction_fallback,
            divergence_reasoning=divergence_reasoning,
            source_cache_dir=source_cache_dir,
            derived_cache_dir=derived_cache_dir,
            progress=progress,
        )
    if not quiet:
        console.print(
            Panel.fit(
                "[bold]Equine corpus — coverage status (pending review)[/bold]\n"
                "This workflow does not claim complete equine law. See artifact disclaimers.",
                style="cyan",
            )
        )
        console.print(
            f"Sources discovered (family candidates): [bold]{cov_summary['sources_discovered_candidates']}[/bold]"
        )
        console.print(
            f"Sources included (ingested): [bold]{cov_summary['sources_included_rows']}[/bold]"
        )
        console.print(
            f"Propositions — direct equine scope links: [bold]{cov_summary['propositions_direct_equine_scope']}[/bold]"
        )
        console.print(
            f"Propositions — indirect: [bold]{cov_summary['propositions_indirect_equine_scope']}[/bold] | "
            f"contextual: [bold]{cov_summary['propositions_contextual_equine_scope']}[/bold]"
        )
        console.print(
            f"Propositions — unreviewed (proposed): [bold]{cov_summary['propositions_unreviewed']}[/bold]"
        )
        console.print(
            f"Propositions — total: [bold]{cov_summary['propositions_total']}[/bold] | "
            f"guidance-ready: [bold]{cov_summary['guidance_ready_propositions']}[/bold]"
        )
        console.print(
            f"Pending legal candidates (discovery rows): [bold]{cov_summary['pending_legal_candidates']}[/bold]"
        )
        console.print(
            f"Lint warnings (total): [bold]{cov_summary.get('lint_warning_total', 0)}[/bold] "
            f"| by quality gate: [bold]{cov_summary.get('lint_warnings_by_quality_gate', {})}[/bold]"
        )
        console.print(
            f"Extraction traces — fallback method: [bold]{cov_summary.get('extraction_trace_fallback_method_count', 0)}[/bold] "
            f"| low confidence: [bold]{cov_summary.get('extraction_trace_low_confidence_count', 0)}[/bold]"
        )
        gaps = cov_summary.get("gaps_needing_manual_review") or []
        if gaps:
            console.print(
                f"Gaps / manual review hints ([bold]{len(gaps)}[/bold] shown, max 50):"
            )
            for line in gaps[:20]:
                console.print(f"  - {line}")
        console.print(
            f"Wrote [bold]equine_source_coverage.json[/bold], [bold]equine_proposition_coverage.json[/bold], "
            f"[bold]equine_corpus_readiness.json[/bold], CSV under [bold]{output_dir}[/bold]"
        )
        rq = bundle.get("run_quality_summary")
        if not isinstance(rq, dict):
            rq = build_run_quality_summary(bundle)
        summary = build_cli_completion_summary(
            bundle, quality_summary=rq, output_dir=output_dir
        )
        print_completion_summary_table(console, summary)
        console.print(Panel.fit("build-equine-corpus completed", style="green"))


@app.command("apply-assessment-review")
def apply_assessment_review(
    case_path: str = typer.Argument(..., help="Path to the input case JSON file."),
    assessment_id: str = typer.Argument(..., help="Assessment ID to review."),
    new_status: ReviewStatus = typer.Argument(..., help="New review status."),
    reviewer: str = typer.Option(..., "--reviewer", help="Reviewer identifier."),
    note: str = typer.Option("", "--note", help="Review note."),
    edited_fields_json: str | None = typer.Option(
        None,
        "--edited-fields-json",
        help="Optional JSON object of edited fields.",
    ),
    use_llm: bool = typer.Option(False, help="Route extraction/reasoning via LiteLLM."),
    extraction_mode: str | None = typer.Option(None, "--extraction-mode"),
    extraction_fallback: str = typer.Option("fallback", "--extraction-fallback"),
    divergence_reasoning: str | None = typer.Option(None, "--divergence-reasoning"),
    source_cache_dir: str | None = typer.Option(
        None,
        "--source-cache-dir",
        help="Explicit source snapshot cache directory.",
    ),
    derived_cache_dir: str | None = typer.Option(
        None,
        "--derived-cache-dir",
        help="Explicit derived artifact cache directory.",
    ),
) -> None:
    bundle = run_case_file(
        case_path=case_path,
        use_llm=use_llm,
        extraction_mode=extraction_mode,
        extraction_fallback=extraction_fallback,
        divergence_reasoning=divergence_reasoning,
        source_cache_dir=source_cache_dir,
        derived_cache_dir=derived_cache_dir,
    )
    updated_bundle = apply_assessment_review_decision(
        bundle=bundle,
        assessment_id=assessment_id,
        new_status=new_status.value,
        reviewer=reviewer,
        note=note,
        edited_fields=parse_edited_fields_payload(edited_fields_json),
    )
    updated_assessment = next(
        item for item in updated_bundle["divergence_assessments"] if item["id"] == assessment_id
    )
    decision = updated_bundle["review_decisions"][-1]
    console.print(Panel.fit(f"Applied review to: {assessment_id}", style="green"))
    console.print_json(json.dumps({"assessment": updated_assessment, "review_decision": decision}))


def _load_json_payload(reference_json: str | None, reference_file: str | None) -> dict[str, object]:
    if reference_json and reference_file:
        raise ValueError("Provide either --reference-json or --reference-file, not both.")
    if not reference_json and not reference_file:
        raise ValueError("Provide --reference-json or --reference-file.")
    if reference_json:
        payload = json.loads(reference_json)
    else:
        assert reference_file is not None
        payload = json.loads(Path(reference_file).read_text(encoding="utf-8"))
    if not isinstance(payload, dict):
        raise ValueError("Reference payload must be a JSON object.")
    return payload


def _split_csv(value: str) -> list[str]:
    return [item.strip() for item in value.split(",") if item.strip()]


@app.command("source-registry-list")
def source_registry_list(
    source_registry_path: str | None = typer.Option(
        None,
        "--source-registry-path",
        help="Path to local source registry JSON file.",
    ),
    source_cache_dir: str | None = typer.Option(
        None,
        "--source-cache-dir",
        help="Explicit source snapshot cache directory.",
    ),
) -> None:
    registry = SourceRegistryService(
        registry_path=source_registry_path,
        source_cache_dir=source_cache_dir,
    )
    console.print_json(json.dumps({"sources": registry.list_entries()}))


@app.command("source-registry-inspect")
def source_registry_inspect(
    registry_id: str = typer.Argument(..., help="Registry source ID."),
    source_registry_path: str | None = typer.Option(
        None,
        "--source-registry-path",
        help="Path to local source registry JSON file.",
    ),
    source_cache_dir: str | None = typer.Option(
        None,
        "--source-cache-dir",
        help="Explicit source snapshot cache directory.",
    ),
) -> None:
    registry = SourceRegistryService(
        registry_path=source_registry_path,
        source_cache_dir=source_cache_dir,
    )
    console.print_json(json.dumps(registry.inspect_entry(registry_id=registry_id)))


@app.command("source-registry-register")
def source_registry_register(
    reference_json: str | None = typer.Option(
        None,
        "--reference-json",
        help="JSON object with source reference fields.",
    ),
    reference_file: str | None = typer.Option(
        None,
        "--reference-file",
        help="Path to JSON file containing source reference fields.",
    ),
    refresh: bool = typer.Option(
        True,
        "--refresh/--no-refresh",
        help="Fetch/normalize immediately after registration.",
    ),
    source_registry_path: str | None = typer.Option(
        None,
        "--source-registry-path",
        help="Path to local source registry JSON file.",
    ),
    source_cache_dir: str | None = typer.Option(
        None,
        "--source-cache-dir",
        help="Explicit source snapshot cache directory.",
    ),
) -> None:
    payload = _load_json_payload(reference_json, reference_file)
    registry = SourceRegistryService(
        registry_path=source_registry_path,
        source_cache_dir=source_cache_dir,
    )
    entry = registry.register_reference(reference=payload, refresh=refresh)
    console.print_json(json.dumps(entry))


@app.command("source-registry-refresh")
def source_registry_refresh(
    registry_id: str = typer.Argument(..., help="Registry source ID."),
    source_registry_path: str | None = typer.Option(
        None,
        "--source-registry-path",
        help="Path to local source registry JSON file.",
    ),
    source_cache_dir: str | None = typer.Option(
        None,
        "--source-cache-dir",
        help="Explicit source snapshot cache directory.",
    ),
) -> None:
    registry = SourceRegistryService(
        registry_path=source_registry_path,
        source_cache_dir=source_cache_dir,
    )
    entry = registry.refresh_reference(registry_id=registry_id)
    console.print_json(json.dumps(entry))


@app.command("run-registry-sources")
def run_registry_sources_command(
    registry_ids: list[str] = typer.Option(
        ...,
        "--registry-id",
        help="Registry source ID. Repeat for multiple sources.",
    ),
    topic_name: str = typer.Option(..., "--topic-name", help="Run topic name."),
    cluster_name: str | None = typer.Option(
        None,
        "--cluster-name",
        help="Optional run cluster name.",
    ),
    analysis_mode: str = typer.Option(
        "auto",
        "--analysis-mode",
        help="auto, divergence, or single_jurisdiction.",
    ),
    analysis_scope: str = typer.Option(
        "selected_sources",
        "--analysis-scope",
        help="eu, uk, eu_uk, or selected_sources (registry tick list).",
    ),
    refresh_sources: bool = typer.Option(
        False,
        "--refresh-sources",
        help="Refresh registry sources before running analysis.",
    ),
    run_id: str | None = typer.Option(None, "--run-id", help="Explicit run ID."),
    run_notes: str = typer.Option("", "--run-notes", help="Optional run notes."),
    subject_tags_csv: str = typer.Option(
        "",
        "--subject-tags",
        help="Comma-separated topic subject tags.",
    ),
    comparison_jurisdiction_a: str | None = typer.Option(
        None,
        "--comparison-jurisdiction-a",
        help="Explicit jurisdiction_a override.",
    ),
    comparison_jurisdiction_b: str | None = typer.Option(
        None,
        "--comparison-jurisdiction-b",
        help="Explicit jurisdiction_b override.",
    ),
    proposition_index: int = typer.Option(
        0,
        "--proposition-index",
        help="Default proposition index for comparison pairing.",
    ),
    use_llm: bool = typer.Option(False, help="Route extraction/reasoning via LiteLLM."),
    extraction_mode: str | None = typer.Option(None, "--extraction-mode"),
    extraction_execution_mode: str | None = typer.Option(
        None,
        "--extraction-execution-mode",
        help="interactive | batch (batch valid with extraction_mode=frontier).",
    ),
    extraction_fallback: str = typer.Option("fallback", "--extraction-fallback"),
    divergence_reasoning: str | None = typer.Option(None, "--divergence-reasoning"),
    source_registry_path: str | None = typer.Option(
        None,
        "--source-registry-path",
        help="Path to local source registry JSON file.",
    ),
    source_cache_dir: str | None = typer.Option(
        None,
        "--source-cache-dir",
        help="Explicit source snapshot cache directory.",
    ),
    derived_cache_dir: str | None = typer.Option(
        None,
        "--derived-cache-dir",
        help="Explicit derived artifact cache directory.",
    ),
    focus_scopes_csv: str = typer.Option(
        "",
        "--focus-scopes",
        help="Comma-separated extraction focus scopes (optional).",
    ),
    max_propositions_per_source: int | None = typer.Option(
        None,
        "--max-propositions-per-source",
        help="Max propositions extracted per source (optional).",
    ),
) -> None:
    scopes = _split_csv(focus_scopes_csv)
    bundle = run_registry_sources(
        registry_ids=registry_ids,
        topic_name=topic_name,
        cluster_name=cluster_name,
        analysis_mode=analysis_mode,
        analysis_scope=analysis_scope,
        refresh_sources=refresh_sources,
        run_id=run_id,
        run_notes=run_notes,
        subject_tags=_split_csv(subject_tags_csv),
        comparison_jurisdiction_a=comparison_jurisdiction_a,
        comparison_jurisdiction_b=comparison_jurisdiction_b,
        proposition_index=proposition_index,
        use_llm=use_llm,
        extraction_mode=extraction_mode,
        extraction_execution_mode=extraction_execution_mode,
        extraction_fallback=extraction_fallback,
        divergence_reasoning=divergence_reasoning,
        source_registry_path=source_registry_path,
        source_cache_dir=source_cache_dir,
        derived_cache_dir=derived_cache_dir,
        focus_scopes=scopes if scopes else None,
        max_propositions_per_source=max_propositions_per_source,
    )
    console.print_json(json.dumps(bundle))


@app.command("list-runs")
def list_runs(
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Directory containing exported run artifacts.",
    ),
) -> None:
    store = OperationalStore(export_dir=export_dir)
    console.print_json(json.dumps({"runs": store.list_runs()}))


@app.command("inspect-run")
def inspect_run(
    run_id: str | None = typer.Option(
        None,
        "--run-id",
        help="Run ID to inspect. Defaults to latest exported run.",
    ),
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Directory containing exported run artifacts.",
    ),
) -> None:
    store = OperationalStore(export_dir=export_dir)
    console.print_json(json.dumps(store.inspect_run(run_id=run_id)))


@app.command("inspect-stage-traces")
def inspect_stage_traces(
    run_id: str | None = typer.Option(
        None,
        "--run-id",
        help="Run ID to inspect. Defaults to latest exported run.",
    ),
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Directory containing exported run artifacts.",
    ),
) -> None:
    store = OperationalStore(export_dir=export_dir)
    console.print_json(json.dumps(store.list_stage_traces(run_id=run_id)))


@app.command("list-run-review-decisions")
def list_run_review_decisions(
    run_id: str | None = typer.Option(
        None,
        "--run-id",
        help="Run ID to inspect. Defaults to latest exported run.",
    ),
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Directory containing exported run artifacts.",
    ),
) -> None:
    store = OperationalStore(export_dir=export_dir)
    console.print_json(json.dumps(store.list_review_decisions(run_id=run_id)))


@app.command("list-sources")
def list_sources(
    run_id: str | None = typer.Option(
        None,
        "--run-id",
        help="Run ID to inspect. Defaults to latest exported run.",
    ),
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Directory containing exported run artifacts.",
    ),
) -> None:
    store = OperationalStore(export_dir=export_dir)
    console.print_json(json.dumps(store.list_source_records(run_id=run_id)))


@app.command("list-source-target-links")
def list_source_target_links(
    run_id: str | None = typer.Option(
        None,
        "--run-id",
        help="Run ID to inspect. Defaults to latest exported run.",
    ),
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Directory containing exported run artifacts.",
    ),
) -> None:
    store = OperationalStore(export_dir=export_dir)
    console.print_json(json.dumps(store.list_source_target_links(run_id=run_id)))


@app.command("list-effective-source-target-links")
def list_effective_source_target_links_cmd(
    run_id: str | None = typer.Option(
        None,
        "--run-id",
        help="Run ID to inspect. Defaults to latest exported run.",
    ),
    source_record_id: str | None = typer.Option(
        None,
        "--source-record-id",
        help="Optional filter by source_record_id.",
    ),
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Directory containing exported run artifacts.",
    ),
) -> None:
    store = OperationalStore(export_dir=export_dir)
    console.print_json(
        json.dumps(
            store.list_effective_source_target_links(
                run_id=run_id,
                source_record_id=source_record_id,
            )
        )
    )


@app.command("list-effective-source-categorisation-rationales")
def list_effective_source_categorisation_rationales_cmd(
    run_id: str | None = typer.Option(
        None,
        "--run-id",
        help="Run ID to inspect. Defaults to latest exported run.",
    ),
    source_record_id: str | None = typer.Option(
        None,
        "--source-record-id",
        help="Optional filter by source_record_id.",
    ),
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Directory containing exported run artifacts.",
    ),
) -> None:
    store = OperationalStore(export_dir=export_dir)
    console.print_json(
        json.dumps(
            store.list_effective_source_categorisation_rationales(
                run_id=run_id,
                source_record_id=source_record_id,
            )
        )
    )


@app.command("list-effective-proposition-extraction-traces")
def list_effective_proposition_extraction_traces_cmd(
    run_id: str | None = typer.Option(
        None,
        "--run-id",
        help="Run ID to inspect. Defaults to latest exported run.",
    ),
    proposition_id: str | None = typer.Option(
        None,
        "--proposition-id",
        help="Optional filter by proposition_id.",
    ),
    source_record_id: str | None = typer.Option(
        None,
        "--source-record-id",
        help="Optional filter by source_record_id.",
    ),
    source_fragment_id: str | None = typer.Option(
        None,
        "--source-fragment-id",
        help="Optional filter by source_fragment_id.",
    ),
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Directory containing exported run artifacts.",
    ),
) -> None:
    store = OperationalStore(export_dir=export_dir)
    console.print_json(
        json.dumps(
            store.list_effective_proposition_extraction_traces(
                run_id=run_id,
                proposition_id=proposition_id,
                source_record_id=source_record_id,
                source_fragment_id=source_fragment_id,
            )
        )
    )


@app.command("list-source-fetch-attempts")
def list_source_fetch_attempts(
    run_id: str | None = typer.Option(
        None,
        "--run-id",
        help="Run ID to inspect. Defaults to latest exported run.",
    ),
    source_record_id: str | None = typer.Option(
        None,
        "--source-record-id",
        help="Optional source record filter.",
    ),
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Directory containing exported run artifacts.",
    ),
) -> None:
    store = OperationalStore(export_dir=export_dir)
    console.print_json(
        json.dumps(
            store.list_source_fetch_attempts(
                run_id=run_id,
                source_record_id=source_record_id,
            )
        )
    )


@app.command("inspect-source")
def inspect_source(
    source_id: str = typer.Argument(..., help="Source record ID."),
    run_id: str | None = typer.Option(
        None,
        "--run-id",
        help="Run ID to inspect. Defaults to latest exported run.",
    ),
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Directory containing exported run artifacts.",
    ),
) -> None:
    store = OperationalStore(export_dir=export_dir)
    console.print_json(json.dumps(store.inspect_source_record(source_id=source_id, run_id=run_id)))


@app.command("inspect-source-snapshots")
def inspect_source_snapshots(
    source_id: str = typer.Argument(..., help="Source record ID."),
    run_id: str | None = typer.Option(
        None,
        "--run-id",
        help="Run ID to inspect. Defaults to latest exported run.",
    ),
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Directory containing exported run artifacts.",
    ),
) -> None:
    store = OperationalStore(export_dir=export_dir)
    console.print_json(json.dumps(store.list_source_snapshots(source_id=source_id, run_id=run_id)))


@app.command("inspect-source-fragments")
def inspect_source_fragments(
    source_id: str = typer.Argument(..., help="Source record ID."),
    run_id: str | None = typer.Option(
        None,
        "--run-id",
        help="Run ID to inspect. Defaults to latest exported run.",
    ),
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Directory containing exported run artifacts.",
    ),
) -> None:
    store = OperationalStore(export_dir=export_dir)
    console.print_json(json.dumps(store.list_source_fragments(source_id=source_id, run_id=run_id)))


@app.command("list-propositions")
def list_propositions(
    run_id: str | None = typer.Option(
        None,
        "--run-id",
        help="Run ID to inspect. Defaults to latest exported run.",
    ),
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Directory containing exported run artifacts.",
    ),
) -> None:
    store = OperationalStore(export_dir=export_dir)
    console.print_json(json.dumps(store.list_propositions(run_id=run_id)))


@app.command("add-review-decision")
def add_review_decision(
    artifact_type: str = typer.Option(..., "--artifact-type", help="Pipeline artifact_type key."),
    artifact_id: str = typer.Option(..., "--artifact-id", help="Stable id of the artifact."),
    decision: str = typer.Option(
        ...,
        "--decision",
        help="approved | rejected | needs_review | overridden | deferred",
    ),
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Directory containing exported run artifacts.",
    ),
    run_id: str | None = typer.Option(None, "--run-id", help="Defaults to run.json id."),
    reviewer: str | None = typer.Option(None, "--reviewer"),
    reason: str = typer.Option("", "--reason"),
    applies_to_field: str | None = typer.Option(None, "--applies-to-field"),
    supersedes_decision_id: str | None = typer.Option(
        None,
        "--supersedes-decision-id",
        help="Optional id of a prior decision this row supersedes.",
    ),
    decision_id: str | None = typer.Option(
        None,
        "--decision-id",
        help="Optional explicit id (must be unique).",
    ),
) -> None:
    row = append_pipeline_review_decision(
        export_dir,
        run_id=run_id,
        artifact_type=artifact_type,
        artifact_id=artifact_id,
        decision=decision,
        reviewer=reviewer,
        reason=reason,
        applies_to_field=applies_to_field,
        supersedes_decision_id=supersedes_decision_id,
        decision_id=decision_id,
    )
    console.print_json(json.dumps(row))


@app.command("list-review-decisions")
def list_review_decisions_cmd(
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Directory containing exported run artifacts.",
    ),
    run_id: str | None = typer.Option(None, "--run-id"),
    artifact_type: str | None = typer.Option(None, "--artifact-type"),
    artifact_id: str | None = typer.Option(None, "--artifact-id"),
    decision: str | None = typer.Option(None, "--decision"),
) -> None:
    store = OperationalStore(export_dir=export_dir)
    payload = store.list_pipeline_review_decisions(
        run_id=run_id,
        artifact_type=artifact_type,
        artifact_id=artifact_id,
        decision=decision,
    )
    console.print_json(json.dumps(payload))


@app.command("compare-runs")
def compare_runs(
    baseline_export_dir: str = typer.Option(
        ...,
        "--baseline-export-dir",
        help="Directory containing baseline static export (flat bundle).",
    ),
    candidate_export_dir: str = typer.Option(
        ...,
        "--candidate-export-dir",
        help="Directory containing candidate static export.",
    ),
    write_summary: str | None = typer.Option(
        None,
        "--write-summary",
        help="Optional path to write run_comparison_summary.json.",
    ),
) -> None:
    summary = compare_export_dirs(
        baseline_export_dir=baseline_export_dir,
        candidate_export_dir=candidate_export_dir,
    )
    console.print_json(json.dumps(summary))
    if write_summary:
        write_comparison_summary(write_summary, summary)
    status = summary.get("status")
    if status == "regression":
        raise typer.Exit(code=1)
    if status == "inconclusive":
        raise typer.Exit(code=2)


@app.command("lint-export")
def lint_export(
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Directory containing exported run artifacts.",
    ),
    no_quality_summary: bool = typer.Option(
        False,
        "--no-quality-summary",
        help="Omit run_quality_summary from CLI output (lint only).",
    ),
) -> None:
    report = lint_export_dir(
        export_dir=export_dir,
        include_run_quality_summary=not no_quality_summary,
    )
    console.print_json(json.dumps(report))
    if not report.get("ok", False):
        raise typer.Exit(code=1)


@app.command("clear-operations-runs")
def clear_operations_runs(
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Operations export bundle directory.",
    ),
    dry_run: bool = typer.Option(False, "--dry-run", help="Print what would be deleted only."),
    confirm: bool = typer.Option(
        False,
        "--confirm",
        help="Required for destructive delete (unless --dry-run).",
    ),
    source_registry_path: str | None = typer.Option(
        None,
        "--source-registry-path",
        help="Registry JSON path used with the API/pipeline (default: temp dir judit/registry).",
    ),
) -> None:
    """Remove exported analysis bundles; keep registered sources in the registry file."""
    try:
        outcome = execute_clear_operations_runs_only(
            export_dir=export_dir,
            source_registry_path=source_registry_path,
            dry_run=dry_run,
            confirm=confirm,
        )
    except (ClearOperationsConfirmationError, UnsafeExportDirError) as exc:
        console.print(Panel.fit(str(exc), style="yellow"))
        raise typer.Exit(code=1) from exc

    console.print(format_clear_report(outcome))


@app.command("clear-operations-all")
def clear_operations_all(
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Operations export bundle directory.",
    ),
    dry_run: bool = typer.Option(False, "--dry-run", help="Print what would be deleted only."),
    confirm: bool = typer.Option(
        False,
        "--confirm",
        help="Required for destructive delete (unless --dry-run).",
    ),
    source_registry_path: str | None = typer.Option(
        None,
        "--source-registry-path",
        help="Registry JSON path to reset.",
    ),
    source_cache_dir: str | None = typer.Option(
        None,
        "--source-cache-dir",
        help="Source snapshot cache directory to clear.",
    ),
    derived_cache_dir: str | None = typer.Option(
        None,
        "--derived-cache-dir",
        help="Derived artifact cache directory to clear.",
    ),
) -> None:
    """Wipe export bundles, registry, source snapshots cache, and derived cache (development reset)."""
    try:
        outcome = execute_clear_operations_all(
            export_dir=export_dir,
            source_registry_path=source_registry_path,
            source_cache_dir=source_cache_dir,
            derived_cache_dir=derived_cache_dir,
            dry_run=dry_run,
            confirm=confirm,
        )
    except (ClearOperationsConfirmationError, UnsafeExportDirError) as exc:
        console.print(Panel.fit(str(exc), style="yellow"))
        raise typer.Exit(code=1) from exc

    console.print(format_clear_report(outcome))


@app.command("inspect-proposition-history")
def inspect_proposition_history(
    proposition_key: str = typer.Argument(..., help="Proposition lineage key."),
    include_runs: bool = typer.Option(
        True,
        "--include-runs/--no-include-runs",
        help="Aggregate observations across exported runs.",
    ),
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Directory containing exported run artifacts.",
    ),
) -> None:
    store = OperationalStore(export_dir=export_dir)
    console.print_json(
        json.dumps(
            store.proposition_history(
                proposition_key=proposition_key,
                include_runs=include_runs,
            )
        )
    )


@app.command("inspect-extraction-failures")
def inspect_extraction_failures(
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Exported static bundle directory (e.g. dist/static-report).",
    ),
) -> None:
    from .extraction_repair import summarize_extraction_inspection
    from .linting import load_exported_bundle

    bundle = load_exported_bundle(export_dir)
    console.print_json(json.dumps(summarize_extraction_inspection(bundle), indent=2))


@app.command("repair-extraction")
def repair_extraction(
    export_dir: str = typer.Option(
        "dist/static-report",
        "--export-dir",
        help="Source export bundle to repair.",
    ),
    output_dir: str | None = typer.Option(
        None,
        "--output-dir",
        help="Write repaired bundle here (required unless --in-place).",
    ),
    in_place: bool = typer.Option(
        False,
        "--in-place",
        help="Overwrite the export-dir bundle in place (destructive).",
    ),
    only: str = typer.Option(
        "repairable",
        "--only",
        help="repairable | all (re-run every extraction job)",
    ),
    extraction_mode: str = typer.Option("frontier", "--extraction-mode"),
    extraction_fallback: str = typer.Option(
        "mark_needs_review",
        "--extraction-fallback",
        help="fallback | fail_closed | mark_needs_review",
    ),
    use_llm: bool = typer.Option(True, "--use-llm/--no-use-llm"),
    retry_failed_llm: bool = typer.Option(
        True,
        "--retry-failed-llm/--no-retry-failed-llm",
        help="Bypass derived-cache entries for failed chunks and re-call the model.",
    ),
    source_cache_dir: str | None = typer.Option(None, "--source-cache-dir"),
    derived_cache_dir: str | None = typer.Option(None, "--derived-cache-dir"),
    quiet: bool = typer.Option(False, "--quiet", "-q"),
    verbose: bool = typer.Option(False, "--verbose", "-v"),
) -> None:
    from .extraction_repair import run_cli_repair_pipeline

    if only not in {"repairable", "all"}:
        raise typer.BadParameter("only must be repairable or all")

    lit_only: Literal["repairable", "all"] = (
        "repairable" if only == "repairable" else "all"
    )

    with pipeline_progress(console, quiet=quiet, verbose=verbose) as progress:
        bundle = run_cli_repair_pipeline(
            export_dir=Path(export_dir),
            output_dir=Path(output_dir) if output_dir else None,
            extraction_mode=extraction_mode,
            extraction_fallback=extraction_fallback,
            only=lit_only,
            in_place=in_place,
            retry_failed_llm=retry_failed_llm,
            source_cache_dir=source_cache_dir,
            derived_cache_dir=derived_cache_dir,
            use_llm=use_llm,
            progress=progress,
        )
    meta = bundle.get("extraction_repair_metadata") or {}
    console.print(Panel.fit("Repair complete", style="green"))
    console.print(json.dumps(meta, indent=2))
    rq = bundle.get("run_quality_summary")
    if isinstance(rq, dict):
        console.print(json.dumps({"run_quality_summary": rq}, indent=2))


def demo_command() -> None:
    demo(use_llm=False)


def run_case_command() -> None:
    app(["run-case"])


def export_case_command() -> None:
    app(["export-case"])
