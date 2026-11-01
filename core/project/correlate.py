"""Cross-run correlation for /project correlate.

Aggregates findings and tool coverage across all runs in a project to
produce: disagreements, new/resolved findings, tool gaps, persistent
findings, and trends. Pure Python, no LLM calls.

Output is action-oriented: every section answers "what should I look at next?"
"""

from collections import defaultdict
from pathlib import Path
from typing import Any

from core.json import load_json
from core.run import load_run_metadata

from .anchor_join import (
    AnchorJoin,
    build_anchor_join,
    load_project_span_index,
)
from .findings_utils import (
    finding_file,
    load_findings_from_dir,
    safe_run_mtime,
)

# --- Status normalization ---

POSITIVE_VERDICTS = frozenset({
    "exploitable", "confirmed", "confirmed_unverified",
    "confirmed_constrained", "confirmed_blocked", "poc_success",
    "validated",
})

NEGATIVE_VERDICTS = frozenset({
    "ruled_out", "disproven", "false_positive",
    "test_code", "dead_code", "mitigated", "unreachable",
})

INCONCLUSIVE_VERDICTS = frozenset({
    "not_disproven",
})

SCAN_COMMAND_TYPES = frozenset({"scan", "codeql"})
LLM_COMMAND_TYPES = frozenset({"agentic", "validate"})


def normalize_verdict(status: str) -> str:
    s = (status or "").strip().lower()
    if s in POSITIVE_VERDICTS:
        return "positive"
    if s in NEGATIVE_VERDICTS:
        return "negative"
    if s in INCONCLUSIVE_VERDICTS:
        return "inconclusive"
    return "unknown"


def get_finding_status(finding: dict) -> str:
    if "is_true_positive" in finding or "is_exploitable" in finding:
        if finding.get("is_true_positive") is False:
            return "false_positive"
        if finding.get("is_exploitable") is True:
            return "exploitable"
        if finding.get("is_true_positive") is True:
            return "confirmed"
    return finding.get("final_status") or finding.get("status") or ""


# --- Main entry point ---


def correlate_sandbox_triage(
    run_dirs: list[Path],
) -> dict[str, Any] | None:
    """Correlate authenticated denial signatures; see sandbox_campaign."""
    from .sandbox_campaign import correlate_campaign

    return correlate_campaign(run_dirs)


def correlate_project(project) -> dict[str, Any]:
    """Correlate findings and coverage across all runs in a project.

    Returns an action-oriented result: disagreements first, then new/resolved
    findings, tool gaps, and finally the existing persistent/trends/coverage.
    """
    run_dirs = project.get_run_dirs(sweep=False)
    if not run_dirs:
        return _empty_result()

    run_models = {d.name: _get_run_model(d) for d in run_dirs}
    run_types = _get_run_types(run_dirs)
    findings_by_run = _load_all_findings(run_dirs)

    # Anchor-identity join: one site key per defect across anchor
    # drift, synthetic-scope name variants, and explicit lineage
    # notes (see core.project.anchor_join). Recency ranks feed only
    # the canonical-anchor tie-break.
    recency = {d.name: i for i, d
               in enumerate(sorted(run_dirs, key=safe_run_mtime))}
    span_index = load_project_span_index(project, run_dirs)
    join = build_anchor_join(findings_by_run, span_index, recency)

    # Existing
    persistent = _find_persistent(findings_by_run, run_models, join=join)
    trends = _build_trends(findings_by_run, run_dirs, run_models, join=join)
    tool_coverage = _build_tool_coverage(run_dirs)

    # New actionable analyses
    disagreements = _find_disagreements(findings_by_run, run_models,
                                        join=join)
    new_resolved = _find_new_and_resolved(findings_by_run, run_dirs,
                                          run_types, join=join)
    tool_gaps = _build_tool_gaps(run_dirs, findings_by_run, run_types,
                                 join=join)
    token_drift = _find_token_drift(run_dirs)
    actions = _build_action_list(
        disagreements, new_resolved, tool_gaps, persistent,
        join_uncertain=join.uncertain_pairs,
    )

    n_persistent = len(persistent)
    n_total_unique = join.site_count()

    sandbox_campaign = correlate_sandbox_triage(run_dirs)

    result = {
        "actions": actions,
        "join": _join_summary(join),
        "disagreements": disagreements,
        "new_findings": new_resolved["new_findings"],
        "potentially_resolved": new_resolved["potentially_resolved"],
        "tool_gaps": tool_gaps,
        "persistent_findings": persistent,
        "tool_coverage": tool_coverage,
        "trends": trends,
        "token_enforcement_drift": token_drift,
        "summary": {
            "runs": len(run_dirs),
            "total_unique_findings": n_total_unique,
            "persistent_findings": n_persistent,
            "tools_used": sorted(tool_coverage.keys()),
            "disagreements": len(disagreements),
            "new_findings": len(new_resolved["new_findings"]),
            "potentially_resolved": len(new_resolved["potentially_resolved"]),
            "token_enforcement_drift": len(token_drift),
        },
    }
    if sandbox_campaign is not None:
        result["sandbox_campaign"] = sandbox_campaign
        result["summary"]["sandbox_campaign_severity"] = (  # type: ignore[index]
            sandbox_campaign["campaign_severity"]
        )
    return result


def _join_summary(join: AnchorJoin) -> dict[str, Any]:
    """Operator-facing join facts: every multi-anchor site plus the
    flagged (NOT joined) uncertain pairs awaiting a human."""
    return {
        "multi_anchor_sites": join.multi_anchor_sites(),
        "uncertain_pairs": join.uncertain_pairs,
        "uncertain_total": join.uncertain_total,
    }


def _empty_result() -> dict[str, Any]:
    return {
        "actions": [],
        "join": {
            "multi_anchor_sites": [],
            "uncertain_pairs": [],
            "uncertain_total": 0,
        },
        "disagreements": [],
        "new_findings": [],
        "potentially_resolved": [],
        "tool_gaps": {
            "scanned_not_validated": [],
            "validated_not_scanned": [],
            "missing_command_types": [],
            "suggested_next_runs": [],
        },
        "persistent_findings": [],
        "tool_coverage": {},
        "trends": {},
        "token_enforcement_drift": [],
        "summary": {
            "runs": 0,
            "total_unique_findings": 0,
            "persistent_findings": 0,
            "tools_used": [],
            "disagreements": 0,
            "new_findings": 0,
            "potentially_resolved": 0,
            "token_enforcement_drift": 0,
        },
    }


# --- Helpers ---

def _load_orchestrated_report(run_dir: Path) -> Any:
    """Budgeted read of a run's ``orchestrated_report.json``.

    The report lives in the sandbox-writable run dir and correlate
    loads one per run — an oversize plant degrades to None (findings
    fall back to the size-gated findings.json path) instead of
    buffering unbounded.
    """
    from core.coverage.record import RUN_ARTIFACT_MAX_BYTES
    return load_json(run_dir / "orchestrated_report.json",
                     max_bytes=RUN_ARTIFACT_MAX_BYTES)


def _get_run_model(run_dir: Path) -> str:
    """Extract the analysis model name for a run."""
    orch = _load_orchestrated_report(run_dir)
    if orch and isinstance(orch, dict):
        o = orch.get("orchestration") or {}
        models = o.get("analysis_models") or []
        if models:
            return ", ".join(models)
        m = o.get("analysis_model")
        if m:
            return m
    meta = load_run_metadata(run_dir)
    if isinstance(meta, dict):
        extra = meta.get("extra") or {}
        models = extra.get("analysis_models") or []
        if models:
            return ", ".join(models)
        m = extra.get("analysis_model")
        if m:
            return m
    return ""


def _get_run_types(run_dirs: list[Path]) -> dict[str, str]:
    """Map run dir name -> command type (scan, agentic, validate, etc.)."""
    result = {}
    for d in run_dirs:
        meta = load_run_metadata(d)
        result[d.name] = (meta if isinstance(meta, dict) else {}).get("command", "unknown")
    return result


def _load_all_findings(
    run_dirs: list[Path],
) -> dict[str, list[dict[str, Any]]]:
    """Load findings from each run dir, keyed by run dir name.

    Prefers orchestrated_report.json results (which have analysed_by and
    multi_model_analyses) over plain findings.json.
    """
    result = {}
    for d in run_dirs:
        orch = _load_orchestrated_report(d)
        if orch and isinstance(orch, dict):
            findings = orch.get("results", [])
            if findings:
                result[d.name] = findings
                continue
        findings = load_findings_from_dir(d)
        if findings:
            result[d.name] = findings
    return result


# --- Disagreement detection ---

def _find_disagreements(
    findings_by_run: dict[str, list[dict]],
    run_models: dict[str, str],
    join: AnchorJoin | None = None,
) -> list[dict[str, Any]]:
    """Find findings where runs disagree on verdict (positive vs negative)."""
    join = join or build_anchor_join(findings_by_run)
    key_to_verdicts: dict[tuple, list[dict]] = defaultdict(list)

    for run_name, findings in findings_by_run.items():
        for i, f in enumerate(findings):
            k = join.key_for(run_name, i)
            status = get_finding_status(f)
            if not status:
                continue
            verdict = normalize_verdict(status)
            if verdict == "unknown":
                continue
            model = f.get("analysed_by") or run_models.get(run_name, "")
            key_to_verdicts[k].append({
                "run": run_name,
                "status": status,
                "verdict": verdict,
                "model": model,
                "score": f.get("exploitability_score")
                         if f.get("exploitability_score") is not None
                         else f.get("cvss_score_estimate"),
            })

    disagreements = []
    for k, verdicts in key_to_verdicts.items():
        verdict_set = {v["verdict"] for v in verdicts}
        if "positive" in verdict_set and "negative" in verdict_set:
            dtype = "positive_vs_negative"
        elif "positive" in verdict_set and "inconclusive" in verdict_set:
            dtype = "positive_vs_inconclusive"
        else:
            continue

        f = join.finding_for(k)
        scores = [v["score"] for v in verdicts if v["score"] is not None]
        disagreements.append(join.annotate({
            "file": k[0],
            "function": k[1],
            "line": k[2],
            "vuln_type": f.get("vuln_type", ""),
            "verdicts": verdicts,
            "disagreement_type": dtype,
            "max_score": max(scores) if scores else 0,
        }, k))

    disagreements.sort(key=lambda d: (
        0 if d["disagreement_type"] == "positive_vs_negative" else 1,
        -(d["max_score"] or 0),
    ))
    return disagreements


# --- New / resolved detection ---

def _find_new_and_resolved(
    findings_by_run: dict[str, list[dict]],
    run_dirs: list[Path],
    run_types: dict[str, str],
    join: AnchorJoin | None = None,
) -> dict[str, list[dict]]:
    """Detect findings that appeared or disappeared across runs.

    Only compares runs of the same command type — a finding in scan-001
    but absent from validate-001 is expected, not "resolved."
    """
    join = join or build_anchor_join(findings_by_run)
    run_order = [d.name for d in sorted(run_dirs, key=safe_run_mtime)]

    key_to_runs_by_type: dict[tuple, dict[str, list[str]]] = defaultdict(
        lambda: defaultdict(list),
    )

    for run_name, findings in findings_by_run.items():
        cmd_type = run_types.get(run_name, "unknown")
        for i, _f in enumerate(findings):
            k = join.key_for(run_name, i)
            key_to_runs_by_type[k][cmd_type].append(run_name)

    new_findings = []
    potentially_resolved = []

    for k, type_runs in key_to_runs_by_type.items():
        f = join.finding_for(k)
        for cmd_type, runs in type_runs.items():
            typed_order = [r for r in run_order if run_types.get(r) == cmd_type]
            if len(typed_order) < 2:
                continue

            earliest = typed_order[0]
            latest = typed_order[-1]

            first_run = min(runs, key=lambda r: (
                run_order.index(r) if r in run_order else 999
            ))
            if first_run != earliest:
                status = get_finding_status(f)
                new_findings.append(join.annotate({
                    "file": k[0],
                    "function": k[1],
                    "line": k[2],
                    "vuln_type": f.get("vuln_type", ""),
                    "status": status,
                    "verdict": normalize_verdict(status),
                    "first_seen_run": first_run,
                    "command_type": cmd_type,
                }, k))

            if latest not in runs:
                last_run = max(runs, key=lambda r: (
                    run_order.index(r) if r in run_order else 0
                ))
                absent = [
                    r for r in typed_order
                    if r not in runs
                    and run_order.index(r) > run_order.index(last_run)
                ]
                potentially_resolved.append(join.annotate({
                    "file": k[0],
                    "function": k[1],
                    "line": k[2],
                    "vuln_type": f.get("vuln_type", ""),
                    "last_seen_run": last_run,
                    "absent_from": absent,
                    "command_type": cmd_type,
                }, k))

    new_findings.sort(key=lambda n: (
        0 if n["verdict"] == "positive" else 1,
    ))
    return {"new_findings": new_findings, "potentially_resolved": potentially_resolved}


# --- Tool gap analysis ---

def _build_tool_gaps(
    _run_dirs: list[Path],
    findings_by_run: dict[str, list[dict]],
    run_types: dict[str, str],
    join: AnchorJoin | None = None,
) -> dict[str, Any]:
    """Identify coverage gaps between scan tools and LLM analysis."""
    join = join or build_anchor_join(findings_by_run)
    scan_files: dict[str, set] = defaultdict(set)
    llm_files: dict[str, set] = defaultdict(set)

    for run_name, findings in findings_by_run.items():
        cmd = run_types.get(run_name, "unknown")
        for i, f in enumerate(findings):
            # finding_file handles both scan-shaped (`file`) and
            # orchestrated (`file_path`) findings — pre-fix agentic
            # findings were silently skipped here, so LLM coverage
            # never registered and every scanned file looked
            # "never LLM-validated".
            fp = finding_file(f)
            if not fp:
                continue
            k = join.key_for(run_name, i)
            if cmd in SCAN_COMMAND_TYPES:
                scan_files[fp].add(k)
            elif cmd in LLM_COMMAND_TYPES:
                llm_files[fp].add(k)

    scanned_not_validated = []
    for fp in sorted(scan_files.keys() - llm_files.keys()):
        n = len(scan_files[fp])
        scanned_not_validated.append({
            "file": fp,
            "finding_count": n,
        })

    validated_not_scanned = sorted(llm_files.keys() - scan_files.keys())

    types_present = set(run_types.values())
    missing = []
    if not types_present & SCAN_COMMAND_TYPES:
        missing.append("scan")
    if not types_present & LLM_COMMAND_TYPES:
        missing.append("validate")

    suggested = []
    if scanned_not_validated:
        n = sum(item["finding_count"] for item in scanned_not_validated)  # type: ignore[misc]
        suggested.append(
            f"raptor validate  # {n} unvalidated scan finding"
            f"{'s' if n != 1 else ''}"
        )
    if validated_not_scanned:
        suggested.append(
            f"raptor scan  # {len(validated_not_scanned)} file"
            f"{'s' if len(validated_not_scanned) != 1 else ''}"
            f" with LLM findings but no static analysis"
        )
    suggested.extend(f"raptor {cmd}  # no {cmd} runs found" for cmd in missing)

    return {
        "scanned_not_validated": scanned_not_validated,
        "validated_not_scanned": [{"file": fp} for fp in validated_not_scanned],
        "missing_command_types": missing,
        "suggested_next_runs": suggested,
    }


# --- Action list ---

def _anchor_label(pair: dict[str, Any]) -> str:
    """Compact ``file:lineA/lineB`` label for an uncertain pair."""
    anchors = pair.get("anchors") or []
    if not anchors:
        return "?"
    lines = "/".join(str(a.get("line", 0)) for a in anchors)
    return f"{anchors[0].get('file', '?')}:{lines}"


def _build_action_list(
    disagreements: list[dict],
    new_resolved: dict[str, list[dict]],
    tool_gaps: dict[str, Any],
    _persistent: list[dict],
    join_uncertain: list[dict] | None = None,
) -> list[dict[str, Any]]:
    """Synthesize all analyses into a single prioritised action list."""
    actions: list[dict[str, Any]] = []

    for d in disagreements:
        pos = [v for v in d["verdicts"] if v["verdict"] == "positive"]
        neg = [v for v in d["verdicts"] if v["verdict"] == "negative"]
        inc = [v for v in d["verdicts"] if v["verdict"] == "inconclusive"]
        if d["disagreement_type"] == "positive_vs_negative":
            summary = (
                f"{d['file']}:{d['line']} ({d['vuln_type']}) — "
                f"{len(pos)} positive vs {len(neg)} negative verdict"
                f"{'s' if len(neg) != 1 else ''}"
            )
            priority = 1
        else:
            summary = (
                f"{d['file']}:{d['line']} ({d['vuln_type']}) — "
                f"{len(pos)} positive vs {len(inc)} inconclusive"
            )
            priority = 4
        actions.append({
            "priority": priority,
            "category": "disagreement",
            "summary": summary,
            "detail": d,
        })

    actions.extend({
            "priority": 2 if nf["verdict"] == "positive" else 6,
            "category": "new_finding",
            "summary": (
                f"{nf['file']}:{nf['line']} ({nf['vuln_type']}) — "
                f"new in {nf['first_seen_run']}"
            ),
            "detail": nf,
        } for nf in new_resolved.get("new_findings", []))

    actions.extend({
            "priority": 3,
            "category": "tool_gap",
            "summary": (
                f"{gap['file']} — {gap['finding_count']} scan finding"
                f"{'s' if gap['finding_count'] != 1 else ''}"
                f" never LLM-validated"
            ),
            "detail": gap,
        } for gap in tool_gaps.get("scanned_not_validated", []))

    # Anchor pairs the join declined (uncertainty is never a join) —
    # each needs a human same-or-distinct call, like the manual
    # dedupe pass this machinery replaces.
    actions.extend({
            "priority": 5,
            "category": "join_uncertain",
            "summary": (
                f"{_anchor_label(pair)} — possible same defect "
                f"({pair.get('reason', '')}); needs manual adjudication"
            ),
            "detail": pair,
        } for pair in (join_uncertain or []))

    actions.extend({
            "priority": 5,
            "category": "resolved",
            "summary": (
                f"{r['file']}:{r['line']} ({r['vuln_type']}) — "
                f"absent from latest {r['command_type']} run"
            ),
            "detail": r,
        } for r in new_resolved.get("potentially_resolved", []))

    actions.extend({
            "priority": 7,
            "category": "tool_gap",
            "summary": f"No {cmd} runs found",
            "command": f"raptor {cmd}",
            "detail": {"missing": cmd},
        } for cmd in tool_gaps.get("missing_command_types", []))

    actions.sort(key=lambda a: a["priority"])
    return actions


# --- Existing analyses (persistent, trends, coverage) ---

def _find_persistent(
    findings_by_run: dict[str, list[dict]],
    run_models: dict[str, str],
    join: AnchorJoin | None = None,
) -> list[dict[str, Any]]:
    """Find findings that appear across 2+ runs."""
    join = join or build_anchor_join(findings_by_run)
    # Unique runs per site: a joined site can carry several anchors
    # from ONE run, which must not inflate runs_seen.
    key_to_runs: dict[tuple, set] = defaultdict(set)
    key_to_models: dict[tuple, set] = defaultdict(set)

    for run_name, findings in findings_by_run.items():
        for i, f in enumerate(findings):
            k = join.key_for(run_name, i)
            key_to_runs[k].add(run_name)
            model = f.get("analysed_by") or run_models.get(run_name, "")
            if model:
                key_to_models[k].add(model)

    persistent = []
    for k, runs in sorted(key_to_runs.items(),
                          key=lambda x: (-len(x[1]), x[0])):
        if len(runs) < 2:
            continue
        f = join.finding_for(k)
        persistent.append(join.annotate({
            "file": k[0],
            "function": k[1],
            "line": k[2],
            "vuln_type": f.get("vuln_type", ""),
            "status": f.get("final_status") or f.get("status", ""),
            "runs_seen": len(runs),
            "run_names": sorted(runs),
            "models": sorted(key_to_models.get(k, set())),
        }, k))

    return persistent


def _build_trends(
    findings_by_run: dict[str, list[dict]],
    run_dirs: list[Path],
    run_models: dict[str, str],
    join: AnchorJoin | None = None,
) -> dict[str, list[dict[str, Any]]]:
    """Track how each finding's status changed across runs.

    Returns {finding_label: [{run, status, score, model}]} ordered by run time.
    """
    join = join or build_anchor_join(findings_by_run)
    run_order = [d.name for d in sorted(run_dirs, key=safe_run_mtime)]

    key_to_history: dict[tuple, list[dict]] = defaultdict(list)
    for run_name, findings in findings_by_run.items():
        for i, f in enumerate(findings):
            k = join.key_for(run_name, i)
            model = f.get("analysed_by") or run_models.get(run_name, "")
            es = f.get("exploitability_score")
            key_to_history[k].append({
                "run": run_name,
                "status": f.get("final_status") or f.get("status", ""),
                "score": es if es is not None else f.get("cvss_score_estimate"),
                "model": model,
            })

    trends = {}
    for k, history in key_to_history.items():
        if len(history) < 2:
            continue
        history.sort(key=lambda h: run_order.index(h["run"]) if h["run"] in run_order else 999)
        label = f"{k[0]}:{k[1]}:{k[2]}" if k[1] else f"{k[0]}:{k[2]}"
        trends[label] = history

    return trends


def _find_token_drift(run_dirs: list[Path]) -> list[dict[str, Any]]:
    """Token-enforcement drift between consecutive map-bearing runs.

    Compares the per-run ``token-map.json`` artifacts
    (:mod:`core.concepts.token_map`) pairwise in run-time order — the
    monitored-invariant view for gated-fragile disproofs whose
    reconsideration condition names the token as sole guard. Pure
    comparison over artifacts that already exist: no new pipeline
    stage, no verdict weight (a ``lost_enforcement`` row is queue food
    for the operator, never an auto-overturn of the recorded
    disproof).
    """
    try:
        from core.concepts.token_map import load_token_map, token_map_drift
    except Exception:  # noqa: BLE001 — enrichment, never a gate
        return []
    ordered = sorted(run_dirs, key=safe_run_mtime)
    maps = [(d.name, load_token_map(d)) for d in ordered]
    with_maps = [(name, m) for name, m in maps if m]
    drift_records: list[dict[str, Any]] = []
    for (p_name, p_map), (c_name, c_map) in zip(with_maps, with_maps[1:]):
        try:
            records = token_map_drift(p_map, c_map)
        except Exception:  # noqa: BLE001 — one bad artifact pair
            continue
        for rec in records:
            rec["prior_run"] = p_name
            rec["current_run"] = c_name
            drift_records.append(rec)
    return drift_records


def _build_tool_coverage(run_dirs: list[Path]) -> dict[str, list[str]]:
    """Build tool -> files-covered mapping from run metadata."""
    tool_files: dict[str, set] = defaultdict(set)

    for d in run_dirs:
        meta = load_run_metadata(d)
        tool = (meta if isinstance(meta, dict) else {}).get("command", "unknown")
        findings = load_findings_from_dir(d)
        for f in findings:
            fp = finding_file(f)
            if fp:
                tool_files[tool].add(fp)

    return {tool: sorted(files) for tool, files in sorted(tool_files.items())}
