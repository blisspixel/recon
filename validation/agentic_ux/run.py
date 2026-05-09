"""End-to-end runner for the v1.9.2 agentic UX validation.

Drives 3 personas x 2 fixtures x 2 fusion modes = 12 sessions through
a single LLM provider, scores the transcripts against the rubric in
``score.py``, and emits a self-contained markdown report
(``validation/v1.9.2-agentic-ux.md`` by default).

Why a single provider per run: the per-provider differences are the
*data* of a future cross-vendor study; we don't bake the comparison
into the harness itself. Run it again with ``--provider openai`` or
``--provider xai`` and append the resulting report to the analysis.

The runner does not import from ``recon_tool``. The fixtures encode
the recon-JSON shape under test, so the harness stays robust to
schema evolution above this revision.
"""

from __future__ import annotations

import argparse
import json
import sys
import textwrap
from dataclasses import dataclass
from datetime import datetime, timezone
from pathlib import Path
from typing import TYPE_CHECKING, Any

from . import score as score_mod
from .providers import (
    ChatMessage,
    ProviderError,
    get_provider,
)

if TYPE_CHECKING:
    from .providers import ChatProvider, ChatResponse


_REPO_ROOT = Path(__file__).resolve().parents[2]
_PERSONA_DIR = Path(__file__).resolve().parent / "personas"
_FIXTURE_DIR = Path(__file__).resolve().parent / "fixtures"

_DEFAULT_PERSONAS = ("analyst", "researcher", "ops")
_DEFAULT_FIXTURES = ("contoso-dense", "hardened-sparse")

# Top-level JSON keys that are exclusively part of the v1.9 fusion
# layer. Stripping these is what the "fusion off" arm of the rubric
# tests against. Earlier-vintage fields (chain_motifs from v1.7,
# infrastructure_clusters from v1.8) stay in place — fusion is the
# thing under evaluation, not the broader correlation work.
_FUSION_FIELDS = ("posterior_observations", "slug_confidences")


@dataclass(frozen=True)
class SessionRecord:
    """Aggregate of one persona/fixture/fusion-mode run."""

    persona: str
    fixture: str
    fusion: bool
    system_prompt: str
    user_prompt: str
    response_text: str
    input_tokens: int
    output_tokens: int
    cost_usd: float
    model: str
    provider: str


def _strip_fusion(payload: dict[str, Any]) -> dict[str, Any]:
    """Return a copy of ``payload`` with the v1.9 fusion fields removed."""
    return {k: v for k, v in payload.items() if k not in _FUSION_FIELDS}


def _load_persona(name: str) -> str:
    path = _PERSONA_DIR / f"{name}.md"
    if not path.exists():
        raise FileNotFoundError(f"persona not found: {path}")
    return path.read_text(encoding="utf-8").strip()


def _load_fixture(name: str) -> dict[str, Any]:
    path = _FIXTURE_DIR / f"{name}.json"
    if not path.exists():
        raise FileNotFoundError(f"fixture not found: {path}")
    return json.loads(path.read_text(encoding="utf-8"))


def _build_user_prompt(fixture_name: str, payload: dict[str, Any]) -> str:
    domain = payload.get("queried_domain") or payload.get("default_domain") or fixture_name
    body = json.dumps(payload, indent=2, ensure_ascii=False)
    return textwrap.dedent(
        f"""\
        Domain to assess: {domain}

        Recon JSON output (passive lookup, no active scans):

        ```json
        {body}
        ```
        """,
    )


def run_session(
    provider: ChatProvider,
    persona: str,
    fixture: str,
    *,
    fusion: bool,
    max_tokens: int,
) -> SessionRecord:
    """Run one persona/fixture/fusion-mode session against ``provider``."""
    system = _load_persona(persona)
    payload = _load_fixture(fixture)
    if not fusion:
        payload = _strip_fusion(payload)
    user = _build_user_prompt(fixture, payload)

    response: ChatResponse = provider.chat(
        system=system,
        messages=[ChatMessage(role="user", content=user)],
        max_tokens=max_tokens,
    )
    return SessionRecord(
        persona=persona,
        fixture=fixture,
        fusion=fusion,
        system_prompt=system,
        user_prompt=user,
        response_text=response.text,
        input_tokens=response.input_tokens,
        output_tokens=response.output_tokens,
        cost_usd=response.cost_usd,
        model=response.model,
        provider=response.provider,
    )


def run_matrix(
    provider: ChatProvider,
    *,
    personas: tuple[str, ...] = _DEFAULT_PERSONAS,
    fixtures: tuple[str, ...] = _DEFAULT_FIXTURES,
    max_tokens: int = 2048,
) -> list[SessionRecord]:
    """Run every persona x fixture x fusion-mode combination."""
    records: list[SessionRecord] = []
    for persona in personas:
        for fixture in fixtures:
            for fusion in (True, False):
                rec = run_session(
                    provider,
                    persona,
                    fixture,
                    fusion=fusion,
                    max_tokens=max_tokens,
                )
                records.append(rec)
    return records


def score_records(records: list[SessionRecord]) -> score_mod.RubricSummary:
    """Apply the rubric to a list of session records."""
    sessions = [
        score_mod.score_session(r.persona, r.fixture, r.fusion, r.response_text) for r in records
    ]
    by_key = {(r.persona, r.fixture, r.fusion): r for r in records}
    score_by_key = {(s.persona, s.fixture, s.fusion): s for s in sessions}

    diffs: list[score_mod.DiffScore] = []
    for persona in {r.persona for r in records}:
        # sparse vs dense, with fusion ON (the configuration the v1.9
        # layer is meant to make legible)
        dense_key = (persona, "contoso-dense", True)
        sparse_key = (persona, "hardened-sparse", True)
        if dense_key in score_by_key and sparse_key in score_by_key:
            diffs.append(
                score_mod.diff_sparse_vs_dense(
                    score_by_key[dense_key],
                    score_by_key[sparse_key],
                    dense_text=by_key[dense_key].response_text,
                    sparse_text=by_key[sparse_key].response_text,
                ),
            )
        # fusion on vs off, on the dense fixture (where fusion has the
        # most material to disagree with)
        on_key = (persona, "contoso-dense", True)
        off_key = (persona, "contoso-dense", False)
        if on_key in score_by_key and off_key in score_by_key:
            diffs.append(
                score_mod.diff_fusion_on_vs_off(
                    score_by_key[on_key],
                    score_by_key[off_key],
                    on_text=by_key[on_key].response_text,
                    off_text=by_key[off_key].response_text,
                ),
            )
    return score_mod.RubricSummary(sessions=sessions, diffs=diffs)


# --- Reporting ---------------------------------------------------------------


def _markdown_session_table(rows: list[dict[str, object]]) -> str:
    header = "| Persona | Fixture | Fusion | Read posterior | Cited interval | Used --explain-dag | Hedge count |"
    sep = "|---|---|---|---|---|---|---|"
    lines = [header, sep]
    for row in rows:
        lines.append(
            "| {persona} | {fixture} | {fusion} | {read} | {cite} | {dag} | {hedge} |".format(
                persona=row["persona"],
                fixture=row["fixture"],
                fusion="on" if row["fusion"] else "off",
                read="yes" if row["read_posterior_block"] else "no",
                cite="yes" if row["cited_credible_interval"] else "no",
                dag="yes" if row["mentioned_explain_dag"] else "no",
                hedge=row["hedge_count"],
            ),
        )
    return "\n".join(lines)


def _markdown_diff_table(rows: list[dict[str, object]]) -> str:
    header = "| Persona | Comparison | Differed | Reason |"
    sep = "|---|---|---|---|"
    lines = [header, sep]
    for row in rows:
        lines.append(
            "| {persona} | {label} | {differed} | {reason} |".format(
                persona=row["persona"],
                label=row["label"],
                differed="yes" if row["differed"] else "no",
                reason=row["reason"],
            ),
        )
    return "\n".join(lines)


def _summarize_findings(summary: score_mod.RubricSummary) -> str:
    """Derive concrete v2.0-disposition findings from the rubric output."""
    sessions = summary.sessions
    total = len(sessions)
    read_post = sum(1 for s in sessions if s.read_posterior_block)
    cited_iv = sum(1 for s in sessions if s.cited_credible_interval)
    used_dag = sum(1 for s in sessions if s.mentioned_explain_dag)

    fusion_on_engaged = {s.persona for s in sessions if s.fusion and s.read_posterior_block}
    personas = {s.persona for s in sessions}
    persona_ignores_fusion = personas - fusion_on_engaged

    sparse_only_intervals = [
        s for s in sessions if s.cited_credible_interval and s.fixture == "hardened-sparse"
    ]
    dense_only_intervals = [
        s for s in sessions if s.cited_credible_interval and s.fixture == "contoso-dense"
    ]

    diff_no_change = [d for d in summary.diffs if not d.differed]

    lines: list[str] = []
    lines.append(
        f"**Headline.** Of {total} sessions: posterior block read in {read_post} "
        f"({read_post * 100 // total}%); credible interval cited in {cited_iv}; "
        f"`--explain-dag` / `explain_dag` mentioned in {used_dag}.",
    )
    lines.append("")
    findings: list[str] = []
    if used_dag == 0:
        findings.append(
            f"**`--explain-dag` is invisible to agents (0/{total} sessions).** "
            "No persona suggested running `--explain-dag` or invoking the "
            "`explain_dag` MCP tool. v2.0 disposition: the affordance exists "
            "but agents do not find it from the JSON alone. Either surface a "
            "pointer field in the JSON (`explanation_pointer: \"--explain-dag\"`) "
            "or rely on docs/MCP-tool-listing rather than expecting the agent "
            "to infer it from output shape.",
        )
    if persona_ignores_fusion:
        names = ", ".join(f"`{n}`" for n in sorted(persona_ignores_fusion))
        findings.append(
            f"**Persona(s) {names} ignore the posterior block in fusion-on mode.** "
            "When the agent's framing is non-technical (vendor assessment for a "
            "non-technical stakeholder), the posterior detail gets stripped from "
            "the response. v2.0 disposition: `posterior_observations` is most "
            "useful for technical personas; non-technical surfaces may need a "
            "separate hedged-narrative summary rather than expecting agents to "
            "translate `interval_low / interval_high` into prose.",
        )
    if sparse_only_intervals and not dense_only_intervals:
        findings.append(
            "**Numeric interval citation only appears on sparse fixtures.** "
            f"All {len(sparse_only_intervals)} interval citations occurred on the "
            "`hardened-sparse` fixture; none on `contoso-dense`. The interval is "
            "load-bearing exactly where uncertainty is wide. v2.0 disposition: "
            "the field earns its keep on hardened targets; no rename needed.",
        )
    for diff in diff_no_change:
        if diff.label == "sparse_vs_dense":
            findings.append(
                f"**`{diff.persona}` persona did not modulate tone between dense and "
                "sparse.** `sparse=true` should drive a hedged voice, but on the "
                f"`{diff.persona}` prompt the dense and sparse responses used the same "
                "hedge density. Could be a prompt-shape artifact. v2.0 disposition: "
                "consider whether the panel should also surface a per-node "
                "`sparse=true` callout in the rendered output, not only in JSON, so "
                "agents whose framing pre-commits to a confident voice still see "
                "the qualifier.",
            )
        elif diff.label == "fusion_on_vs_off":
            findings.append(
                f"**`{diff.persona}` persona showed no fusion-on/off difference.** "
                "Either the posterior block adds no decision-relevant signal for "
                "this persona, or the agent ignored it. The latter is more likely "
                "when the same persona also did not engage with posterior "
                "material in either run.",
            )
    for idx, body in enumerate(findings, start=1):
        lines.append(f"{idx}. {body}")
    lines.append("")
    lines.append(
        "**Net effect on recon.** This run does not show that fusion is broken; "
        "it shows that fusion's value is bounded by the agent's framing. "
        "Technical personas (analyst, ops) read and use posterior material; "
        "narrative personas do not. The most actionable finding for v2.0 is the "
        "explain-DAG invisibility — that is a fixable shape-of-the-JSON issue, "
        "not a model-of-uncertainty issue. The v1.9.3 bridge milestone "
        "(email_security_strong topology surgery) is independent of this run; "
        "the v2.0 schema-lock disposition for `posterior_observations` is "
        "informed by it.",
    )
    return "\n".join(lines)


def render_report(
    records: list[SessionRecord],
    summary: score_mod.RubricSummary,
    *,
    started_at: datetime,
    finished_at: datetime,
) -> str:
    """Produce the self-contained v1.9.2 markdown artifact."""
    if not records:
        raise ValueError("cannot render report from empty record list")

    total_input = sum(r.input_tokens for r in records)
    total_output = sum(r.output_tokens for r in records)
    total_cost = sum(r.cost_usd for r in records)
    provider = records[0].provider
    model = records[0].model

    duration = (finished_at - started_at).total_seconds()
    persona_count = len({r.persona for r in records})
    fixture_count = len({r.fixture for r in records})

    parts: list[str] = []
    parts.append("# Agentic UX Validation — v1.9.2\n")
    parts.append(
        "Bridge milestone: **v1.9.2 — UX validation via agentic QA** "
        "(see `docs/roadmap.md`).\n",
    )
    parts.append("**Run metadata.**\n")
    parts.append(f"- Provider / model: `{provider}` / `{model}`")
    parts.append(
        f"- Sessions: {len(records)} ({persona_count} personas "
        f"x {fixture_count} fixtures x 2 fusion modes)",
    )
    parts.append(f"- Started: {started_at.isoformat()}")
    parts.append(f"- Finished: {finished_at.isoformat()} (duration {duration:.1f}s)")
    parts.append(f"- Tokens: {total_input:,} input / {total_output:,} output")
    parts.append(f"- Realized cost: **${total_cost:.4f}**\n")
    parts.append("## Methodology\n")
    parts.append(
        "Three persona system prompts (security analyst, due-diligence "
        "researcher, ops engineer) are run against two fixtures: a dense "
        "recon lookup of `contoso.com` (Microsoft's fictional brand) and "
        "a hand-stripped `hardened-sparse` fixture for "
        "`northwindtraders.com` with a single weak signal. Each "
        "persona/fixture pair runs twice — once with the v1.9 fusion "
        "fields (`posterior_observations`, `slug_confidences`) included, "
        "once with them stripped — so the rubric can diff the agent's "
        "reasoning between the two.\n",
    )
    parts.append(
        "None of the persona prompts mention `posterior_observations`, "
        "`sparse=true`, `--explain-dag`, or credible intervals. The "
        "rubric measures whether the agent finds and uses those "
        "affordances unprompted.\n",
    )
    parts.append("## Rubric — per-session\n")
    parts.append(_markdown_session_table(summary.session_table))
    parts.append("")
    parts.append("## Rubric — cross-session diffs\n")
    parts.append(_markdown_diff_table(summary.diff_table))
    parts.append("")
    parts.append("## Findings\n")
    parts.append(_summarize_findings(summary))
    parts.append("")
    parts.append("## Persona system prompts (verbatim)\n")

    seen_personas: set[str] = set()
    for record in records:
        if record.persona in seen_personas:
            continue
        seen_personas.add(record.persona)
        parts.append(f"### {record.persona}\n")
        parts.append("```text")
        parts.append(record.system_prompt)
        parts.append("```\n")

    parts.append("## Transcripts\n")
    for record in records:
        fusion_label = "fusion=on" if record.fusion else "fusion=off"
        parts.append(f"### {record.persona} / {record.fixture} / {fusion_label}\n")
        parts.append(
            f"_Tokens: {record.input_tokens:,} in / {record.output_tokens:,} out — "
            f"cost ${record.cost_usd:.4f}_\n",
        )
        parts.append("**Agent response:**\n")
        parts.append("```markdown")
        parts.append(record.response_text.strip() or "(empty response)")
        parts.append("```\n")

    parts.append("## Reproducing this run\n")
    parts.append("```bash")
    parts.append("# Requires ANTHROPIC_API_KEY (or the provider-equivalent env var).")
    parts.append("python -m validation.agentic_ux.run \\")
    parts.append(f"    --provider {provider} \\")
    parts.append(f"    --model {model} \\")
    parts.append("    --output validation/v1.9.2-agentic-ux.md")
    parts.append("```")
    parts.append("")
    parts.append(
        "The fixtures (`validation/agentic_ux/fixtures/`) and persona "
        "prompts (`validation/agentic_ux/personas/`) are the only "
        "committed inputs; everything else is derived from the run.",
    )
    parts.append("")
    return "\n".join(parts) + "\n"


# --- CLI ---------------------------------------------------------------------


def _parse_csv(value: str | None, default: tuple[str, ...]) -> tuple[str, ...]:
    if not value:
        return default
    items = tuple(item.strip() for item in value.split(",") if item.strip())
    return items or default


def _build_parser() -> argparse.ArgumentParser:
    parser = argparse.ArgumentParser(
        prog="validation.agentic_ux.run",
        description="Run the v1.9.2 agentic UX validation matrix.",
    )
    parser.add_argument("--provider", default="anthropic", choices=("anthropic", "openai", "xai"))
    parser.add_argument("--model", default="claude-sonnet-4-6")
    parser.add_argument("--api-key", default=None, help="Override env-var-supplied API key.")
    parser.add_argument("--base-url", default=None, help="Override provider base URL.")
    parser.add_argument("--input-price", type=float, default=None, help="USD per million input tokens.")
    parser.add_argument("--output-price", type=float, default=None, help="USD per million output tokens.")
    parser.add_argument("--max-tokens", type=int, default=2048)
    parser.add_argument("--personas", default=None, help="Comma-separated subset (default: all).")
    parser.add_argument("--fixtures", default=None, help="Comma-separated subset (default: all).")
    default_output = _REPO_ROOT / "validation" / "v1.9.2-agentic-ux.md"
    parser.add_argument("--output", "-o", type=Path, default=default_output)
    parser.add_argument(
        "--records-json",
        type=Path,
        default=None,
        help="Optional path to also dump raw session records as JSON.",
    )
    return parser


def main(argv: list[str] | None = None) -> int:
    args = _build_parser().parse_args(argv)
    personas = _parse_csv(args.personas, _DEFAULT_PERSONAS)
    fixtures = _parse_csv(args.fixtures, _DEFAULT_FIXTURES)

    provider_kwargs: dict[str, object] = {}
    if args.api_key is not None:
        provider_kwargs["api_key"] = args.api_key
    if args.base_url is not None:
        provider_kwargs["base_url"] = args.base_url
    if args.input_price is not None:
        provider_kwargs["input_price"] = args.input_price
    if args.output_price is not None:
        provider_kwargs["output_price"] = args.output_price
    try:
        provider = get_provider(args.provider, args.model, **provider_kwargs)
    except (ProviderError, TypeError) as exc:
        print(f"error: {exc}", file=sys.stderr)
        return 2

    started = datetime.now(timezone.utc)
    try:
        records = run_matrix(
            provider,
            personas=personas,
            fixtures=fixtures,
            max_tokens=args.max_tokens,
        )
    except ProviderError as exc:
        print(f"error: {exc}", file=sys.stderr)
        return 1
    finished = datetime.now(timezone.utc)

    summary = score_records(records)
    report = render_report(records, summary, started_at=started, finished_at=finished)

    output_path = args.output
    output_path.parent.mkdir(parents=True, exist_ok=True)
    output_path.write_text(report, encoding="utf-8")

    if args.records_json:
        records_payload = [
            {
                "persona": r.persona,
                "fixture": r.fixture,
                "fusion": r.fusion,
                "input_tokens": r.input_tokens,
                "output_tokens": r.output_tokens,
                "cost_usd": r.cost_usd,
                "model": r.model,
                "provider": r.provider,
                "response_text": r.response_text,
            }
            for r in records
        ]
        args.records_json.parent.mkdir(parents=True, exist_ok=True)
        args.records_json.write_text(
            json.dumps(records_payload, indent=2, ensure_ascii=False),
            encoding="utf-8",
        )

    total_cost = sum(r.cost_usd for r in records)
    print(
        f"wrote {output_path} ({len(records)} sessions, ${total_cost:.4f} realized cost)",
        file=sys.stderr,
    )
    return 0


if __name__ == "__main__":  # pragma: no cover
    raise SystemExit(main())
