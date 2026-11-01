"""Render draft hunt markdown files into the Hecate workspace.

Kept separate from the orchestrator so we can unit-test rendering without any
subprocess or filesystem side effects other than writing the final file.
"""

from __future__ import annotations

import json
import logging
import os
import re
from dataclasses import dataclass, field
from datetime import UTC, datetime
from pathlib import Path
from typing import Any

import yaml

from hecate_runner.atomic_write import atomic_write_text
from hecate_runner.hecate_client import HypothesisResult

log = logging.getLogger(__name__)


@dataclass
class DraftHuntRequest:
    hunt_id: str
    threat_intel: str
    hypothesis: HypothesisResult
    generated_at: datetime
    research_id: str | None = None
    tactics: list[str] = field(default_factory=list)
    platforms: list[str] = field(default_factory=list)
    source_url: str = ""
    related_hunts: list[str] = field(default_factory=list)
    # Sigma rules drafted for this hunt, as
    # {"logsource_category", "title", "level", "techniques", "rule_yaml"}.
    # Empty renders the same "human to draft" placeholder as before, so a
    # generation failure degrades to the old behavior rather than to a hunt
    # that looks like it has queries and does not.
    sigma_rules: list[dict[str, Any]] = field(default_factory=list)
    sigma_rule_dir: str = ""
    #: Rendered grounding audit (see grounding.py). Empty renders nothing, so
    #: a draft written before the audit runs is simply missing the section
    #: rather than claiming a clean result it never computed.
    grounding_section: str = ""
    #: Primary-source evidence (hecate_agent.core.source_evidence.SourceEvidence
    #: .to_dict()) and the feed's indicators typed against it
    #: (IndicatorRecord dicts). Empty renders no evidence section.
    source_evidence: dict[str, Any] = field(default_factory=dict)
    indicator_records: list[dict[str, Any]] = field(default_factory=list)
    #: Quality of the research context's web search, shown next to its link.
    #: Empty when no research ran.
    research_grounding: str = ""
    #: Supporting passage per technique (TechniqueEvidence dicts from the
    #: orchestrator), including techniques dropped as capability-only.
    technique_evidence: list[dict[str, Any]] = field(default_factory=list)
    #: What the claim audit removed or rewrote (hecate_agent.core.claim_audit
    #: ClaimFinding dicts). Rendered under Grounding, so the quoted originals
    #: are shown as audit record, not as the draft's own claims.
    claim_audit: list[dict[str, Any]] = field(default_factory=list)
    #: The source's detection guidance (GuidanceItem dicts): each item quoted,
    #: with the telemetry that can see it and the rule drafted from it.
    detection_guidance: list[dict[str, Any]] = field(default_factory=list)
    #: Behaviours the rule reviewer found no rule for, each with its verified quote.
    review_gaps: list[dict[str, str]] = field(default_factory=list)
    #: Purple-team replay (hecate_runner.purple_team): rules that had source
    #: events to replay, rules that matched them and no benign event, rules
    #: tuned, and the number of synthesised events.
    purple_team_rules_evaluated: int = 0
    purple_team_rules_validated: int = 0
    purple_team_rules_tuned: int = 0
    purple_team_telemetry_count: int = 0
    purple_team_atomic_techniques: list[str] = field(default_factory=list)
    purple_team_atomic_tests: list[dict[str, str]] = field(default_factory=list)
    #: Closed-loop live adversary emulation & breach simulation (BAS) verification results
    bas_verification: dict[str, Any] | None = None
    #: Claim excerpts and exact source passages checked by the Runner.
    claim_evidence: list[dict[str, str]] = field(default_factory=list)
    #: Incremental campaign updates / dossier revision history
    campaign_updates: list[dict[str, Any]] = field(default_factory=list)


#: Ceiling on the CTI blurb embedded in a draft. Generous on purpose: the
#: providers already bound what they emit (MISP inlines at most 40 attributes,
#: OTX 40 indicators, both at 120 chars each), so their worst case is ~8k and
#: this should never bite in practice.
#:
#: It used to be 2,000, which was below both. The blurb was then silently cut
#: mid-indicator-list, and because `hunt_audit` re-derives the CTI from this
#: embedded copy, every indicator past the cut was re-graded UNSUPPORTED --
#: real C2 domains reported as fabrications on H-0007 and H-0010. A false
#: fabrication alarm is the one thing the grounding audit must not produce,
#: so if this ever does truncate it says so in the text rather than leaving
#: the audit to draw the wrong conclusion from silence.
_MAX_EMBEDDED_CTI = 10_000


_IPV4_TOKEN = re.compile(
    r"(?<![\w.])(?:(?:25[0-5]|2[0-4]\d|1\d\d|[1-9]?\d)\.){3}"
    r"(?:25[0-5]|2[0-4]\d|1\d\d|[1-9]?\d)(?![\w.])"
)
_URL_TOKEN = re.compile(r"(?i)\bhttps?://[^\s<>()\[\]{}\"']+")
_DOMAIN_TOKEN = re.compile(
    r"(?i)(?<![\w.-])(?:[a-z0-9](?:[a-z0-9-]{0,61}[a-z0-9])?\.)+"
    r"[a-z]{2,63}(?![\w-])"
)
_COMMON_TLDS = frozenset(
    [
        "ai",
        "app",
        "asia",
        "au",
        "biz",
        "ca",
        "cc",
        "cloud",
        "cn",
        "co",
        "com",
        "de",
        "edu",
        "fr",
        "gov",
        "in",
        "info",
        "io",
        "ir",
        "jp",
        "me",
        "mil",
        "mobi",
        "net",
        "nl",
        "nz",
        "online",
        "org",
        "pro",
        "ru",
        "shop",
        "site",
        "tech",
        "top",
        "tv",
        "uk",
        "us",
        "xyz",
        "za",
    ]
)
_NON_DOMAIN_SUFFIXES = frozenset(
    [
        "bat",
        "bin",
        "cache",
        "cmd",
        "conf",
        "config",
        "css",
        "csv",
        "dat",
        "dll",
        "docx",
        "drv",
        "exe",
        "gz",
        "htm",
        "html",
        "ini",
        "js",
        "jsx",
        "json",
        "log",
        "md",
        "ocx",
        "pdf",
        "path",
        "preload",
        "ps1",
        "psm1",
        "py",
        "pyc",
        "registry",
        "scr",
        "security",
        "so",
        "sys",
        "tar",
        "ts",
        "tsx",
        "txt",
        "vbe",
        "vbs",
        "wsh",
        "wsf",
        "xlsx",
        "xml",
        "yaml",
        "yml",
        "zip",
    ]
)


def _network_ioc_tokens(text: str) -> set[str]:
    """Find IPv4, URL, and public-looking hostname literals in source text."""
    tokens = {match.group(0).rstrip(".,;:!?") for match in _URL_TOKEN.finditer(text)}
    tokens.update(match.group(0) for match in _IPV4_TOKEN.finditer(text))
    for match in _DOMAIN_TOKEN.finditer(text):
        value = match.group(0)
        suffix = value.rsplit(".", 1)[-1].lower()
        if suffix in _COMMON_TLDS and suffix not in _NON_DOMAIN_SUFFIXES:
            tokens.add(value)
    return {token for token in tokens if token}


def _defang_network_value(value: str) -> str:
    """Render a network IOC so prose cannot turn it into a live link or lookup."""
    defanged = re.sub(r"(?i)^http", lambda match: "hxxp", value)
    return defanged.replace(".", "[.]")


def _defang_prose_iocs(markdown: str, indicators: set[str]) -> str:
    """Defang network indicators in prose and Sigma provenance metadata.

    Detection code in fences remains byte-for-byte intact so reviewed queries
    can still be copied and run. Prose, indicator tables, quoted CTI, and the
    non-executable ``hecate_provenance`` YAML block are presentation text.
    """
    if not indicators:
        return markdown

    patterns = [
        re.compile(rf"(?<![\w.-]){re.escape(value)}(?![\w-])", re.IGNORECASE)
        for value in sorted(indicators, key=len, reverse=True)
        if "[.]" not in value
    ]
    output: list[str] = []
    in_fence = False
    yaml_fence = False
    fence_character = ""
    in_provenance = False
    for line in markdown.splitlines(keepends=True):
        fence = re.match(r"^\s*(`{3,}|~{3,})(.*)$", line)
        if fence:
            if not in_fence:
                in_fence = True
                fence_character = fence.group(1)[0]
                yaml_fence = fence.group(2).strip().lower() in {"yaml", "yml"}
                in_provenance = False
            elif fence.group(1)[0] == fence_character:
                in_fence = False
                yaml_fence = False
                in_provenance = False
            output.append(line)
            continue
        if in_fence:
            is_top_level_key = bool(re.match(r"^[A-Za-z_][A-Za-z0-9_-]*:\s*", line))
            if yaml_fence and re.match(r"^hecate_provenance:\s*$", line):
                in_provenance = True
            elif in_provenance and is_top_level_key:
                in_provenance = False
            if in_provenance:
                for pattern in patterns:
                    line = pattern.sub(lambda match: _defang_network_value(match.group(0)), line)
            output.append(line)
            continue
        for pattern in patterns:
            line = pattern.sub(lambda match: _defang_network_value(match.group(0)), line)
        output.append(line)
    return "".join(output)


def embedded_cti(threat_intel: str) -> str:
    """The CTI blurb as it is quoted into a draft."""
    text = (threat_intel or "").strip()
    if len(text) > _MAX_EMBEDDED_CTI:
        omitted = len(text) - _MAX_EMBEDDED_CTI
        text = (
            text[:_MAX_EMBEDDED_CTI].rstrip()
            + f"\n[... {omitted} characters of CTI omitted from this draft. "
            "Indicators below this point were available to drafting but are not "
            "quoted here, so a grounding audit cannot confirm them.]"
        )
    # Demote/strip internal headings so they do not collide with document-level sections
    text = re.sub(r"(?m)^#{1,4}\s+(?:Threat Context|Primary Source Evidence)\b[^\n]*\n?", "", text)
    text = re.sub(r"(?m)^#{1,3}\s+", "#### ", text)
    return text.strip()


# Hunt ID allocation (hunt_id_lock, next_hunt_id) lives in hecate_agent.core.hunt_ids,
# shared with the Hecate-Core CLI, MCP tools and LangGraph orchestrator, which all
# write the same hunts/ directory. Callers must allocate AND write the draft inside
# hunt_id_lock, exactly as before.


def draft_hunt_path(hunts_root: Path, hunt_id: str, when: datetime) -> Path:
    year = when.strftime("%Y")
    quarter = f"Q{(when.month - 1) // 3 + 1}"
    return hunts_root / year / quarter / f"{hunt_id}.md"


# Frontmatter `title:` is a single YAML scalar line; keep it well clear of
# the ~1000-char per-line lint some tooling enforces on frontmatter, while
# still reading as an actual sentence rather than the ~80-char hard cut this
# replaced, which routinely sliced mid-word ("...on high-valu") with no
# ellipsis, silently presenting a truncated fragment as if it were complete.
_TITLE_MAX_LEN = 100


def _short_title(hypothesis: str) -> str:
    text = (hypothesis or "Untitled draft").strip()
    if len(text) <= _TITLE_MAX_LEN:
        return text
    truncated = text[:_TITLE_MAX_LEN]
    if " " in truncated:
        truncated = truncated.rsplit(" ", 1)[0]
    return truncated + "..."


def _title_scalar(hypothesis: str) -> str:
    """The `title:` value, quoted so it is always a valid YAML scalar.

    Every list field here goes through ``json.dumps`` for exactly this
    reason; the title was the one interpolated bare, and a hypothesis
    carrying a colon broke the frontmatter of the whole hunt. H-0002 was
    drafted from an ESET event titled "MoustachedBouncer: Espionage against
    foreign diplomats" and came out as::

        title: DRAFT - Indicators published in MoustachedBouncer: Espionage ...

    which YAML reads as a second mapping value and rejects. `hecate-agent
    hunt validate` then failed on the file, so the draft was unparseable by
    the very tooling meant to check it.

    A JSON string is a valid YAML double-quoted scalar, so this also covers
    embedded quotes and backslashes. ``ensure_ascii=False`` keeps non-ASCII
    titles readable rather than escaping them to \\uXXXX.
    """
    return json.dumps(f"DRAFT - {_short_title(hypothesis)}", ensure_ascii=False)


def _able_cell(value: str) -> str:
    """Render one ABLE Scoping table cell.

    Falls back to the same "[Review CTI and populate]" placeholder the
    table always showed when the hypothesis-generator left the field empty
    (no LLM, or the model didn't find grounding for it in the CTI) --
    honest about the gap rather than fabricating a value. `|` is escaped
    since it's the markdown table cell delimiter; a hypothesis-generator
    field containing one would otherwise silently break the table layout.
    """
    text = value.strip()
    if not text:
        return "[Review CTI and populate]"
    return text.replace("|", "\\|")


def _draft_tags(is_threat_report: bool, is_indicator_only: bool = False) -> list[str]:
    """Frontmatter `tags:` for a draft, with `low-confidence-source`
    appended when the hypothesis-generator judged the CTI itself doesn't
    describe real adversary behavior -- lets `hecate-agent hunt search`/filtering
    surface (or exclude) these during triage instead of a reviewer having
    to open every draft to notice the banner in the body.

    `indicator-sweep` marks the other kind of thin source: a narrative-free
    feed dump, which produces an indicator-presence draft rather than a
    behavioral hypothesis. Distinct from `low-confidence-source` on purpose
    -- a feed dump is genuine threat intel, just not a story, and conflating
    the two would dilute what the low-confidence tag means at triage.
    """
    tags = ["draft", "auto-generated", "requires-human-review"]
    if not is_threat_report:
        tags.append("low-confidence-source")
    if is_indicator_only:
        tags.append("indicator-sweep")
    return tags


def _research_link_target(research_id: str, when: datetime) -> str:
    """Return the draft-relative path to a research doc.

    Derived from :func:`draft_hunt_path` rather than hardcoded: the depth of a
    draft below the workspace root is a property of that layout, and the two
    had drifted apart. drafts live at ``hunts/<year>/<quarter>/H-XXXX.md`` (3
    levels down) while the link said ``../../../../``, which resolved outside
    the workspace entirely and left every generated hunt pointing at a
    nonexistent file. The actual hunts_root value cancels out, so a nominal
    one is enough to measure the depth.
    """
    nominal_root = Path("/workspace/hunts")
    draft = draft_hunt_path(nominal_root, "H-0000", when)
    research = nominal_root.parent / "research" / f"{research_id}.md"
    return os.path.relpath(research, draft.parent)


def _research_document_line(req: DraftHuntRequest) -> str:
    """Render the Threat Intel & Research bullet naming the research doc.

    An indicator sweep gets its own wording rather than the generic "grounding
    unavailable": research is deliberately skipped for those, not failed, and
    the old line read like something had gone wrong. The alternative -- running
    research anyway -- produced documents whose every section said it had
    nothing to say, linked from here as "detailed pre-hunt research".
    """
    if req.research_id:
        target = _research_link_target(req.research_id, req.generated_at)
        grounding = f" ({req.research_grounding})" if req.research_grounding else ""
        return f"- **Research Context:** See [{req.research_id}]({target}) for background leads{grounding}"
    if req.hypothesis.is_indicator_only:
        return (
            "- **Research Context:** None — an indicator sweep needs no research "
            "grounding; the CTI's own indicator list is the hunt"
        )
    return "- **Research Context:** None — review the CTI directly"


def _clean_rule_yaml_for_display(rule_yaml: str) -> str:
    """Strip internal provenance tracking structures from displayed markdown YAML."""
    if "hecate_provenance:" not in rule_yaml:
        return rule_yaml.rstrip()
    try:
        data = yaml.safe_load(rule_yaml)
        if isinstance(data, dict) and "hecate_provenance" in data:
            data.pop("hecate_provenance", None)
            return yaml.safe_dump(data, sort_keys=False).rstrip()
    except Exception:
        pass
    cleaned = re.sub(r"(?m)^hecate_provenance:\s*\n(^(?:  |-|\s).*\n)*", "", rule_yaml)
    return cleaned.rstrip()


def _render_sigma_section(req: DraftHuntRequest) -> str:
    """Render the drafted Sigma rules, or the old placeholder if there are none.

    Rules are shown in full rather than linked. An operator reviewing this
    hunt has to be able to judge the detection logic here, before advancing
    the status -- making them open five files elsewhere to do it is how
    review turns into rubber-stamping. The files still exist alongside, and
    are what `sigma convert` reads.
    """
    if not req.sigma_rules:
        return (
            "#### Initial Query\n\n"
            "```\n"
            "[Human to draft based on Observe section - no rules were generated "
            "for this hunt]\n"
            "```\n"
        )

    replay = [r.get("purple_team") or {} for r in req.sigma_rules]
    validated = sum(1 for r in replay if r.get("validated"))
    replayed = sum(1 for r in replay if r.get("status") and r.get("status") != "no_replay_events")
    parts = [
        f"> {len(req.sigma_rules)} Sigma rule(s) auto-drafted from the source intelligence, "
        "one per applicable log source.",
    ]
    if replayed:
        if req.purple_team_atomic_techniques:
            emulated_str = ", ".join(f"`{t}`" for t in req.purple_team_atomic_techniques[:4])
            parts.append(
                f"> **Adversary Emulation (Atomic Red Team):** {validated} of {replayed} evaluated rule(s) validated "
                f"against dynamic adversary emulation telemetry across {emulated_str} and none of the benign baseline."
            )
        else:
            parts.append(
                f"> **Purple-team replay:** {validated} of {replayed} replayed rule(s) matched events synthesised "
                "from the report's own artifacts and none of a small benign sample"
                + (
                    f"; {len(req.sigma_rules) - replayed} had no source artifact to replay"
                    if replayed < len(req.sigma_rules)
                    else ""
                )
                + ". A replay of what the report names, not emulation: it shows a rule can match the "
                "described activity, not that it is quiet in your environment."
            )
    parts.append(
        "> **Unreviewed.** Sigma is platform-neutral: convert with "
        "`sigma convert -t <backend>` once a target is chosen. Field names and "
        "false positives are the model's proposal and must be checked against "
        "real telemetry before anything is run."
    )
    if req.sigma_rule_dir:
        parts.append(f">\n> Rule files: `{req.sigma_rule_dir}`")
    parts.append("")

    for rule in req.sigma_rules:
        category = str(rule.get("logsource_category", "unknown"))
        title = str(rule.get("title", "Untitled rule"))
        level = str(rule.get("level", "medium"))
        techniques = ", ".join(str(t) for t in rule.get("techniques") or []) or "unmapped"
        parts.append(f"#### {category} - {title}")
        parts.append("")
        parts.append(f"*Severity:* {level} | *ATT&CK:* {techniques}")
        parts.append("")
        clean_yaml = _clean_rule_yaml_for_display(str(rule.get("rule_yaml", "")).rstrip())
        parts.append("```yaml")
        parts.append(clean_yaml)
        parts.append("```")
        parts.append("")

        ryaml = str(rule.get("rule_yaml", "")).strip()
        if ryaml:
            try:
                from hecate_agent.api import transpile_sigma_rule

                t_queries = transpile_sigma_rule(ryaml)
                successful_t = [
                    t
                    for t in t_queries.values()
                    if getattr(t, "success", False) and getattr(t, "query", None)
                ]
                if successful_t:
                    parts.append("##### Native EDR & SIEM Queries")
                    parts.append("")
                    is_deterministic_ioc = (
                        "named in the source intelligence" in title.lower()
                        or len(clean_yaml.splitlines()) > 35
                    )
                    if is_deterministic_ioc:
                        parts.append("<details>")
                        parts.append(
                            "<summary><b>View Transpiled Native Queries for SIEM/EDR Targets (Click to expand)</b></summary>"
                        )
                        parts.append("")
                    for t_item in successful_t:
                        code_lang = (
                            "kql"
                            if t_item.dialect == "kql"
                            else ("text" if t_item.dialect in {"leql", "s1ql"} else t_item.dialect)
                        )
                        parts.append(f"**{t_item.platform_name} ({t_item.dialect.upper()}):**")
                        parts.append(f"```{code_lang}")
                        parts.append(t_item.query.strip())
                        parts.append("```")
                        parts.append("")
                    if is_deterministic_ioc:
                        parts.append("</details>")
                        parts.append("")
            except Exception:
                pass

    return "\n".join(parts)


_RULE_PLACEMENT_NOTE = {
    "archive": "none: an archive never runs as a process",
    "document": "none: a document is not a process image",
    "script": "none: a script runs as its interpreter, which carries the interpreter's hash",
    "network_content": "none: network content, not a file on disk",
    "memory_only": "none: exists only in memory",
    "historical": "none: historical, not this intrusion",
    "non_file": "none: a token, key or certificate fingerprint, not the hash of a file",
    "target": "none: an address the actor targeted, not infrastructure a host connects to",
}


def _rule_placements(record: dict[str, Any]) -> str:
    """The log sources a record's rules go to, from the same routing the Sigma stage uses.

    Restating the routing here drifted from it: inbound attack sources were
    listed as outbound network_connection, and bare dual-use URL paths as proxy.
    """
    from hecate_agent.core.provenance import IndicatorRecord, placements

    placed = placements(IndicatorRecord.from_dict(record))
    if not placed:
        role = str(record.get("role", ""))
        if record.get("status") == "historical":
            role = "historical"
        return _RULE_PLACEMENT_NOTE.get(role, "none: no log records it in this role")
    ports = ", ".join(str(p) for p in record.get("ports") or [])
    categories = dict.fromkeys(p.split(".")[0] for p in placed)
    return ", ".join(
        f"{c} on {ports}" if ports and c == "network_connection" else c for c in categories
    )


def _cell(text: str, limit: int = 160) -> str:
    text = " ".join(str(text).split()).replace("|", "\\|")
    return text if len(text) <= limit else text[: limit - 1] + "…"


def _render_source_evidence(req: DraftHuntRequest) -> str:
    """The primary report's verified artifacts and each indicator's role, as the draft's own content."""
    ev = req.source_evidence
    if not ev:
        return ""
    url = ev.get("url", "")
    if ev.get("error") and not ev.get("artifacts"):
        return f"### Primary Source Evidence\n\nNot extracted from {url}: {_cell(ev['error'])}\n\n"
    lines = [
        "### Primary Source Evidence",
        "",
        f"Extracted from [{url}]({url}) ({ev.get('chars', 0):,} characters). Artifacts in the first table "
        "were verified verbatim in the report. Feed indicators are listed separately; only indicators "
        "with a quoted evidence passage are verified against this report. This is the report's account, "
        "not independent confirmation.",
        "",
    ]
    behaviours = [a for a in ev.get("artifacts", []) if a.get("kind") not in _INDICATOR_KINDS]
    if behaviours:
        lines += ["| Artifact | Kind | Role | Status | Evidence |", "|---|---|---|---|---|"]
        for a in behaviours:
            evidence = f'"{_cell(a["evidence"])}"' if a.get("evidence") else "unverified"
            lines.append(
                f"| `{_cell(a['value'], 90)}` | {a['kind']} | {_cell(a['role'], 40)} | {a['status']} | {evidence} |"
            )
        lines.append("")
    records = req.indicator_records
    if records:
        lines += [
            "**Indicators by role** (the feed's indicators, typed against the report):",
            "",
            "| Indicator | Type | Role | Status | Confidence | Rules | Evidence |",
            "|---|---|---|---|---|---|---|",
        ]
        if len(records) > 20:
            non_hashes = [
                r
                for r in records
                if str(r.get("type", "")).lower()
                not in {"md5", "sha1", "sha256", "filehash-md5", "filehash-sha1", "filehash-sha256"}
            ]
            hashes = [
                r
                for r in records
                if str(r.get("type", "")).lower()
                in {"md5", "sha1", "sha256", "filehash-md5", "filehash-sha1", "filehash-sha256"}
            ]
            displayed_hashes = hashes[:10]
            omitted_hashes = len(hashes) - len(displayed_hashes)

            for r in non_hashes + displayed_hashes:
                evidence = f'"{_cell(r["evidence"])}"' if r.get("evidence") else "unverified"
                lines.append(
                    f"| `{_cell(r['value'], 70)}` | {r['type']} | {r.get('role', 'unknown')} | "
                    f"{r.get('status', 'unknown')} | {r.get('confidence', 'unknown')} | {_rule_placements(r)} | "
                    f"{evidence} |"
                )
            if omitted_hashes > 0:
                lines.append(
                    f"| *(+{omitted_hashes} additional file hash indicators)* | file_hash | unknown | active | cti | "
                    f"process_creation | *See queries/{req.hunt_id}/indicator_sweep.py for full indicator list* |"
                )
        else:
            for r in records:
                evidence = f'"{_cell(r["evidence"])}"' if r.get("evidence") else "unverified"
                lines.append(
                    f"| `{_cell(r['value'], 70)}` | {r['type']} | {r.get('role', 'unknown')} | "
                    f"{r.get('status', 'unknown')} | {r.get('confidence', 'unknown')} | {_rule_placements(r)} | "
                    f"{evidence} |"
                )
        lines.append("")
    return "\n".join(lines) + "\n"


def _render_claim_audit(req: DraftHuntRequest) -> str:
    """Every observable the audit removed and every sentence it rewrote, with the reason."""
    if not req.claim_audit:
        return ""
    lines = ["", "", "#### Claim Audit", ""]
    for f in req.claim_audit:
        lines.append(
            f'- {f["action"]} ({f["field"]}): "{_cell(f["text"], 200)}" - {_cell(f["reason"], 160)}'
        )
    return "\n".join(lines)


def _render_claim_evidence(req: DraftHuntRequest) -> str:
    """Show quote provenance for generated claims, including missing links."""
    if not req.claim_evidence:
        return ""
    active_claims = [
        row
        for row in req.claim_evidence
        if row.get("quote") or row.get("status") != "no exact claim citation supplied"
    ]
    unquoted_count = len(req.claim_evidence) - len(active_claims)

    lines = [
        "",
        "#### Claim Evidence References",
        "",
        "The Runner checks that each quote occurs in the source text and that the cited claim excerpt appears in the final field. "
        "A text match does not prove the quote supports the claim; review that relationship.",
        "",
    ]
    if active_claims:
        lines += [
            "| Field | Claim excerpt | Source passage | Quote check |",
            "|---|---|---|---|",
        ]
        for row in active_claims:
            quote = f'"{_cell(row.get("quote", ""), 220)}"' if row.get("quote") else "—"
            source = row.get("source", "")
            source_link = (
                f"[{_cell(source, 100)}]({source})"
                if source.startswith(("https://", "http://"))
                else _cell(source, 100) or "—"
            )
            lines.append(
                f"| {row.get('field', '')} | {_cell(row.get('claim', ''), 180)} | {quote} | "
                f"{_cell(row.get('status', ''), 80)} ({source_link}) |"
            )
        lines.append("")
    if unquoted_count > 0:
        lines.append(
            f"> **Note:** {unquoted_count} additional technique(s) and observable(s) were derived from feed metadata "
            "or contextual inference without direct in-text quotations (see Grounding Audit below)."
        )
        lines.append("")
    return "\n".join(lines) + "\n"


_GUIDANCE_ROUTES = {
    "sigma": "Sigma",
    "edr": "EDR query",
    "network-content": "IDS/NDR signature",
    "indicator": "IOC sweep",
    "review": "Review",
}


def _render_review_gaps(req: DraftHuntRequest) -> str:
    """Behaviours the reviewer found no rule for, quoted from the hypothesis or the source."""
    if not req.review_gaps:
        return ""
    lines = ["", "", "#### Not Covered by Any Rule (rule review)", ""]
    for gap in req.review_gaps:
        lines.append(
            f'- {_cell(gap.get("behaviour", ""), 160)}: "{_cell(gap.get("quote", ""), 200)}"'
        )
    return "\n".join(lines)


def _render_detection_guidance(req: DraftHuntRequest) -> str:
    """The source's own detection guidance, each item routed to the telemetry that can see it."""
    if not req.detection_guidance:
        return ""
    source = next((g.get("source") for g in req.detection_guidance if g.get("source")), "")
    titles = [str(r.get("title", "")) for r in req.sigma_rules]
    lines = [
        "### Detection Guidance from the Source",
        "",
        f"Quoted from the detection section of {source}."
        if source
        else "Quoted from the source's detection section.",
        "",
        "| ID | Guidance | Runs in | Analytic |",
        "|---|---|---|---|",
    ]
    for g in req.detection_guidance:
        route = str(g.get("route", "review"))
        if route == "sigma":
            drafted = [
                t.split(": ", 1)[-1]
                for t in titles
                if t.startswith(f"Source guidance {g.get('id')}:")
            ]
            analytic = "; ".join(drafted) if drafted else "no rule drafted; write one by hand"
        elif route == "indicator":
            analytic = "covered by the IOC rules"
        else:
            analytic = str(g.get("reason", ""))
        lines.append(
            f'| {g.get("id")} | "{_cell(str(g.get("text", "")), 200)}" | {_GUIDANCE_ROUTES.get(route, route)} | '
            f"{_cell(analytic, 160)} |"
        )
    return "\n".join(lines) + "\n\n"


def _render_technique_evidence(req: DraftHuntRequest) -> str:
    """Why each technique is mapped, and which were left out as capability only."""
    rows = [e for e in req.technique_evidence if e.get("status") != "capability"]
    capability = [e for e in req.technique_evidence if e.get("status") == "capability"]
    if not rows and not capability:
        return ""
    lines = ["", "#### Technique Evidence", ""]
    if rows:
        lines += ["| Technique | Status | Evidence | Source |", "|---|---|---|---|"]
        for e in rows:
            passage = f'"{_cell(e["passage"], 220)}"' if e.get("passage") else "—"
            basis = f" ({_cell(e['behaviour'], 40)})" if e.get("behaviour") else ""
            lines.append(
                f"| {e['technique_id']} | {e.get('status', '')} | {passage}{basis} | {e.get('source', '')} |"
            )
    if capability:
        lines += [
            "",
            "Not mapped, capability only (the source describes what a tool can do, not what happened):",
            "",
        ]
        for e in capability:
            lines.append(f'- {e["technique_id"]}: "{_cell(e.get("passage", ""), 220)}"')
    return "\n".join(lines) + "\n"


_INDICATOR_KINDS = frozenset({"sha256", "sha1", "md5", "ipv4", "domain", "hostname", "url"})


def _render_hypothesis_quality(hyp: HypothesisResult) -> str:
    """Render hypothesis quality rubric and falsification criteria when available."""
    has_rubric = bool(hyp.rubric_score)
    has_baselines = bool(
        hyp.expected_malicious or hyp.expected_benign or hyp.falsification_criteria
    )
    if not has_rubric and not has_baselines:
        return ""

    lines = ["", "### Hypothesis Quality & Falsification", ""]
    if has_rubric:
        score = hyp.rubric_score
        verdict = score.get("verdict", "N/A")
        total = score.get("total", 0)
        lines += [
            f"- **Rubric Gate Verdict:** `{verdict}` ({total}/15 points)",
            f"  - Specificity: {score.get('specificity', 0)}/3 | Testability: {score.get('testability', 0)}/3 | "
            f"Falsifiability: {score.get('falsifiability', 0)}/3 | Relevance: {score.get('relevance', 0)}/3 | "
            f"Pyramid Level: {score.get('pyramid_level', 0)}/3",
            "",
        ]
    if has_baselines:
        lines += [
            "| **Dimension** | **Criteria** |",
            "|---|---|",
            f"| **Expected Malicious** | {_cell(hyp.expected_malicious or '[Review CTI and populate]', 200)} |",
            f"| **Expected Benign Baseline** | {_cell(hyp.expected_benign or '[Review baseline telemetry]', 200)} |",
            f"| **Falsification Criteria** | {_cell(hyp.falsification_criteria or '[Review telemetry falsification criteria]', 200)} |",
            "",
        ]
    return "\n".join(lines)


def _render_atomic_tests(techniques: list[str], platforms: list[str] | None = None) -> str:
    """Render Atomic Red Team validation procedures for mapped techniques."""
    if not techniques:
        return ""
    try:
        from hecate_agent.core.atomic_red_team import format_atomic_tests_markdown

        content = format_atomic_tests_markdown(techniques, platforms=platforms)
        return ("\n" + content) if content else ""
    except ImportError:
        return ""


def _render_bas_verification(req: DraftHuntRequest) -> str:
    """Render closed-loop adversary emulation & breach simulation (BAS) validation findings."""
    if not req.bas_verification:
        return ""
    bas = req.bas_verification
    status = bas.get("status", "unknown")
    if status == "skipped":
        return (
            "\n### Breach & Attack Simulation (BAS)\n\n**Skipped:** "
            + str(bas.get("reason", "No approved procedure."))
            + "\n"
        )
    status_badge = {
        "verified_true_positive": "✅ **VERIFIED TRUE POSITIVE**",
        "detection_miss": "⚠️ **DETECTION MISS (Telemetry arrived, rule missed)**",
        "telemetry_missing": "❌ **TELEMETRY MISSING (Sensor blind spot - no events observed)**",
        "detonation_failed": "⚠️ **DETONATION FAILED**",
        "error": "❌ **EXECUTION ERROR**",
    }.get(status, f"`{status}`")

    provider = str(bas.get("provider", "unknown")).upper()
    technique = bas.get("technique_id", "unspecified")
    hits = bas.get("matched_events_count", 0)
    duration = bas.get("duration_seconds", 0.0)
    notes = bas.get("notes") or []
    notes_str = "; ".join(notes) if notes else ""

    lines = [
        "",
        "### Live Adversary Emulation & Breach Simulation (BAS)",
        "",
        f"> **Closed-Loop Validation Result:** {status_badge}",
        "> ",
        f"> - **Provider:** `{provider}`",
        f"> - **Verification scope:** `{bas.get('verification_scope', 'rule_evaluation')}`",
        f"> - **Target Technique:** `{technique}` ({bas.get('ability_id', '')})",
        f"> - **Telemetry Observed:** {'Yes' if bas.get('telemetry_arrived') else 'No'}",
        f"> - **Detection Triggered:** {'Yes' if bas.get('rule_triggered') else 'No'} ({hits} hit(s))",
    ]
    if duration > 0:
        lines.append(f"> - **Duration:** {duration:.2f}s")
    if notes_str:
        lines.append(f"> - **Notes:** `{notes_str}`")
    lines.append("")
    return "\n".join(lines)


def _render_pivot_matrix(req: DraftHuntRequest) -> str:
    """Render concrete operational pivoting guidance for SOC analysts."""
    platforms_lower = {p.strip().lower() for p in req.platforms if p.strip()}
    is_macos = any(p in ("macos", "darwin", "osx") for p in platforms_lower)
    is_linux = any(p in ("linux", "containers", "kubernetes") for p in platforms_lower)
    is_cloud = any(
        p
        in (
            "cloud",
            "iaas",
            "saas",
            "aws",
            "gcp",
            "azure",
            "m365",
            "office365",
            "entra id",
            "okta",
        )
        for p in platforms_lower
    )

    if is_cloud:
        rows = [
            (
                "Anomalous API Action / Role Assumption",
                "Principal Identity & Source IP",
                "Query CloudTrail / Entra logs for all calls from principal session ±2 hours.",
            ),
            (
                "New OAuth Grant / Service Principal",
                "Permissions & App Scope",
                "Review Microsoft Graph / cloud IAM role grants for high-privilege directory permissions.",
            ),
            (
                "External Data Access / Egress Spike",
                "Target Object / Storage Bucket",
                "Check bucket access logs and VPC flow logs for unauthorized egress destinations.",
            ),
        ]
    elif is_macos:
        rows = [
            (
                "Suspicious Command Line / Script Execution",
                "Parent Process Lineage",
                "Query parent executable, code signing entitlements, and Terminal/app session ±5 min.",
            ),
            (
                "External C2 Network Connection",
                "Host Socket & DNS History",
                "Extract all outgoing connections from endpoint ±15 min; correlate with proxy logs.",
            ),
            (
                "Staged Payload / Script in User Cache",
                "File Metadata & TCC Database",
                "Check ~/Library/Caches and LaunchAgents for persistence; verify Quarantine bit status.",
            ),
            (
                "LaunchAgent / Daemon Creation",
                "Persistence & Authorization",
                "Inspect plist program arguments and run `sfltool dumpbtm` to inspect background task.",
            ),
        ]
    elif is_linux:
        rows = [
            (
                "Suspicious Command Line Parameter",
                "Parent Process Lineage",
                "Query parent PID, shell type, executable path, and user session within ±5 min.",
            ),
            (
                "External C2 Network Connection",
                "Host Socket & DNS History",
                "Extract all outbound connections from endpoint ±15 min; isolate if beaconing.",
            ),
            (
                "Staged Payload in /tmp or /dev/shm",
                "File Inode & Execution Context",
                "Inspect file permissions and hash; query auditd execve logs for related invocations.",
            ),
            (
                "Cron / Systemd Unit Persistence",
                "User Crontabs & Service Units",
                "Review /etc/cron* and /etc/systemd/system/ for unauthorized modifications.",
            ),
        ]
    else:  # Windows & Generic
        rows = [
            (
                "Suspicious Command Line Argument",
                "Parent Process Lineage",
                "Query parent executable, user account, and process tree within ±5 min.",
            ),
            (
                "External C2 Network Connection",
                "Host Socket & DNS History",
                "Extract all external connections from the endpoint within ±15 min; isolate if beaconing.",
            ),
            (
                "Staged Payload in Staging Directory",
                "File Metadata & Global Scope",
                "Compute file SHA256; search enterprise EDR for matching hashes across all endpoints.",
            ),
            (
                "Registry Persistence Key",
                "User Account & Run Keys",
                "Inspect autoruns and scheduled tasks registered by the same security identifier (SID).",
            ),
        ]

    lines = [
        "#### 4. Investigative Pivot Matrix",
        "",
        "| If Alert Trigger Shows | Pivot Investigation To | Recommended Query / Action |",
        "|---|---|---|",
    ]
    for trigger, pivot, action in rows:
        lines.append(f"| **{trigger}** | {pivot} | {action} |")
    return "\n".join(lines)


def _render_alerting_profile(req: DraftHuntRequest) -> str:
    """Render operational deployment mode, alerting tier, and rate-limiting guidance."""
    is_ioc = req.hypothesis.is_indicator_only
    tier = (
        "Tier-3 Retrospective Sweep / Scheduled Hunt"
        if is_ioc
        else "Tier-1 Real-Time Alert / High-Fidelity TTP"
    )
    throttle = (
        "Aggregate by IOC, run weekly across 30-day historical telemetry."
        if is_ioc
        else "Aggregate by `Computer, User` (1-hour window); alert immediately on first occurrence."
    )
    return (
        "#### 5. Operational Alerting Profile\n\n"
        f"- **Recommended Deployment Tier:** `{tier}`\n"
        f"- **Aggregation & Throttling:** {throttle}\n"
        "- **Target Queue:** SOC Primary Queue for single-host detection; IR Priority Queue if multi-host correlation is observed.\n"
    )


def _render_telemetry_prerequisites(req: DraftHuntRequest) -> str:
    """Render platform-specific audit policies and telemetry prerequisites."""
    platforms_lower = {p.strip().lower() for p in req.platforms if p.strip()}
    sources = set(req.hypothesis.data_sources or [])
    lines: list[str] = []

    if any(p in ("windows", "endpoint") for p in platforms_lower) or not platforms_lower:
        lines.append("- **Windows Audit Policies & Telemetry:**")
        lines.append(
            "  - Process Creation: Windows Event ID 4688 (with CLI auditing enabled) or Sysmon Event ID 1."
        )
        if "network_connections" in sources or "proxy" in sources or "dns_query" in sources:
            lines.append(
                "  - Network Activity: Sysmon Event ID 3 (Network Connection) or EDR `DeviceNetworkEvents`."
            )
        if "registry_events" in sources:
            lines.append(
                "  - Registry Monitoring: Sysmon Event ID 12/13/14 or EDR `DeviceRegistryEvents`."
            )
        if "file_operations" in sources:
            lines.append(
                "  - File Integrity / Creation: Sysmon Event ID 11 or EDR `DeviceFileEvents`."
            )
        lines.append(
            "  - Scripting: PowerShell ScriptBlock Logging (Microsoft-Windows-PowerShell/Operational Event ID 4104)."
        )

    if any(p in ("linux", "containers", "kubernetes") for p in platforms_lower):
        lines.append("- **Linux Audit & Sensor Requirements:**")
        lines.append(
            "  - Process Execution: `auditd` rule (`-a always,exit -F arch=b64 -S execve`) or eBPF process monitor."
        )
        lines.append(
            "  - Socket & Network: eBPF socket connect probes or auditd network tracing (`connect`, `bind`)."
        )
        lines.append(
            "  - File Monitoring: Inotify / auditd watches on sensitive directories (`/tmp`, `/etc/cron*`, `/etc/systemd`)."
        )

    if any(
        p
        in (
            "cloud",
            "iaas",
            "saas",
            "aws",
            "gcp",
            "azure",
            "m365",
            "office365",
            "entra id",
            "okta",
        )
        for p in platforms_lower
    ):
        lines.append("- **Cloud & Identity Audit Telemetry:**")
        lines.append(
            "  - Management Plane: AWS CloudTrail (management + S3/Lambda data events), Entra ID AuditLogs & SignInLogs."
        )
        lines.append(
            "  - Identity Token Monitoring: OAuth app consent grants, STS `AssumeRole` events, service principal credential updates."
        )

    if any(p in ("macos", "darwin", "osx") for p in platforms_lower):
        lines.append("- **macOS Telemetry Sources:**")
        lines.append(
            "  - Endpoint Security Framework (ESF) process, file, and authorization events."
        )
        lines.append(
            "  - Apple Unified Logging subsystem monitoring for `com.apple.security` and `com.apple.TCC`."
        )

    return (
        "\n".join(lines)
        if lines
        else "- Standard enterprise endpoint and network telemetry logging enabled."
    )


def _render_attack_chain(req: DraftHuntRequest) -> str:
    """Render a tactical attack sequence flow for mapped techniques and tactics."""
    techniques = req.hypothesis.techniques
    if not techniques:
        return ""
    tactics = req.tactics or []
    tactic_order = [
        "initial-access",
        "execution",
        "persistence",
        "privilege-escalation",
        "defense-evasion",
        "credential-access",
        "discovery",
        "lateral-movement",
        "collection",
        "command-and-control",
        "exfiltration",
        "impact",
    ]
    ordered_tactics = [t for t in tactic_order if t in tactics] or tactics
    if ordered_tactics:
        chain_str = " ➔ ".join(f"`{t.replace('-', ' ').title()}`" for t in ordered_tactics[:6])
        return f"- **Adversary Attack Path Progression:** {chain_str}\n"
    if len(techniques) > 1:
        return f"- **Attack Chain Progression:** `{' ➔ '.join(techniques[:5])}`\n"
    return ""


def _render_campaign_history(req: DraftHuntRequest) -> str:
    """Render incremental enrichment history for living campaign dossiers."""
    updates = getattr(req, "campaign_updates", None)
    if not updates:
        return ""
    lines = [
        "",
        "### Campaign Evolution & Incremental Dossier History",
        "",
        "| Date | Source / CTI | Action Taken | Incremental Indicators | Rule Variants |",
        "|---|---|---|---|---|",
    ]
    for update in updates:
        date = str(update.get("date", req.generated_at.strftime("%Y-%m-%d")))
        source = str(update.get("source", "CTI Update"))
        action = str(update.get("action", "Enrichment"))
        iocs = str(update.get("new_iocs", "None"))
        rules = str(update.get("rule_variants", "None"))
        lines.append(f"| {date} | {source} | {action} | {iocs} | {rules} |")
    lines.append("")
    return "\n".join(lines)


def _render_soc_triage_playbook(req: DraftHuntRequest) -> str:
    """Render SOC Responder Triage Playbook (ADS-Lite) to guide analysts when alerts fire."""
    if req.hypothesis.is_indicator_only:
        return (
            "\n### SOC Responder Triage Playbook (ADS-Lite)\n\n"
            "**Target Scope:** Indicator Sweep (IOC presence in telemetry)  \n"
            "**Strategy Abstract:** Detects presence of reported network or file indicators across enterprise telemetry.\n\n"
            "#### 1. Triage & Initial Scoping (First 3 Steps)\n"
            "1. **Indicator Match Verification:** Verify whether the observed hit is an exact match against "
            "the reported indicator list (IP, domain, URL, or hash).\n"
            "2. **Host & User Scoping:** Identify endpoints or accounts that connected to or created the indicator.\n"
            "3. **Temporal Scoping:** Determine the first and last observed timestamps of the indicator activity.\n\n"
            "#### 2. Containment & IR Escalation\n"
            "- **Blocklist Enforcement:** Add confirmed malicious domains/IPs to edge proxy and firewall perimeter blocks.\n"
            "- **Host Isolation:** Isolate endpoints with confirmed execution or bidirectional communication.\n"
            "- **Incident Escalation:** Escalate to Incident Response if multiple internal hosts query or connect to the IOCs.\n\n"
            "#### 3. Detection Robustness & Evasion Cost\n"
            "- **Observable Robustness:** IOC-centric (Pyramid of Pain: Hashes / IP Addresses / Domains). Fragile and easily changed by adversary.\n"
            "- **Event Robustness:** Sensor & perimeter logging (Proxy, DNS, Firewall, EDR network events).\n"
            "- **Adversary Evasion Cost:** Low — adversary can rapidly alter domain or IP infrastructure.\n\n"
            + _render_alerting_profile(req)
        )

    techniques = ", ".join(req.hypothesis.techniques) if req.hypothesis.techniques else "Unmapped"
    behavior = req.hypothesis.behavior or req.hypothesis.hypothesis or "Target behavior"
    platforms_lower = {p.strip().lower() for p in req.platforms if p.strip()}

    # Cloud / SaaS / Identity Triage Playbook
    if any(
        p
        in (
            "iaas",
            "saas",
            "cloud",
            "aws",
            "gcp",
            "azure",
            "office365",
            "m365",
            "entra id",
            "google workspace",
            "okta",
        )
        for p in platforms_lower
    ):
        return (
            "\n### SOC Responder Triage Playbook (ADS-Lite)\n\n"
            f"**Target Technique:** `{techniques}`  \n"
            f"**Strategy Abstract:** Detects `{_cell(behavior, 120)}` in Cloud/SaaS telemetry by identifying anomalous "
            "API calls, privilege escalation, or identity token abuse contrasting with the authorized baseline.\n\n"
            "#### 1. Triage & Initial Scoping (First 3 Steps)\n"
            "1. **Identity & API Verification:** Review CloudTrail, Entra, or SaaS audit logs for the invoking "
            "principal ARN, user account, source IP address, user agent, and MFA status.\n"
            "2. **Identity & Host Scoping:** Identify whether the actor assumed additional roles (STS AssumeRole), "
            "granted OAuth permissions, or generated new API access keys within +/- 2 hours of the alert.\n"
            "3. **Telemetry Correlation:** Correlate across cloud accounts, regions, or tenants for concurrent "
            "actions originating from the same session token, IP, or credential set.\n\n"
            "#### 2. Containment & IR Escalation\n"
            "- **Immediate Isolation Threshold:** Disable compromised access keys, revoke active session tokens, "
            "and remove illicit OAuth app consents or IAM role attachments immediately.\n"
            "- **Credential Invalidation:** Force password reset, revoke active refresh tokens, and re-issue MFA credentials.\n"
            "- **Incident Escalation:** Escalate to Tier-2 / IR Incident Commander if persistence mechanisms or secondary host "
            "compromise attempts are identified.\n\n"
            "#### 3. Detection Robustness & Evasion Cost\n"
            "- **Observable Robustness:** Behavioral / TTP-centric (Pyramid of Pain: TTPs). Resistant to IP or tool rotation.\n"
            "- **Event Robustness:** Control Plane / Management Plane audit telemetry (immutable CloudTrail / Entra Audit logs).\n"
            "- **Adversary Evasion Cost:** High — adversary cannot bypass management-plane audit logging without cloud control plane compromise.\n\n"
            + _render_pivot_matrix(req)
            + "\n\n"
            + _render_alerting_profile(req)
        )

    # Linux & Containers Triage Playbook
    if any(p in ("linux", "containers", "kubernetes") for p in platforms_lower):
        return (
            "\n### SOC Responder Triage Playbook (ADS-Lite)\n\n"
            f"**Target Technique:** `{techniques}`  \n"
            f"**Strategy Abstract:** Detects `{_cell(behavior, 120)}` on Linux/Container hosts by identifying anomalous "
            "execution patterns contrasting with authorized system administration baselines.\n\n"
            "#### 1. Triage & Initial Scoping (First 3 Steps)\n"
            "1. **Lineage Verification:** Inspect process tree, parent shell PID, executable inode/path, and namespace context "
            "to determine whether execution originated from an authorized SSH session or deployment pipeline.\n"
            "2. **Identity & Host Scoping:** Check `/var/log/auth.log`, `auditd`, and PAM events within +/- 2 hours "
            "to assess authentication method (SSH key vs password), `sudo` elevation, or abnormal TTY allocation.\n"
            "3. **Telemetry Correlation:** Correlate network socket connections with file creations in `/tmp`, `/var/tmp`, "
            "or `/dev/shm`, and check for new cron jobs or systemd service units.\n\n"
            "#### 2. Containment & IR Escalation\n"
            "- **Immediate Isolation Threshold:** Apply container network policy or host iptables isolation if unauthorized "
            "binaries execute from world-writable paths or `/etc/shadow` / credential stores are accessed.\n"
            "- **Credential Invalidation:** Terminate active SSH/TTY sessions, rotate compromised user SSH keys and passwords.\n"
            "- **Incident Escalation:** Escalate to Tier-2 / IR Incident Commander if persistence mechanisms or secondary host "
            "compromise attempts are identified.\n\n"
            "#### 3. Detection Robustness & Evasion Cost\n"
            "- **Observable Robustness:** Behavioral / TTP-centric (Pyramid of Pain: TTPs). Resistant to simple script or binary renaming.\n"
            "- **Event Robustness:** Sensor & kernel audit telemetry (`auditd`, eBPF, EDR Linux sensor).\n"
            "- **Adversary Evasion Cost:** High — adversary must redesign execution vehicle or bypass telemetry hooks.\n\n"
            + _render_pivot_matrix(req)
            + "\n\n"
            + _render_alerting_profile(req)
        )

    # macOS Triage Playbook
    if any(p in ("macos", "darwin", "osx") for p in platforms_lower):
        return (
            "\n### SOC Responder Triage Playbook (ADS-Lite)\n\n"
            f"**Target Technique:** `{techniques}`  \n"
            f"**Strategy Abstract:** Detects `{_cell(behavior, 120)}` on macOS endpoints by identifying anomalous "
            "execution patterns, LaunchAgent/Daemon persistence, or Gatekeeper bypass contrasting with authorized baselines.\n\n"
            "#### 1. Triage & Initial Scoping (First 3 Steps)\n"
            "1. **Lineage Verification:** Inspect process tree, parent process path, code signatures (codesign/spctl), "
            "and execution context (Terminal, Script Editor, or background service).\n"
            "2. **Identity & Host Scoping:** Check Unified Logging / OpenBSM audit trails and system logs within +/- 2 hours "
            "for authorization prompts (osascript, sudo), user login sessions, or keychain access attempts.\n"
            "3. **Telemetry Correlation:** Correlate network connections with file creations in `~/Library/LaunchAgents`, "
            "`/Library/LaunchDaemons`, `/tmp`, or `~/Library/Caches`, and check for `xattr` modifications.\n\n"
            "#### 2. Containment & IR Escalation\n"
            "- **Immediate Isolation Threshold:** Host network isolation is recommended if unsigned or ad-hoc signed Mach-O binaries execute "
            "from non-standard paths, or credential stores (Keychains, browser profiles) are accessed.\n"
            "- **Credential Invalidation:** Revoke active user sessions and rotate credentials for affected accounts.\n"
            "- **Incident Escalation:** Escalate to Tier-2 / IR Incident Commander if persistence mechanisms or secondary host "
            "compromise attempts are identified.\n\n"
            "#### 3. Detection Robustness & Evasion Cost\n"
            "- **Observable Robustness:** Behavioral / TTP-centric (Pyramid of Pain: TTPs). Resistant to file hash or binary path changes.\n"
            "- **Event Robustness:** Endpoint Security Framework (ESF) / Unified Logging sensor telemetry.\n"
            "- **Adversary Evasion Cost:** High — adversary must redesign execution vehicle or bypass macOS transparency and security hooks.\n\n"
            + _render_pivot_matrix(req)
            + "\n\n"
            + _render_alerting_profile(req)
        )

    # Windows & Generic Endpoint Triage Playbook
    return (
        "\n### SOC Responder Triage Playbook (ADS-Lite)\n\n"
        f"**Target Technique:** `{techniques}`  \n"
        f"**Strategy Abstract:** Detects `{_cell(behavior, 120)}` by identifying anomalous execution patterns "
        "and telemetry signatures contrasting with the established benign baseline.\n\n"
        "#### 1. Triage & Initial Scoping (First 3 Steps)\n"
        "1. **Lineage Verification:** Inspect process tree, command-line arguments, and parent-child relationships "
        "to confirm if the execution originated from an authorized administrative workflow or interactive session.\n"
        "2. **Identity & Host Scoping:** Identify the executing user principal and assess authentication logs "
        "(e.g., Event ID 4624 / IdP audit) within +/- 2 hours of alert trigger for anomalous source IPs or MFA fatigue.\n"
        "3. **Telemetry Correlation:** Correlate with network connection logs (Sysmon Event ID 3 / proxy logs) and file "
        "creations in `%TEMP%` or `%APPDATA%` to identify staging or C2 communication.\n\n"
        "#### 2. Containment & IR Escalation\n"
        "- **Immediate Isolation Threshold:** Host network isolation is recommended if unrecognized binaries execute "
        "from non-standard paths or direct credential access (e.g. LSASS access, SAM hive export) is observed.\n"
        "- **Credential Invalidation:** Revoke active user sessions and rotate credentials for affected accounts.\n"
        "- **Incident Escalation:** Escalate to Tier-2 / IR Incident Commander if persistence mechanisms or secondary host "
        "compromise attempts are identified.\n\n"
        "#### 3. Detection Robustness & Evasion Cost\n"
        "- **Observable Robustness:** Behavioral / TTP-centric (Pyramid of Pain: TTPs). Resistant to simple file hash or IP changes.\n"
        "- **Event Robustness:** Kernel / EDR sensor-level telemetry (e.g., Sysmon / EDR process creation & memory access).\n"
        "- **Adversary Evasion Cost:** High — adversary must redesign execution vehicle or bypass telemetry hooks.\n\n"
        + _render_pivot_matrix(req)
        + "\n\n"
        + _render_alerting_profile(req)
    )


def render_draft(req: DraftHuntRequest) -> str:
    """Return the full markdown content for a draft hunt."""
    hyp = req.hypothesis
    # Frontmatter carries only real, validated values; an unmapped field is
    # left empty rather than filled with a stand-in. "TXXXX" and
    # "unclassified" used to sit here as "honest placeholders", but both are
    # checked by `hecate-agent hunt validate` against the ATT&CK matrix, so every
    # draft that hit this path was written already failing the framework's
    # own validator ("Unknown MITRE technique: TXXXX"). "TXXXX" also *looks*
    # like a real ATT&CK ID at a glance, which a word like "unclassified"
    # at least does not. The human-facing gap markers live in the rendered
    # body below, where a reviewer actually reads them.
    techniques = hyp.techniques
    tactics = req.tactics
    platforms = req.platforms
    # Body-only rendering of the same gap, for the reviewer rather than the
    # validator. An empty ", ".join() would render a bare dangling label.
    techniques_display = (
        ", ".join(techniques) if techniques else "[none mapped - human to populate]"
    )
    # An empty list is an honest gap the reviewer can see; a vendor name is a
    # fabricated answer to "what telemetry does this hunt need", and this
    # workspace has no CrowdStrike. The rendered body already shows "[TBD]"
    # for the same emptiness.
    data_sources = hyp.data_sources

    def bullets(items: list[str]) -> str:
        return "\n".join(f"- {i}" for i in items) if items else "- [TBD]"

    # YAML frontmatter — list fields serialized with json.dumps to get valid quoting
    frontmatter = (
        "---\n"
        f"hunt_id: {req.hunt_id}\n"
        f"title: {_title_scalar(hyp.hypothesis)}\n"
        "status: planning\n"
        f"date: {req.generated_at.strftime('%Y-%m-%d')}\n"
        "hunter: hecate-runner orchestrator (draft)\n"
        f"platform: {json.dumps(platforms)}\n"
        f"tactics: {json.dumps(tactics)}\n"
        f"techniques: {json.dumps(techniques)}\n"
        f"data_sources: {json.dumps(data_sources)}\n"
        + (f"spawned_from: {req.research_id}\n" if req.research_id else "")
        + f"related_hunts: {json.dumps(req.related_hunts)}\n"
        "findings_count: 0\n"
        "true_positives: 0\n"
        "false_positives: 0\n"
        "customer_deliverables: []\n"
        f"tags: {json.dumps(_draft_tags(hyp.is_threat_report, hyp.is_indicator_only))}\n"
        + (
            f"purple_team_validated: {str(req.purple_team_rules_validated > 0).lower()}\n"
            f"purple_team_rules_evaluated: {req.purple_team_rules_evaluated}\n"
            f"purple_team_rules_validated: {req.purple_team_rules_validated}\n"
            f"purple_team_rules_tuned: {req.purple_team_rules_tuned}\n"
            f"purple_team_telemetry_events: {req.purple_team_telemetry_count}\n"
            if req.purple_team_rules_evaluated > 0
            else ""
        )
        + (
            (
                f"bas_verified: {str(req.bas_verification.get('status') == 'verified_true_positive').lower()}\n"
                if req.bas_verification.get("status") != "skipped"
                else ""
            )
            + f"bas_run_id: {json.dumps(req.bas_verification.get('run_id', ''))}\n"
            f"bas_provider: {json.dumps(req.bas_verification.get('provider', ''))}\n"
            f"bas_status: {json.dumps(req.bas_verification.get('status', ''))}\n"
            f"bas_backend: {json.dumps(req.bas_verification.get('backend', ''))}\n"
            f"bas_detection_triggered: {str(bool(req.bas_verification.get('rule_triggered'))).lower()}\n"
            if req.bas_verification
            else ""
        )
        + "---\n\n"
    )

    low_confidence_banner = (
        (
            "\n> **🚩 LOW-CONFIDENCE SOURCE:** The hypothesis-generator judged that the source CTI "
            "does not actually describe observed/reported adversary behavior (e.g. vendor/product "
            "marketing, a compliance announcement) -- this hypothesis is speculative, not derived "
            f"from a specific reported campaign. {hyp.low_confidence_reason or ''}".rstrip()
        )
        if not hyp.is_threat_report
        else ""
    )

    # OBSERVE mirrors the three subsections of Hecate's own HUNT_LOCK template.
    # It previously carried a fourth, "Known False Positives", and left "What
    # Normal Looks Like" as "[Human review required]" -- but the template
    # defines that section as "legitimate activity that might trigger false
    # positives", which is exactly what hyp.false_positives holds. So the most
    # useful section in the block sat empty while its content was rendered
    # under an invented heading below it. "Expected Observables" likewise
    # repeated hyp.observables verbatim from "What Suspicious Looks Like"; it
    # now carries only what is actually distinct, the data sources.
    body = f"""# {req.hunt_id}: DRAFT - Automated Hunt Draft

> **⚠️ This hunt was auto-generated by hecate-runner.**
> **Do not execute queries until a human reviews the Learn/Observe sections and advances the status.**
{low_confidence_banner}

**Hunt Metadata**

- **Date:** {req.generated_at.strftime("%Y-%m-%d")}
- **Hunter:** hecate-runner orchestrator (draft)
- **Status:** planning
- **MITRE ATT&CK:** {techniques_display}

---

## LEARN: Prepare the Hunt

### Hypothesis Statement

{hyp.hypothesis or "[Model produced no hypothesis - review CTI intake]"}

### Threat Context

Source CTI:

> {embedded_cti(req.threat_intel)}

{_render_source_evidence(req)}### Justification

{hyp.justification or "[No justification generated]"}

### ABLE Scoping

| **Field**   | **Your Input** |
|-------------|----------------|
| **Actor** | {_able_cell(hyp.actor)} |
| **Behavior** | {_able_cell(hyp.behavior)} |
| **Location** | {_able_cell(hyp.location)} |
| **Evidence** | {_able_cell(hyp.evidence)} |
{_render_hypothesis_quality(hyp)}
### Threat Intel & Research

- **MITRE ATT&CK Techniques:** {techniques_display}
{_render_attack_chain(req)}- **CTI Sources & References:** {f"[{req.source_url}]({req.source_url})" if req.source_url else "[Review CTI and populate]"}
{_research_document_line(req)}
{_render_technique_evidence(req)}
{_render_claim_evidence(req)}
### Grounding

{req.grounding_section or "Not yet audited."}{_render_claim_audit(req)}
{_render_campaign_history(req)}
### Related Tickets

| **Team** | **Ticket/Details** |
|----------|-------------------|
| **SOC/IR** | N/A (auto-generated) |

---

## OBSERVE: Expected Behaviors

### What Normal Looks Like

{bullets(hyp.false_positives)}

### What Suspicious Looks Like

{bullets(hyp.observables)}

### Expected Observables

- **Data Sources:** {", ".join(hyp.data_sources) or "[TBD]"}
- **Observables:** listed under "What Suspicious Looks Like" above

### Telemetry & Audit Prerequisites

{_render_telemetry_prerequisites(req)}

---

## CHECK: Execute & Analyze

### Data Source Information

- **Index/Data Source:** [Human to populate]
- **Time Range:** [Human to populate]
- **Events Analyzed:** 0 (draft - not yet executed)
- **Data Quality:** N/A

{_render_detection_guidance(req)}### Hunting Queries

{_render_sigma_section(req)}{_render_review_gaps(req)}
{_render_atomic_tests(techniques, platforms=req.platforms)}
{_render_bas_verification(req)}
---

## KEEP: Findings & Response

### Executive Summary

[To be completed after human review and execution]

### Findings

| **Finding** | **Ticket** | **Description** |
|-------------|-----------|-----------------|
| N/A | N/A | Draft only |

**True Positives:** 0
**False Positives:** 0
{_render_soc_triage_playbook(req)}
---

**Draft Created:** {req.generated_at.strftime("%Y-%m-%d %H:%M:%S UTC")} by hecate-runner
**Next Review:** [Human review required before status can advance to `in-progress`]
"""
    prose_sources = [
        req.threat_intel,
        hyp.hypothesis,
        hyp.justification,
        hyp.actor,
        hyp.behavior,
        hyp.location,
        hyp.evidence,
        hyp.expected_malicious,
        hyp.expected_benign,
        hyp.falsification_criteria,
        hyp.low_confidence_reason,
        req.grounding_section,
        *hyp.observables,
        *hyp.false_positives,
    ]
    prose_sources.extend(str(record.get("value", "")) for record in req.indicator_records)
    prose_sources.extend(str(rule.get("title", "")) for rule in req.sigma_rules)
    prose_sources.extend(
        str(artifact.get(field, ""))
        for artifact in req.source_evidence.get("artifacts", [])
        for field in ("value", "evidence")
    )
    for records, fields in (
        (req.claim_audit, ("text", "reason")),
        (req.claim_evidence, ("claim", "quote")),
        (req.detection_guidance, ("text", "reason")),
        (req.review_gaps, ("behaviour", "quote")),
        (req.technique_evidence, ("passage", "behaviour")),
    ):
        prose_sources.extend(str(record.get(field, "")) for record in records for field in fields)
    if req.bas_verification:
        prose_sources.extend(str(note) for note in req.bas_verification.get("notes") or [])
    network_iocs = _network_ioc_tokens("\n".join(str(value) for value in prose_sources))
    network_iocs.update(
        str(record.get("value", "")).strip()
        for record in req.indicator_records
        if (
            str(record.get("type", "")).lower() in {"ipv4", "ip", "domain", "hostname", "url"}
            and str(record.get("value", "")).strip()
        )
    )
    return _defang_prose_iocs(frontmatter + body, network_iocs)


def write_draft(req: DraftHuntRequest, hunts_root: Path) -> Path:
    """Render and write the draft. Returns the file path."""
    path = draft_hunt_path(hunts_root, req.hunt_id, req.generated_at)
    path.parent.mkdir(parents=True, exist_ok=True)
    atomic_write_text(path, render_draft(req))
    log.info("Wrote draft hunt %s (%d bytes)", path, path.stat().st_size)
    return path


def utcnow() -> datetime:
    return datetime.now(UTC)
