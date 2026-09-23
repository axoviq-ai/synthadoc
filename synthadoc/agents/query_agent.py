# SPDX-License-Identifier: AGPL-3.0-or-later
# Copyright (C) 2026 Paul Chen / axoviq.com
from __future__ import annotations

import asyncio
import logging
import re
import time
from dataclasses import dataclass, field
from pathlib import Path

from synthadoc.agents._base import BaseAgent
from synthadoc.agents._query_utils import (
    has_cjk,
    detect_cjk_language,
    filter_history_by_language,
    history_block,
    build_synthesis_system,
    trim_history,
    decompose_question,
    STOPWORDS,
)
from synthadoc.agents.action_agent import ActionAgent
from synthadoc.agents.hint_engine import HintEngine, SessionMode
from synthadoc.agents.lint_agent import LINT_SKIP_SLUGS
from synthadoc.agents.rewrite_agent import RewriteAgent
from synthadoc.agents.search_decompose_agent import SearchDecomposeAgent
from synthadoc.providers.base import LLMProvider, Message
from synthadoc.storage.log import AuditDB
from synthadoc.storage.search import HybridSearch, SearchResult
from synthadoc.storage.wiki import WikiStorage

logger = logging.getLogger(__name__)

_MIN_TERM_FREQ = 2

# ── bundled system knowledge (answers Synthadoc product questions) ────────────
_KNOWLEDGE_DIR = Path(__file__).parent.parent / "knowledge"


@dataclass
class _SystemPage:
    keywords: list[str]
    title: str
    content: str


def _load_system_knowledge() -> list[_SystemPage]:
    """Load bundled knowledge pages from synthadoc/knowledge/ once at import."""
    pages: list[_SystemPage] = []
    if not _KNOWLEDGE_DIR.exists():
        return pages
    for md_file in sorted(_KNOWLEDGE_DIR.glob("*.md")):
        try:
            text = md_file.read_text(encoding="utf-8")
            keywords: list[str] = []
            title = md_file.stem
            content = text
            if text.startswith("---"):
                parts = text.split("---", 2)
                if len(parts) >= 3:
                    fm = parts[1]
                    content = parts[2].strip()
                    for line in fm.splitlines():
                        if line.startswith("title:"):
                            title = line[6:].strip()
                        elif line.startswith("keywords:"):
                            kw_raw = line[9:].strip()
                            if kw_raw.startswith("["):
                                keywords = [
                                    k.strip().strip("\"'")
                                    for k in kw_raw.strip("[]").split(",")
                                    if k.strip()
                                ]
            pages.append(_SystemPage(keywords=keywords, title=title, content=content))
        except Exception as exc:
            logger.warning("system knowledge: could not load %s (%s)", md_file, exc)
    return pages


_SYSTEM_KNOWLEDGE: list[_SystemPage] = _load_system_knowledge()
_CANDIDATE_POOL_SIZE = 20

# CJK helpers, STOPWORDS, history helpers, synthesis system builder, trim_history,
# and decompose_question are imported from _query_utils above.

# Backward-compatible aliases — keep old private names accessible for existing tests
# that import them directly from this module.
_has_cjk = has_cjk
_detect_cjk_language = detect_cjk_language
_filter_history_by_language = filter_history_by_language
_history_block = history_block
_STOPWORDS = STOPWORDS


@dataclass
class QueryResult:
    question: str
    answer: str
    citations: list[str]
    tokens_used: int = 0
    input_tokens: int = 0
    output_tokens: int = 0
    knowledge_gap: bool = False
    suggested_searches: list[str] = field(default_factory=list)
    sub_questions_count: int = 0
    cacheable: bool = True  # False for action results and live-data answers
    routing_warning: str = ""  # Non-empty when routing-scoped search fell back to full corpus
    cross_wiki_offline: list[str] = field(default_factory=list)
    cross_wiki_searched: list[str] = field(default_factory=list)
    cross_wiki_skipped: bool = False
    cross_wiki_skip_reason: str = ""


# Keywords that indicate the question is asking about live wiki state
_LIVE_DATA_TRIGGERS: frozenset[str] = frozenset({
    "stale", "archived", "archive", "draft", "active", "contradicted",
    "contradictions", "contradiction", "review", "lifecycle", "lifecycle state",
    "pages marked", "which pages", "how many pages", "page count",
    "changed", "this week", "recently", "recent changes", "what's new",
    "whats new", "updated", "new pages", "added", "last week", "past week",
    "this month", "last month", "past month", "this year", "last year", "past year",
    "adversarial", "adversarial warning", "flagged", "overstated", "claim concern",
    "lint warning", "warnings",
    "truncated", "truncation", "max_source_chars", "source limit",
    "job", "jobs", "job id", "job status", "ingest job", "queue",
    "pending jobs", "failed job", "dead job",
    "wiki status", "page status", "show status",
    "lint", "lint report", "lint run", "lint results", "lint check",
})

_LINT_TRIGGERS: frozenset[str] = frozenset({
    "lint", "lint report", "lint run", "lint results", "lint check", "lint status",
    "last lint", "lint summary",
})

_RECENT_CHANGE_TRIGGERS: frozenset[str] = frozenset({
    "changed", "this week", "recently", "recent changes", "what's new",
    "whats new", "updated", "new pages", "added", "last week", "past week",
    "this month", "last month", "past month", "this year", "last year", "past year",
})

_ADVERSARIAL_TRIGGERS: frozenset[str] = frozenset({
    "adversarial", "adversarial warning", "flagged", "overstated", "claim concern",
    "lint warning", "warnings",
})

_TRUNCATION_TRIGGERS: frozenset[str] = frozenset({
    "truncated", "truncation", "max_source_chars", "source limit",
})

_JOB_TRIGGERS: frozenset[str] = frozenset({
    "job", "jobs", "job id", "job status", "ingest job", "queue",
    "pending jobs", "failed job", "dead job",
})

# Phrase fragments that identify meta/introspective questions about the wiki's own
# content or scope ("What topics does this wiki cover?"). These can never be gaps:
# the answer is precisely the retrieved wiki pages. Gap detection would fire here
# because all content words (topic, cover, scope, wiki) are either stopwords or
# too short, leaving _key_terms empty and candidates < 3 (signal 1 fires).
# CLI subcommands — if the question starts with "synthadoc <subcommand>" or
# contains known CLI patterns, treat it as a system knowledge query and suppress
# gap. This prevents wiki-miss false positives when users paste CLI commands.
_SYNTHADOC_CLI_SUBCOMMANDS: frozenset[str] = frozenset({
    "synthadoc ingest", "synthadoc jobs", "synthadoc job",
    "synthadoc lifecycle", "synthadoc lint", "synthadoc status",
    "synthadoc export", "synthadoc candidates", "synthadoc web",
    "synthadoc query", "synthadoc config",
})

_WIKI_INTROSPECTIVE_TRIGGERS: frozenset[str] = frozenset({
    "what topics",
    "key topics",
    "what subject",
    "what does this wiki",
    "what's in this wiki",
    "whats in this wiki",
    "what is in this wiki",
    "what does my wiki",
    "what does your wiki",
    "what pages",
    "wiki cover",
    "wiki contain",
    "wiki includ",
    "wiki know about",
    "topics covered",
    "subjects covered",
    "topics in this wiki",
    "topics in my wiki",
    "this wiki cover",
    "this wiki know",
    "this wiki includ",
    "this wiki contain",
    # Wiki-purpose / scope meta-queries: "Summarize Wiki Purpose — General",
    # "What is the purpose of this wiki?". These always resolve from purpose.md
    # (pinned as _purpose_ctx) so gap detection would fire falsely on 0 candidates.
    "wiki purpose",
    "purpose of this wiki",
    "purpose of my wiki",
    "purpose of your wiki",
    "summarize wiki",
})

# ── Hints used in _fetch_live_wiki_data for lifecycle state display ────────────
_HINTS: dict[str, str] = {
    "draft":        "← run `synthadoc lint run` to promote",
    "stale":        "← re-ingest needed",
    "contradicted": "← review required",
}


def _select_live_data_question(question: str, retrieval_question: str) -> str:
    """Return which question string to use for live-data trigger detection.

    Three cases:
    1. Original question already contains live-data trigger words → use it directly.
    2. Original question is specific (≥3 content key terms) → use it to avoid false
       positives when the rewrite injects history words like "active" or "stale".
    3. Original question is vague (<3 content key terms, e.g. "check it again") → use
       retrieval_question so the resolved intent triggers the correct live-data path.
    """
    q_lower = question.lower()
    if any(kw in q_lower for kw in _LIVE_DATA_TRIGGERS):
        return question
    content_term_count = sum(
        1 for w in question.split()
        if len(w) >= 4 and w.lower().rstrip("s'?!.,") not in STOPWORDS
    )
    return question if content_term_count >= 3 else retrieval_question


def _is_introspective(question: str) -> bool:
    """Return True when a question asks about the wiki's own content or scope,
    or is a Synthadoc CLI invocation — both should suppress gap detection."""
    q = question.lower()
    return any(t in q for t in _WIKI_INTROSPECTIVE_TRIGGERS) or any(
        q.startswith(c) for c in _SYNTHADOC_CLI_SUBCOMMANDS
    )


def _parse_lookback_days(question: str) -> int:
    """Return a lookback window in days parsed from natural language time phrases.

    Recognises "last N months/weeks", month/year keywords, and falls back to 7 days
    (one week) for bare "recently", "this week", "last week", etc.
    """
    q = question.lower()
    m = re.search(r'(?:last|past)\s+(\d+)\s+months?', q)
    if m:
        return int(m.group(1)) * 30
    m = re.search(r'(?:last|past)\s+(\d+)\s+weeks?', q)
    if m:
        return int(m.group(1)) * 7
    if any(kw in q for kw in ("this year", "last year", "past year")):
        return 365
    if any(kw in q for kw in ("this month", "last month", "past month")):
        return 30
    return 7  # week / recently / default


_GUARD_C_MIN_CHARS = 300
_GUARD_C_MIN_CITATIONS = 2
# "What does X cover?" queries cite exactly one page yet produce very long answers.
# Suppress the gap when the answer is clearly comprehensive even with a single citation.
_GUARD_C_HIGH_CONFIDENCE_CHARS = 800


def _guard_c_suppress(gap: bool, answer: str, caller: str) -> bool:
    """Return False (suppress gap) when the answer is substantial and well-cited.

    Guards A/B detect gaps; Guard C is the corrective: if _detect_gap() fired
    pre-synthesis but the LLM still produced a long, well-cited answer without
    a [GAP] prefix, the wiki clearly covered the question and the gap was a
    false positive.

    Two suppression paths:
    - Standard: >300 chars + ≥2 wiki citations (multi-source answers).
    - High-confidence: >800 chars + ≥1 wiki citation — covers single-source
      queries like "What does X cover?" where the answer summarises one page
      and naturally produces only one [[wikilink]] reference.
    """
    if not gap or answer.startswith("[GAP]"):
        return gap
    n_chars = len(answer)
    cite_count = len(re.findall(r"\[\[[^\]]+\]\]", answer))
    standard = n_chars > _GUARD_C_MIN_CHARS and cite_count >= _GUARD_C_MIN_CITATIONS
    high_conf = n_chars > _GUARD_C_HIGH_CONFIDENCE_CHARS and cite_count >= 1
    if standard or high_conf:
        logger.debug(
            "%s: guard C suppressed false-positive gap — %d chars, %d wiki citations",
            caller, n_chars, cite_count,
        )
        return False
    return gap


# Matches [MISSING: slug1, slug2] on its own line.
# ']' is optional — LLMs sometimes omit the closing bracket.
# '^' anchor (MULTILINE) ensures we only match at the start of a line,
# preventing accidental matches in mid-sentence wikilink patterns.
_MISSING_RE = re.compile(r'^\[MISSING:\s*([^\]\n]+?)(?:\])?\s*$', re.MULTILINE)


def _extract_missing_slugs(text: str) -> tuple[list[str], str]:
    """Extract and strip a [MISSING: slug1, slug2] sentinel appended by the LLM.

    When the synthesis prompt (gap=True branch) asks the LLM to identify absent
    topics, it appends this marker on its own line.  Guard C may still suppress
    _gap for a well-cited answer; this sentinel re-enables chip generation for
    the explicitly-identified missing pages regardless.

    Handles two LLM failure modes:
    - Missing closing ']' (']' is optional in the pattern).
    - Sentinel placed mid-response (before a Sources section) rather than at
      the very end; content after the sentinel is preserved in cleaned_text.

    Returns (slugs, cleaned_text).  Returns ([], text) when no sentinel is found.
    """
    m = _MISSING_RE.search(text)
    if not m:
        return [], text
    slugs = [s.strip() for s in m.group(1).split(",") if s.strip()]
    before = text[: m.start()].rstrip()
    after = text[m.end() :].lstrip("\n")
    cleaned = (before + "\n" + after).strip() if after else before
    return slugs, cleaned


# ── pre_prompt helpers (stale pages / re-ingest completion detection) ─────────

_STALE_SLUG_RE = re.compile(
    # Handles common LLM list formats — requires "stale" in the qualifier so
    # a "changed pages this week" list doesn't trigger the pre-prompt:
    #   - slug (stale since...)      ← paren contains "stale"
    #   1. slug (stale since...)     ← numbered bullet
    #   - `slug` (stale...)          ← backtick-wrapped
    #   - **slug** (stale...)        ← bold
    #   - slug: stale since...       ← colon, "stale" follows on same line
    #   - slug — stale               ← em-dash, "stale" follows
    r'(?:^|\n)\s*(?:\d+[.)]\s*|[-*|]?\s*)`?(?:\*{1,2})?([a-z0-9][a-z0-9\-_]{2,})(?:\*{1,2})?`?'
    r'\s*(?:'
    r'\([^)\n]{0,120}stale[^)\n]{0,120}\)'  # (... stale ...)
    r'|:\s*stale\b'                          # : stale since ...
    r'|\s+[—–]\s*stale\b'                   # — stale / – stale
    r')',
    re.MULTILINE | re.IGNORECASE,
)
# Fallback for slug lists under a header line that mentions "stale pages" anywhere,
# e.g. "Stale pages:", "You have 2 stale pages:", "## Currently stale pages —"
# Items may lack a "stale" qualifier; the header provides the context.
_STALE_SECTION_RE = re.compile(
    r'(?:^|\n)[^\n]*\bstale\s+pages?\b[^\n]*[:\-—]\s*\n'
    r'((?:[ \t]*(?:\d+[.)]\s*|[-*]\s*)[^\n]+\n?)*)',
    re.IGNORECASE | re.MULTILINE,
)
_SIMPLE_LIST_SLUG_RE = re.compile(
    r'(?:^|\n)\s*(?:\d+[.)]\s*|[-*]\s*)`?(?:\*{1,2})?([a-z0-9][a-z0-9\-_]{2,})(?:\*{1,2})?`?',
    re.MULTILINE,
)
_STALE_HEADER_RE = re.compile(r'\bstale\b', re.IGNORECASE)
_NO_STALE_RE = re.compile(
    r'\bno\s+stale\b'
    r'|0\s+stale'
    r'|\bzero\s+stale\b'
    r'|\|\s*stale\s*\|\s*0\s*\|'                        # wiki-status table: | stale | 0 |
    r'|\bstale\b[^(\n]*\(0\)'                            # lint header: Stale pages (0)
    r'|\bno\s+pages?\s+(?:are\s+)?(?:currently\s+)?stale\b'   # "no pages are stale"
    r'|\bthere\s+(?:are|is)\s+no\s+stale\b',            # "there are no stale pages"
    re.IGNORECASE,
)
_REINGEST_COMPLETE_RE = re.compile(
    r're[-\s]?ingested\s+successfully', re.IGNORECASE
)
_BROKEN_LINKS_RE = re.compile(
    r'\bbroken\s+wikilinks?\b|\bdead\s+(?:wiki\s*)?links?\b|\bdangling\s+(?:wiki\s*)?links?\b',
    re.IGNORECASE,
)
_NO_BROKEN_LINKS_RE = re.compile(
    r'\bno\s+broken\b|0\s+broken|zero\s+broken|link\s+integrity\s+is\s+clean',
    re.IGNORECASE,
)
_CONTRADICTED_COUNT_RE = re.compile(
    r'\b([1-9]\d*)\s+contradicted\b',
    re.IGNORECASE,
)
# Additional patterns matching the two non-LLM output formats:
#   Lint report:   "**Contradicted pages (4)** — resolve..."
#   Wiki-status:   "| contradicted | 4 | conflicting..."
_CONTRADICTED_PARENS_RE = re.compile(
    r'\bcontradicted\b[^(\n]*\(([1-9]\d*)\)',
    re.IGNORECASE,
)
_CONTRADICTED_TABLE_RE = re.compile(
    r'\|\s*contradicted\s*\|\s*([1-9]\d*)\s*\|',
    re.IGNORECASE,
)
_NO_CONTRADICTED_RE = re.compile(
    r'\b0\s+contradicted\b|no\s+contradicted|zero\s+contradicted'
    # wiki-status table with 0:  "| contradicted | 0 |"
    r'|\|\s*contradicted\s*\|\s*0\s*\|'
    # lint-report header with 0: "Contradicted pages (0)"
    r'|\bcontradicted\b[^(\n]*\(0\)',
    re.IGNORECASE,
)
# Orphan page patterns — four output formats:
#   LLM text:         "2 orphan pages found"  /  "2 orphaned pages"
#   Lint summary:     "- Orphan pages: 2"  (CLI lint-report summary line)
#   Lint section hdr: "Orphan pages (2) — no inbound links:"  (LLM-generated)
#   Wiki-status:      "| orphan | 2 | no inbound links |"
_ORPHAN_COUNT_RE = re.compile(
    r'\b([1-9]\d*)\s+orphan(?:ed)?\s+pages?\b',
    re.IGNORECASE,
)
# Matches the lint-report CLI summary line "- Orphan pages: N"
# (number comes AFTER "Orphan pages:" — distinct from _ORPHAN_COUNT_RE)
_ORPHAN_SUMMARY_RE = re.compile(
    r'\borphan\s+pages?\s*:\s*([1-9]\d*)\b',
    re.IGNORECASE,
)
_ORPHAN_PARENS_RE = re.compile(
    r'\borphan\b[^(\n]*\(([1-9]\d*)\)',
    re.IGNORECASE,
)
_ORPHAN_TABLE_RE = re.compile(
    r'\|\s*orphan\s*\|\s*([1-9]\d*)\s*\|',
    re.IGNORECASE,
)
_NO_ORPHAN_RE = re.compile(
    r'\b0\s+orphan\b|no\s+orphan|zero\s+orphan'
    # lint-report summary with 0:  "- Orphan pages: 0"
    r'|\borphan\s+pages?\s*:\s*0\b'
    # wiki-status table with 0:   "| orphan | 0 |"
    r'|\|\s*orphan\s*\|\s*0\s*\|'
    # lint-report section hdr 0:  "Orphan pages (0)"
    r'|\borphan\b[^(\n]*\(0\)',
    re.IGNORECASE,
)
# Broken citation patterns — three output formats:
#   LLM text / CLI summary: "2 broken citations" / "2 citation issue(s)"
#   CLI section header:     "Citation Issues (2 across 1 pages):"
#   LLM / colon form:       "citation issues: 2" / "broken citations: 2"
_BROKEN_CITATIONS_COUNT_RE = re.compile(
    r'\b([1-9]\d*)\s+(?:broken\s+)?citation\s*(?:issue|ref|problem)s?\b'
    r'|\b([1-9]\d*)\s+broken\s+citations?\b',
    re.IGNORECASE,
)
_BROKEN_CITATIONS_HEADER_RE = re.compile(
    r'\bcitation\s*(?:issue|ref|problem)s?\s*\(\s*([1-9]\d*)',
    re.IGNORECASE,
)
_BROKEN_CITATIONS_AFTER_RE = re.compile(
    # "citation issues: 2"  /  "citation refs: 2"
    r'\b(?:broken\s+)?citation\s*(?:issue|ref|problem)s?\s*:\s*([1-9]\d*)'
    # "broken citations: 2"  (lint-report summary line — the most reliable total)
    r'|\bbroken\s+citations?\s*:\s*([1-9]\d*)',
    re.IGNORECASE,
)
_NO_BROKEN_CITATIONS_RE = re.compile(
    r'\b0\s+citation\s*(?:issue|ref|problem)s?\b'
    r'|no\s+citation\s*(?:issue|ref|problem)s?\b'
    r'|zero\s+broken\s+citations?\b'
    r'|\bcitation\s*(?:issue|ref|problem)s?\s*\(\s*0\s*\)'
    r'|\bcitation\s*(?:issue|ref|problem)s?\s*:\s*0\b',
    re.IGNORECASE,
)


def _build_pre_prompt(answer: str) -> str | None:
    """Return a pre_prompt string if the response has an unambiguous next step.

    Priority order (highest first):
      1. Re-ingest just completed → prompt to run lint
      2. Contradicted pages present → prompt to run the resolver
         (contradicted is more critical than stale: it serves actively
         conflicting information in query answers; stale is merely outdated)
      3. Stale pages present (with named slugs) → prompt to re-ingest
      4. Orphan pages present → prompt to run the orphan resolver
         Four formats: LLM text, lint-report summary ("- Orphan pages: N"),
         lint-report section header ("Orphan pages (N)…"), wiki-status table
      5. Broken wikilinks → prompt to scan
      6. Broken citations → prompt to run the citation resolver
         Three formats: LLM text / CLI summary ("N citation issue(s)"),
         CLI section header ("Citation Issues (N across M pages)"),
         colon form ("citation issues: N")

    Returns None if no clear next action is present.
    """
    if _REINGEST_COMPLETE_RE.search(answer):
        return "Run lint to promote re-ingested pages to active"
    # Contradicted page hint — fires after a lint job / status report that
    # found contradicted pages.  Three output formats are matched:
    #   1. LLM text:       "2 contradicted pages found"
    #   2. Lint report:    "**Contradicted pages (4)** — ..."
    #   3. Wiki-status:    "| contradicted | 4 | ..."
    # Checked before stale: contradicted pages serve actively conflicting
    # information and take precedence when both conditions are present.
    if not _NO_CONTRADICTED_RE.search(answer):
        for pat in (_CONTRADICTED_COUNT_RE, _CONTRADICTED_PARENS_RE, _CONTRADICTED_TABLE_RE):
            m = pat.search(answer)
            if m:
                n = int(m.group(1))
                page_word = "page" if n == 1 else "pages"
                return (
                    f"{n} {page_word} marked contradicted — "
                    "run the contradiction resolver to fix them interactively?"
                )
    # Only trigger on positive stale context ("stale pages" but not "no stale pages").
    if _STALE_HEADER_RE.search(answer) and not _NO_STALE_RE.search(answer):
        # Primary: slugs whose qualifier explicitly says "stale" on the same line.
        slugs = _STALE_SLUG_RE.findall(answer)
        if not slugs:
            # Fallback: simple list items under a "Stale pages:" section header.
            for m in _STALE_SECTION_RE.finditer(answer):
                slugs.extend(_SIMPLE_LIST_SLUG_RE.findall(m.group(1)))
        if slugs:
            slug_list = ", ".join(slugs[:10])
            return (
                f"Re-ingest {len(slugs)} stale page{'s' if len(slugs) != 1 else ''}: "
                f"{slug_list}"
            )
        # No slugs parsed — the word "stale" may appear in a negation context
        # ("no pages are in the stale state") that _NO_STALE_RE didn't catch.
        # Don't emit a generic suggestion; require concrete slugs to be safe.
    # Orphan page hint — fires after a lint report / direct query that surfaces
    # pages with no inbound [[wikilinks]].  Four output formats are matched:
    #   1. LLM text:        "2 orphan pages found"  /  "2 orphaned pages"
    #   2. Lint summary:    "- Orphan pages: 2"  (CLI lint-report summary line)
    #   3. Lint section:    "Orphan pages (2) — no inbound links:"  (LLM-generated)
    #   4. Wiki-status:     "| orphan | 2 | no inbound links |"
    # Priority is below contradicted and stale: orphan pages are inaccessible
    # via navigation but do not serve actively conflicting information.
    if not _NO_ORPHAN_RE.search(answer):
        for pat in (_ORPHAN_COUNT_RE, _ORPHAN_SUMMARY_RE, _ORPHAN_PARENS_RE, _ORPHAN_TABLE_RE):
            m = pat.search(answer)
            if m:
                n = int(m.group(1))
                page_word = "page" if n == 1 else "pages"
                return (
                    f"Fix {n} orphan {page_word} — run the orphan resolver?"
                )
    # Trigger when lint/status reports broken wikilinks.
    if _BROKEN_LINKS_RE.search(answer) and not _NO_BROKEN_LINKS_RE.search(answer):
        return "Scan for broken wikilinks"
    # Trigger when lint/status reports broken source citations.
    # Three formats matched: "2 citation issue(s)", "Citation Issues (2 across…)",
    # "citation issues: 2".  Priority below broken wikilinks — citations are
    # invisible in navigation but do not block page rendering.
    if not _NO_BROKEN_CITATIONS_RE.search(answer):
        for pat in (
            # Try summary/total formats first so a "Broken citations: 2" line
            # wins over per-page "(1 broken citation(s))" detail lines.
            _BROKEN_CITATIONS_AFTER_RE,
            _BROKEN_CITATIONS_HEADER_RE,
            _BROKEN_CITATIONS_COUNT_RE,
        ):
            m = pat.search(answer)
            if m:
                # _BROKEN_CITATIONS_COUNT_RE has two alternation groups;
                # take the first non-None capture.
                raw = next(g for g in m.groups() if g is not None)
                n = int(raw)
                word = "citation" if n == 1 else "citations"
                return f"Fix {n} broken {word} — run the citation resolver?"
    return None


class QueryAgent(BaseAgent):
    def __init__(self, provider: LLMProvider, store: WikiStorage,
                 search: HybridSearch,
                 query_config=None,
                 model: str = "",
                 gap_score_threshold: float = 2.0,
                 routing_path: Path | None = None,
                 orchestrator: object | None = None,
                 max_tokens: int = 8192) -> None:
        from synthadoc.config import QueryConfig
        from synthadoc.core.context_budget import compute_char_budgets
        super().__init__(provider)
        self._store = store
        self._search = search
        self._gap_score_threshold = gap_score_threshold
        self._orchestrator = orchestrator
        self._max_tokens = max_tokens
        self._model = model
        self._query_config = query_config or QueryConfig()
        self._char_budgets = compute_char_budgets(model, self._query_config)
        self._routing = None
        if routing_path:
            from synthadoc.core.routing import RoutingIndex
            self._routing = RoutingIndex.parse(routing_path)

    async def _routing_branch_pick(self, question: str) -> list[str]:
        """Ask LLM to select top 1-2 branch names from ROUTING.md relevant to question."""
        if not self._routing or not self._routing.branches:
            return []
        from synthadoc.agents._routing import pick_routing_branches
        return await pick_routing_branches(
            self._provider, self._routing.branches,
            f"Question: {question}", multi=True,
        )

    @staticmethod
    def _get_relevant_system_pages(question: str) -> str:
        """Return formatted system knowledge pages whose keywords match the question.

        CLI command prefix ("synthadoc <subcommand>") is treated as an implicit
        system-knowledge match — all bundled pages are included so the LLM has
        full context for the command being asked about.
        """
        q_lower = question.lower()
        matched: list[str] = []
        for page in _SYSTEM_KNOWLEDGE:
            # Use ASCII-only boundaries so English keywords adjacent to CJK characters
            # (e.g. "调度器scheduler") still match — Unicode \b treats CJK as word chars.
            if any(re.search(r'(?<![a-zA-Z0-9])' + re.escape(kw) + r'(?![a-zA-Z0-9])',
                             q_lower) for kw in page.keywords):
                matched.append(f"### {page.title}\n{page.content}")
        # If no keyword matched but question looks like a CLI invocation, include
        # all system pages so the LLM can answer from bundled documentation.
        if not matched and any(cmd in q_lower for cmd in _SYNTHADOC_CLI_SUBCOMMANDS):
            matched = [f"### {p.title}\n{p.content}" for p in _SYSTEM_KNOWLEDGE]
        return "\n\n".join(matched)

    def _warned_pages(self) -> list[tuple[str, int]]:
        """Return (slug, warning_count) sorted by count desc for pages that have lint_warnings."""
        warned = [
            (slug, len(page.lint_warnings))
            for slug in self._store.list_pages()
            if (page := self._store.read_page(slug)) and page.lint_warnings
        ]
        warned.sort(key=lambda x: x[1], reverse=True)
        return warned

    async def _fetch_live_wiki_data(self, question: str) -> str:
        """Return a formatted snapshot of live wiki lifecycle data if the question asks for it.

        Queries AuditDB directly — no HTTP round-trip. Returns empty string if the DB
        does not exist yet (fresh install before first ingest).
        """
        q_lower = question.lower()
        if not any(kw in q_lower for kw in _LIVE_DATA_TRIGGERS):
            return ""

        audit_path = self._store._root.parent / ".synthadoc" / "audit.db"
        if not audit_path.exists():
            return ""

        try:
            audit = AuditDB(audit_path)
            await audit.init()
            _live = lambda slug: slug not in LINT_SKIP_SLUGS and self._store.page_exists(slug)
            all_page_states = await audit.get_live_page_states(_live)
            counts: dict[str, int] = await audit.get_live_lifecycle_summary(_live)

            lines: list[str] = []

            if counts:
                lines.append("### Current page counts")
                for state in ("active", "draft", "stale", "contradicted", "archived"):
                    n = counts.get(state, 0)
                    hint = f"  {_HINTS[state]}" if state in _HINTS and n > 0 else ""
                    lines.append(f"  {state:<14} {n}{hint}")

                # For specific state questions, list the actual page slugs
                detected_state: str | None = None
                for state in ("stale", "archived", "draft", "contradicted", "active"):
                    if state in q_lower or (state == "contradicted" and "contradiction" in q_lower):
                        detected_state = state
                        break

                if detected_state:
                    matching = [p for p in all_page_states if p["state"] == detected_state]
                    if matching:
                        lines.append(f"\n### Pages currently marked '{detected_state}'")
                        for p in matching:
                            ts = p.get("updated_at", "")[:10]
                            lines.append(f"  - {p['slug']}  (since {ts})" if ts else f"  - {p['slug']}")
                    else:
                        lines.append(f"\n### Pages currently marked '{detected_state}'\n  (none)")

            # Adversarial warnings — read directly from page frontmatter
            if any(kw in q_lower for kw in _ADVERSARIAL_TRIGGERS):
                warned = self._warned_pages()
                if warned:
                    lines.append("\n### Pages with adversarial warnings")
                    for slug, n in warned:
                        lines.append(f"  - [[{slug}]]  ({n} warning{'s' if n != 1 else ''})")
                else:
                    lines.append("\n### Pages with adversarial warnings\n  (none — run `synthadoc lint run` to check)")

            # Truncated sources — read directly from page frontmatter
            if any(kw in q_lower for kw in _TRUNCATION_TRIGGERS):
                truncated: list[tuple[str, str, int]] = []
                for slug in self._store.list_pages():
                    page = self._store.read_page(slug)
                    if not page:
                        continue
                    for src in (page.sources or []):
                        if getattr(src, "truncated", False):
                            truncated.append((slug, src.file, src.size))
                if truncated:
                    lines.append("\n### Sources truncated at ingest time")
                    for slug, file, size in truncated:
                        lines.append(f"  - [[{slug}]]  source: {file}  ({size:,} chars)")
                else:
                    lines.append("\n### Sources truncated at ingest time\n  (none)")

            # Recent ingest history when question asks about changes/updates
            if any(kw in q_lower for kw in _RECENT_CHANGE_TRIGGERS):
                _days = _parse_lookback_days(question)
                _window_label = (
                    f"{_days // 365} year{'s' if _days // 365 > 1 else ''}" if _days >= 365
                    else f"{_days // 30} month{'s' if _days // 30 > 1 else ''}" if _days >= 30
                    else f"{_days} day{'s' if _days > 1 else ''}"
                )
                recent = await audit.list_ingests_since(days=_days)
                if recent:
                    lines.append(f"\n### Pages ingested or updated in the last {_window_label}")
                    seen: set[str] = set()
                    for r in recent:
                        slug = r.get("wiki_page") or ""
                        src = r.get("source_path") or ""
                        date = (r.get("ingested_at") or "")[:10]
                        if slug and slug not in seen:
                            seen.add(slug)
                            lines.append(f"  - [[{slug}]]  (from {src}, {date})" if src else f"  - [[{slug}]]  ({date})")
                else:
                    lines.append(f"\n### Pages ingested or updated in the last {_window_label}\n  (none)")

            # Full lint report — aggregate stats + live contradicted/orphan/warnings
            if any(kw in q_lower for kw in _LINT_TRIGGERS):
                lint_summary = await audit.get_last_lint_summary()
                if lint_summary:
                    ts = (lint_summary.get("timestamp") or "")[:16].replace("T", " ")
                    dangling = lint_summary.get("dangling_removed", 0)
                    orphans_n = lint_summary.get("orphans", 0)
                    c_res = lint_summary.get("contradictions_resolved", 0)
                    c_flag = lint_summary.get("contradictions_flagged", 0)
                    lines.append(f"\n### Last lint run ({ts} UTC)")
                    if dangling:
                        lines.append(f"  Dangling links removed : {dangling}")
                    lines.append(f"  Orphans found          : {orphans_n}")
                    lines.append(f"  Contradictions         : {c_res} resolved, {c_flag} flagged")
                else:
                    lines.append(
                        "\n### Lint report\n"
                        "  (no lint run recorded yet — run `synthadoc lint run`)"
                    )

                # Contradicted pages — current live state
                contradicted_pages = [p for p in all_page_states if p["state"] == "contradicted"]
                if contradicted_pages:
                    lines.append("\n### Currently contradicted pages")
                    for p in contradicted_pages:
                        since = p.get("updated_at", "")[:10]
                        lines.append(f"  - {p['slug']}  (since {since})" if since else f"  - {p['slug']}")
                else:
                    lines.append("\n### Currently contradicted pages\n  (none)")

                # Adversarial warnings — current live state from page frontmatter
                warned = self._warned_pages()
                if warned:
                    lines.append("\n### Pages with adversarial warnings")
                    for slug, n in warned:
                        lines.append(f"  - [[{slug}]]  ({n} warning{'s' if n != 1 else ''})")
                else:
                    lines.append("\n### Pages with adversarial warnings\n  (none)")

                # Orphan pages — current live state from page frontmatter
                orphan_slugs = sorted(
                    s for s in self._store.list_pages()
                    if ((_p := self._store.read_page(s)) and _p.orphan)
                )
                if orphan_slugs:
                    lines.append("\n### Orphan pages (no inbound links)")
                    for s in orphan_slugs:
                        lines.append(f"  - {s}")
                else:
                    lines.append("\n### Orphan pages\n  (none)")

            # Job status — detect a specific 8-char hex job ID or list recent jobs
            if any(kw in q_lower for kw in _JOB_TRIGGERS) and self._orchestrator is not None:
                _queue = self._orchestrator._queue
                _job_id_match = re.search(r'\b([0-9a-f]{8})\b', q_lower)
                if _job_id_match:
                    _job_id = _job_id_match.group(1)
                    _job = await _queue.get_job(_job_id)
                    if _job:
                        lines.append(f"\n### Job {_job_id}")
                        lines.append(f"  operation : {_job.operation}")
                        lines.append(f"  status    : {_job.status.value}")
                        lines.append(f"  retries   : {_job.retries}")
                        if _job.error:
                            lines.append(f"  error     : {_job.error}")
                        if _job.created_at:
                            lines.append(f"  created   : {(_job.created_at or '')[:19]}")
                    else:
                        lines.append(f"\n### Job {_job_id}\n  (not found)")
                else:
                    _recent_jobs = await _queue.list_jobs(order="desc")
                    if _recent_jobs:
                        lines.append("\n### Recent jobs")
                        for _j in _recent_jobs[:10]:
                            _ts = (_j.created_at or "")[:10]
                            _err = f"  — {_j.error}" if _j.error else ""
                            lines.append(f"  - [{_j.id}] {_j.operation}  {_j.status.value}  {_ts}{_err}")
                    else:
                        lines.append("\n### Jobs\n  (no jobs found)")

            return "\n".join(lines) if lines else ""
        except Exception as exc:
            logger.debug("live wiki data fetch failed: %s", exc)
            return ""

    def _build_synthesis_system(self, question: str) -> str:
        """Return the language-enforcement system prompt for synthesis."""
        return build_synthesis_system(question)

    def _build_synthesis_prompt(
        self,
        question: str,
        context: str,
        *,
        gap: bool,
        system_ctx: str,
        is_live_data: bool,
        history: list[dict] | None = None,
    ) -> str:
        """Build the LLM synthesis prompt. When history is provided it is prepended."""
        prefix = history_block(history, question) if history else ""
        if gap:
            return prefix + (
                f"The wiki does not yet have a dedicated page on this topic. "
                f"Answer the question using the wiki pages below and your general knowledge. "
                f"Note in one sentence that the wiki lacks a dedicated page and suggest the user enriches it.\n\n"
                f"Question: {question}\n\n"
                f"Wiki pages available:\n{context}"
            )
        if system_ctx:
            return prefix + (
                f"Answer the question using the Synthadoc Help documentation and Live Wiki Data below. "
                f"If Live Wiki Data is present, use it to give concrete, specific answers "
                f"(e.g. list the actual page names, show real counts). "
                f"Present every CLI command in a fenced code block, exactly as it appears in the documentation. "
                f"Angle-bracket placeholders like <schedule-id> or <slug> are literal CLI arguments — "
                f"copy them verbatim, do not omit or paraphrase them. "
                f"Keep the answer concise; do not add a verification or troubleshooting section. "
                f"Do not reference or cite wiki pages.\n\n"
                f"Question: {question}\n\nDocumentation:\n{context}"
            )
        if is_live_data:
            return prefix + (
                f"Answer using the Live Wiki Data below. "
                f"The data is fetched directly from Synthadoc's audit log and page state database — "
                f"give specific, concrete answers using the actual page names, dates, and counts shown. "
                f"Do not reference or cite wiki page content.\n\n"
                f"Question: {question}\n\nData:\n{context}"
            )
        return prefix + (
            f"Answer using ONLY these wiki pages. Cite with [[PageTitle]].\n"
            f"Respond in the same language as the Question. "
            f"Do not use the language of the Pages or the conversation history.\n"
            f"Extract and include all specific facts from the pages — dates, years, numbers, and names — "
            f"even when they appear briefly or in passing. Do not claim a fact is absent unless it is "
            f"genuinely missing from every page below.\n"
            f"When wiki pages contain tables or worked financial examples, reproduce the key rows and "
            f"figures exactly — do not summarize or omit them.\n"
            f"Do not cite the Wiki Scope section — it is background context only, not a citable source.\n\n"
            f"Question: {question}\n\nPages:\n{context}"
        )

    def _load_purpose_context(self) -> str:
        """Return purpose.md as a pinned preamble for synthesis, or '' if absent."""
        page = self._store.read_page("purpose")
        if not page:
            return ""
        budget = self._char_budgets["system"]
        if len(page.content) > budget:
            logger.warning(
                "purpose.md truncated to %d chars (context_system_pct budget); "
                "full content is %d chars — increase context_system_pct or shorten purpose.md",
                budget, len(page.content),
            )
        return f"### Wiki Scope (purpose.md)\n{page.content[:budget]}"

    def _build_wiki_context(self, candidates) -> str:
        """Greedy-fill wiki context up to the wiki char budget.

        Pages are appended in candidate score order until the budget is exhausted.
        A partial page is included when enough remaining budget exists (>100 chars).
        The 'purpose' page is always skipped — it is pinned separately.
        """
        budget = self._char_budgets["wiki"]
        parts = []
        used = 0
        for r in candidates:
            page = self._store.read_page(r.slug)
            if not page or r.slug in LINT_SKIP_SLUGS:
                continue
            chunk = f"### {page.title}\n{page.content}"
            if used + len(chunk) > budget:
                remaining = budget - used
                if remaining > 100:
                    parts.append(chunk[:remaining])
                break
            parts.append(chunk)
            used += len(chunk)
        return "\n\n".join(parts)

    def _trim_history(self, history: list[dict]) -> list[dict]:
        """Return the most-recent turns that fit within the history char budget."""
        return trim_history(history, self._char_budgets["history"])

    def _expand_aliases(self, question: str) -> str:
        """Replace alias matches in question with canonical slug names."""
        alias_map: dict[str, str] = {}
        for slug in self._store.list_pages():
            page = self._store.read_page(slug)
            if page and page.aliases:
                for alias in page.aliases:
                    alias_map[alias.lower()] = slug
        if not alias_map:
            return question
        q = question
        for alias, slug in sorted(alias_map.items(), key=lambda x: -len(x[0])):
            q = re.sub(re.escape(alias), slug, q, flags=re.IGNORECASE)
        return q

    # Decompose is an optional optimisation — cap it so slow local models fail fast
    # and leave the full budget for synthesis.
    _DECOMPOSE_TIMEOUT_SECS = 30

    async def decompose(self, question: str) -> list[str]:
        """Break a question into focused sub-questions for independent retrieval.

        Returns [question] on any failure so callers always get a usable list.
        """
        return await decompose_question(self._provider, question, self._DECOMPOSE_TIMEOUT_SECS)

    async def _translate_for_retrieval(self, question: str) -> str:
        """Translate a CJK query to English so BM25 can match English wiki content.

        Only called when *question* contains CJK characters.  The original question
        is preserved by the caller for answer synthesis, so the user still receives
        a response in their language.
        """
        try:
            resp = await asyncio.wait_for(
                self._provider.complete(
                    messages=[Message(
                        role="user",
                        content=(
                            "Translate the following question to English for a knowledge-base search. "
                            "Return only the English translation — no explanation, no quotes.\n\n"
                            f"Question: {question}"
                        ),
                    )],
                    max_tokens=200,
                ),
                timeout=20.0,
            )
            translated = (resp.text or "").strip()
            if translated:
                logger.info("cjk-translate: %r → %r", question, translated)
                return translated
        except Exception:
            logger.warning("cjk-translate failed — using original question for retrieval", exc_info=True)
        return question

    async def _run_search(
        self, question: str
    ) -> tuple[list[str], list[SearchResult], str]:
        """Decompose question, apply routing scope, run parallel BM25 search.

        Returns (sub_questions, candidates, routing_warning).  When *question* contains
        CJK characters it is translated to English before retrieval.  If routing-scoped
        results are too weak (max_score below threshold), falls back to full-corpus BM25
        and returns a non-empty routing_warning string explaining the fallback.
        """
        retrieval_question = question
        if has_cjk(question):
            retrieval_question = await self._translate_for_retrieval(question)

        sub_questions = await self.decompose(retrieval_question)

        scoped_slugs: list[str] | None = None
        if self._routing:
            branches = await self._routing_branch_pick(retrieval_question)
            if branches:
                scoped_slugs = self._routing.slugs_for_branches(branches)

        async def _search_one(sub_q: str, slugs: list[str] | None) -> list[SearchResult]:
            return await self._search.hybrid_search(
                sub_q.lower().split(), top_n=_CANDIDATE_POOL_SIZE, scoped_slugs=slugs
            )

        results_per_sub = await asyncio.gather(
            *[_search_one(q, scoped_slugs) for q in sub_questions]
        )
        best: dict[str, SearchResult] = {}
        for results in results_per_sub:
            for r in results:
                if r.slug not in best or r.score > best[r.slug].score:
                    best[r.slug] = r
        candidates = sorted(best.values(), key=lambda r: r.score, reverse=True)[:_CANDIDATE_POOL_SIZE]

        routing_warning = ""
        if scoped_slugs is not None:
            max_score = max((r.score for r in candidates), default=0.0)
            # Use 1.5× the gap threshold so borderline scoped results (score between
            # gap_threshold and 1.5×) also fall back.  This avoids Signal 6 false
            # positives where routing picks domain-A pages for a cross-domain query
            # and the domain-B acronym has doc_freq=0 in those pages.
            scoped_weak = max_score < self._gap_score_threshold * 1.5
            if scoped_weak:
                # Routing-scoped results are below threshold — fall back to full corpus.
                full_per_sub = await asyncio.gather(
                    *[_search_one(q, None) for q in sub_questions]
                )
                full_best: dict[str, SearchResult] = {}
                for results in full_per_sub:
                    for r in results:
                        if r.slug not in full_best or r.score > full_best[r.slug].score:
                            full_best[r.slug] = r
                full_candidates = sorted(
                    full_best.values(), key=lambda r: r.score, reverse=True
                )[:_CANDIDATE_POOL_SIZE]
                if full_candidates:
                    candidates = full_candidates
                    routing_warning = (
                        "ROUTING.md may be incomplete or stale — search scope was expanded "
                        "to the full wiki. To fix: delete ROUTING.md and run "
                        "`synthadoc routing init`."
                    )
                    logger.warning(
                        "routing scope too weak (max_score=%.2f, scoped_slugs=%d) "
                        "— fell back to full-corpus (%d candidates)",
                        max_score, len(scoped_slugs), len(candidates),
                    )

        return sub_questions, candidates, routing_warning

    async def run(  # type: ignore[override]
        self, question: str, history: list[dict] | None = None
    ) -> QueryResult:
        """Public entry point.

        Errors are not suppressed: callers access result attributes directly,
        so a ``None`` fallback would replace one exception with an
        ``AttributeError``.  Let errors propagate so the original exception
        type and traceback are preserved.
        """
        return await self._run(question, history)

    def _safe_default(self) -> None:  # type: ignore[override]
        """Never reached — ``run()`` does not suppress errors."""
        return None

    async def _run(self, question: str, history: list[dict] | None = None) -> QueryResult:
        question = self._expand_aliases(question)

        # Action pre-flight: if orchestrator is available and question is an action, dispatch it
        if self._orchestrator is not None:
            _action_agent = ActionAgent(self._provider, self._orchestrator,
                                        self._store._root.parent)
            if _action_agent.detect(question, history=None):
                _result = await _action_agent.run(question)
                if _result is not None:
                    return QueryResult(
                        question=question,
                        answer=_result.message,
                        citations=[],
                        knowledge_gap=not _result.success,
                        cacheable=False,
                    )

        sub_questions, candidates, routing_warning = await self._run_search(question)

        _max_score = max((r.score for r in candidates), default=0.0)
        # Use sub-questions for gap detection so decomposition strips request framing.
        # For CJK queries we keep the original question so _detect_gap's CJK guard
        # continues to suppress key-term signals on non-English content.
        _gap_q = question if has_cjk(question) else (
            " ".join(sub_questions) if sub_questions else question
        )
        _used_tf_fallback = any(r.tf_fallback for r in candidates)
        _gap, _discriminating_term, _pages_with_overlap, _min_specific_qualifying = \
            self._detect_gap(_gap_q, candidates, _max_score, used_tf_fallback=_used_tf_fallback)
        _system_ctx = self._get_relevant_system_pages(question)
        _live_data = await self._fetch_live_wiki_data(question)
        if _system_ctx or _live_data:
            _gap = False
        if _gap and _is_introspective(question):
            _gap = False
        _purpose_ctx = self._load_purpose_context()
        if _gap:
            _suggested = await SearchDecomposeAgent(self._provider).run(
                question, domain_context=_purpose_ctx
            ) or [question]
        else:
            _suggested = []

        citations = [r.slug for r in candidates]
        _pages_ctx = self._build_wiki_context(candidates) or "No relevant pages found."
        _ctx_parts = []
        if _purpose_ctx:
            _ctx_parts.append(_purpose_ctx)
        _is_live_data = False
        if _system_ctx:
            # System knowledge matched: answer from help pages only; wiki pages are irrelevant noise
            _ctx_parts.append(f"## Synthadoc Help\n{_system_ctx}")
            citations = []
            if _live_data:
                _ctx_parts.append(f"## Live Wiki Data\n{_live_data}")
                _is_live_data = True
        elif _live_data:
            # Pure live-data query (no system knowledge page matched, but audit/queue data available)
            citations = []
            _ctx_parts.append(f"## Live Wiki Data\n{_live_data}")
            _is_live_data = True
        else:
            _ctx_parts.append(_pages_ctx)
        context = "\n\n".join(_ctx_parts)

        _trimmed_history = self._trim_history(history or [])
        synthesis_prompt = self._build_synthesis_prompt(
            question, context,
            gap=_gap, system_ctx=_system_ctx, is_live_data=_is_live_data,
            history=_trimmed_history if _trimmed_history else None,
        )
        _synthesis_system = self._build_synthesis_system(question)

        resp2 = await self._provider.complete(
            messages=[Message(role="user", content=synthesis_prompt)],
            system=_synthesis_system,
            temperature=0.0,
            max_tokens=self._max_tokens,
        )

        # Post-synthesis gap override: the sentinel [GAP] in the answer means the LLM
        # could not find enough in the wiki pages despite pre-synthesis gap detection
        # saying no gap (Guard B false negative). Strip the marker before displaying.
        answer_text = resp2.text
        if not _gap and resp2.text.startswith("[GAP]"):
            _gap = True
            answer_text = resp2.text[len("[GAP]"):].lstrip("\n")
            _suggested = await SearchDecomposeAgent(self._provider).run(
                question, domain_context=_purpose_ctx
            ) or [question]

        _gap = _guard_c_suppress(_gap, answer_text, "query")

        # [MISSING: ...] sentinel — re-enable gap and chip generation even when
        # Guard C suppressed it for a well-cited answer.  Strip the marker from
        # the displayed text so clients never see it.
        # Strip any stray [MISSING: ...] text the LLM may have written; do not
        # use it to re-enable gap — Guard C's assessment is final.
        _missing_slugs, answer_text = _extract_missing_slugs(answer_text)
        if _missing_slugs:
            logger.debug("query: [MISSING] text stripped (Guard C decision preserved) — %s", _missing_slugs)

        logger.info("query answered — %d page(s) cited, %d tokens",
                    len(citations), resp2.total_tokens)
        return QueryResult(
            question=question,
            answer=answer_text,
            citations=[] if _gap else citations,
            tokens_used=resp2.total_tokens,
            input_tokens=resp2.input_tokens,
            output_tokens=resp2.output_tokens,
            knowledge_gap=_gap,
            suggested_searches=_suggested,
            sub_questions_count=len(sub_questions),
            cacheable=not _is_live_data,
            routing_warning=routing_warning,
        )

    def _detect_gap(
        self, question: str, candidates: list[SearchResult], max_score: float,
        used_tf_fallback: bool = False,
    ) -> tuple[bool, str, int, int]:
        """Full 7-signal knowledge gap detection.

        Returns (gap, discriminating_term, pages_with_overlap, min_specific_qualifying).
        Called by both run() and run_stream() so they share identical detection logic.
        """
        _any_term_missing = False
        _defining_term_absent = False
        _discriminating_term = ""
        _pages_with_overlap = len(candidates)
        _min_specific_qualifying = len(candidates)

        _contains_cjk = any(
            '぀' <= c <= 'ヿ'
            or '一' <= c <= '鿿'
            or '가' <= c <= '힯'
            for c in question
        )
        _key_terms: set[str] = set()
        # How many times each key term appears in the question / joined sub-questions.
        # Used by Signal 7 to detect prominent absent entities.
        _q_term_freq: dict[str, int] = {}
        # All-uppercase terms with bare length 2-5 (USB, TCP, AI, ENIAC…).
        # Tracked separately so signal 6 can fire when a specific acronym or
        # proper-name abbreviation is completely absent from all retrieved pages
        # even when general topic terms are well covered.
        _acronym_key_terms: set[str] = set()
        if not _contains_cjk:
            for _w in question.split():
                _bare = _w.lower().rstrip("s'?!.,").replace("-", " ")
                # Check both the bare form AND the original lowercased word: "does"
                # strips to "doe" which is not in STOPWORDS, but "does" is.
                if ((len(_w) >= 4 or (len(_w) >= 2 and _w.upper() == _w))
                        and _bare not in STOPWORDS
                        and _w.lower() not in STOPWORDS):
                    _key_terms.add(_bare)
                    _q_term_freq[_bare] = _q_term_freq.get(_bare, 0) + 1
                    _stripped = _w.rstrip("s'?!.,")
                    if _stripped and _stripped.upper() == _stripped and 2 <= len(_bare) <= 5:
                        _acronym_key_terms.add(_bare)

        if _key_terms and candidates:
            _term_doc_freq = {
                t: sum(
                    1 for r in candidates
                    if (p := self._store.read_page(r.slug))
                    and t in p.content.lower().replace("-", " ")
                )
                for t in _key_terms
            }
            _covered = {t: f for t, f in _term_doc_freq.items() if f > 0}
            _n_cands = len(candidates)
            _specific = {t: f for t, f in _covered.items() if f <= _n_cands * 0.8}
            if not _specific:
                _specific = _covered
            elif max(_specific.values(), default=0) <= 1:
                _specific = _covered

            if _specific:
                _discriminating_term = min(_specific, key=lambda t: _specific[t])
            elif _covered:
                _discriminating_term = min(_covered, key=lambda t: _covered[t])
            elif _term_doc_freq:
                _discriminating_term = min(_term_doc_freq, key=lambda t: _term_doc_freq[t])

            _term_qualifying_pages: dict[str, int] = {t: 0 for t in _specific}
            _pages_with_overlap = 0
            for _r in candidates:
                _p = self._store.read_page(_r.slug)
                if not _p:
                    continue
                _content = _p.content.lower().replace("-", " ")
                _page_on_topic = False
                for _t in _specific:
                    if _content.count(_t) >= _MIN_TERM_FREQ:
                        _term_qualifying_pages[_t] += 1
                        _page_on_topic = True
                if _page_on_topic:
                    _pages_with_overlap += 1

            _signal4_active = _pages_with_overlap < _n_cands // 2
            _any_term_missing = (
                _signal4_active
                and bool(_covered)
                and len(_term_doc_freq) >= 2
                and any(f == 0 for f in _term_doc_freq.values())
                and max(_covered.values()) / len(candidates) <= 0.8
            )
            _min_specific_qualifying = (
                min(_term_qualifying_pages.values()) if _term_qualifying_pages else 0
            )
            _signal5_doc_freq_cap = max(2, (_n_cands + 2) // 3)
            # Pages whose title contains the term are considered dedicated to it even
            # when the body doesn't repeat the term ≥ MIN_FREQ times.  This suppresses
            # the false positive where a "Methodology Guide" page doesn't repeat the
            # word "methodology" twice in its body — the title is sufficient coverage.
            _title_covered: set[str] = set()
            for _r in candidates:
                _tp = self._store.read_page(_r.slug)
                if _tp:
                    _t_norm = _tp.title.lower().replace("-", " ")
                    for _t in _specific:
                        if _t in _t_norm:
                            _title_covered.add(_t)
            _signal5_triggers = [
                t for t in _term_qualifying_pages
                if _term_qualifying_pages[t] == 0
                and _specific[t] <= _signal5_doc_freq_cap
                and t not in _title_covered
            ]
            if _signal5_triggers:
                logger.debug("signal5 candidates: %r (cap=%d, title_covered=%r)",
                             _signal5_triggers, _signal5_doc_freq_cap, sorted(_title_covered))
            # Signal 5 coverage gate: only fire when fewer than 75% of candidates are
            # on-topic.  When the wiki broadly covers the query (≥ 75% on-topic pages
            # and strong retrieval score), a term with qualifying_pages=0 is almost
            # always a query-framing word, not a content gap — Guard B (post-synthesis)
            # handles residual gaps in that regime.  The 75% threshold is higher than
            # Signal 4's 50% gate so Signal 5 can still fire at moderate coverage
            # (e.g., 4/8 on-topic pages) where the wiki has genuinely thin depth.
            _signal5_active = _pages_with_overlap < _n_cands * 3 // 4
            _defining_term_absent = _signal5_active and bool(_specific) and len(_term_doc_freq) >= 2 and bool(_signal5_triggers)
            # Signal 6: a specific acronym or proper-name abbreviation typed
            # ALL-CAPS in the query (USB, TCP, ENIAC, AI…) has zero occurrences
            # across all retrieved pages — the wiki simply does not cover this
            # entity regardless of how well the general topic is represented.
            _acronym_absent = bool(_acronym_key_terms) and any(
                _term_doc_freq.get(t, 0) == 0
                for t in _acronym_key_terms
            )
            # Signal 7: a key term appears in the query but has zero occurrences in
            # every retrieved page, AND overall coverage is genuinely thin (< 65 % of
            # candidates are on-topic).  The coverage gate distinguishes genuine gaps
            # from word-form misses: if the wiki covers the topic but uses a different
            # form (e.g. "Canadian" vs "Canada", "garden" vs "backyard"), most pages
            # are still on-topic (≥ 65 %) and the gate stays closed.  65 % is
            # deliberately lower than the 80 % used by Signal 4 — this catches the
            # iPhone-style case where ~45–60 % of pages have generic term overlap (from
            # "mobile", "computing" etc.) but the specific entity is absent.
            _prominent_term_absent = (
                _pages_with_overlap < _n_cands * 0.65
                and any(
                    _q_term_freq.get(t, 0) >= 1 and _term_doc_freq.get(t, 0) == 0
                    for t in _key_terms
                )
            )
        else:
            _acronym_absent = False
            _prominent_term_absent = False

        gap = self._gap_score_threshold > 0 and (
            (len(candidates) < 3 and not used_tf_fallback and max_score < self._gap_score_threshold)
            or (bool(_key_terms) and not used_tf_fallback and max_score < self._gap_score_threshold)  # skip when no content words or TF fallback
            or (_pages_with_overlap < 2 and max_score < self._gap_score_threshold)  # one strong page is enough
            or _any_term_missing
            or _defining_term_absent
            or _acronym_absent
            or _prominent_term_absent
        )
        logger.info(
            "query retrieval — pages=%d, max_score=%.2f, "
            "discriminating_term=%r, on_topic_pages=%d, min_qualifying=%d, gap=%s",
            len(candidates), max_score, _discriminating_term,
            _pages_with_overlap, _min_specific_qualifying, gap,
        )
        return gap, _discriminating_term, _pages_with_overlap, _min_specific_qualifying

    async def run_stream(
        self,
        question: str,
        session_id: str | None = None,
        history: list[dict] | None = None,
        session_mode: SessionMode = "POWER_USER",
    ):
        """Stream query response as an async generator of SSE event dicts.

        Event sequence: status(retrieving) → status(synthesizing) → token* → citations → [gap] → done
        """
        # Action pre-flight: dispatch action requests before entering the query pipeline
        if self._orchestrator is not None:
            _action_agent = ActionAgent(self._provider, self._orchestrator,
                                        self._store._root.parent)
            if _action_agent.detect(question, history=history or []):
                # Track whether the action agent produced a done event.  run_gen()
                # always emits a leading _init tool_progress; only a done event means
                # the action was actually handled.  If extraction fails (None / "none")
                # the generator returns after _init without done — fall through to the
                # QueryAgent pipeline so the user still gets an answer.
                _had_done = False
                async for _evt in _action_agent.run_gen(question, history=history or [], session_id=session_id, session_mode=session_mode):
                    yield _evt
                    if _evt.get("event") == "done":
                        _had_done = True
                if _had_done:
                    return

        yield {"event": "status", "data": {"phase": "retrieving"}}

        question = self._expand_aliases(question)

        # Rewrite question for retrieval when history is present
        retrieval_question = question
        if history:
            rewritten = await RewriteAgent(self._provider).run(question, history)
            retrieval_question = rewritten or question

        sub_questions, candidates, routing_warning = await self._run_search(retrieval_question)

        citations = [r.slug for r in candidates]
        _purpose_ctx = self._load_purpose_context()
        # Use retrieval_question (history-enriched) for keyword/trigger matching so
        # follow-up messages like "check it again" resolve to the correct live data
        # and system knowledge. The synthesis prompt still shows the original question.
        _system_ctx = self._get_relevant_system_pages(retrieval_question)
        _pages_ctx = self._build_wiki_context(candidates) or "No relevant pages found."
        _ctx_parts = []
        if _purpose_ctx:
            _ctx_parts.append(_purpose_ctx)
        _is_live_data = False
        _live_data = await self._fetch_live_wiki_data(
            _select_live_data_question(question, retrieval_question)
        )
        if _system_ctx:
            # System knowledge matched: answer from help pages only; wiki pages are irrelevant noise
            _ctx_parts.append(f"## Synthadoc Help\n{_system_ctx}")
            citations = []
            if _live_data:
                _ctx_parts.append(f"## Live Wiki Data\n{_live_data}")
                _is_live_data = True
        elif _live_data:
            # Pure live-data query (no system knowledge page matched, but audit/queue data available)
            citations = []
            _ctx_parts.append(f"## Live Wiki Data\n{_live_data}")
            _is_live_data = True
        else:
            _ctx_parts.append(_pages_ctx)
        context = "\n\n".join(_ctx_parts)

        _max_score = max((r.score for r in candidates), default=0.0)
        _gap_q = question if has_cjk(question) else (
            " ".join(sub_questions) if sub_questions else question
        )
        _used_tf_fallback = any(r.tf_fallback for r in candidates)
        _gap, _discriminating_term, _pages_with_overlap, _min_specific_qualifying = \
            self._detect_gap(_gap_q, candidates, _max_score, used_tf_fallback=_used_tf_fallback)

        if _system_ctx or _live_data:
            _gap = False
        if _gap and _is_introspective(retrieval_question):
            _gap = False

        _trimmed_history = self._trim_history(history or [])
        synthesis_prompt = self._build_synthesis_prompt(
            question, context,
            gap=_gap, system_ctx=_system_ctx, is_live_data=_is_live_data,
            history=_trimmed_history if _trimmed_history else None,
        )
        _synthesis_system = self._build_synthesis_system(question)

        yield {"event": "status", "data": {"phase": "synthesizing", "sources": len(citations)}}

        _synth_start = time.monotonic()
        _first_token = True
        logger.info(
            "run_stream: synthesis starting — context %d chars, %d page(s)",
            len(context), len(candidates),
        )
        full_answer = ""
        # Hold-back buffer: text accumulated since the last newline, held only when
        # the line starts with "[" — the sole prefix for "[MISSING: ...]" sentinels.
        # Non-"[" fragments are flushed immediately so normal streaming is unaffected.
        _last_line_buf = ""
        async for token in self._provider.complete_stream(
            messages=[Message(role="user", content=synthesis_prompt)],
            system=_synthesis_system,
            temperature=0.0,
            max_tokens=self._max_tokens,
        ):
            if _first_token:
                logger.info(
                    "run_stream: first token received after %.1fs",
                    time.monotonic() - _synth_start,
                )
                _first_token = False
            full_answer += token
            combined = _last_line_buf + token
            if "\n" in combined:
                parts = combined.split("\n")
                yield {"event": "token", "data": {"text": "\n".join(parts[:-1]) + "\n"}}
                _last_line_buf = parts[-1]
            elif not combined.startswith("["):
                # Cannot be a [MISSING: ...] sentinel — yield immediately.
                yield {"event": "token", "data": {"text": combined}}
                _last_line_buf = ""
            else:
                # Starts with "[" — could be the sentinel; hold until newline or end.
                _last_line_buf = combined

        if not _first_token:
            logger.info(
                "run_stream: synthesis complete — %.1fs, %d chars",
                time.monotonic() - _synth_start, len(full_answer),
            )

        if not full_answer:
            logger.warning("run_stream: LLM returned empty response for question %r", question)
            fallback = "(No response was generated. Please try again.)"
            yield {"event": "token", "data": {"text": fallback}}
            full_answer = fallback
            _last_line_buf = ""

        # Extract [MISSING: ...] sentinel before Guard B/C so they see clean text.
        # If the sentinel is present, _last_line_buf holds it — don't emit that line.
        # If absent, flush _last_line_buf to the client now.
        _missing_slugs, full_answer = _extract_missing_slugs(full_answer)
        if not _missing_slugs and _last_line_buf:
            yield {"event": "token", "data": {"text": _last_line_buf}}

        # Guard B: post-synthesis gap detection — same logic as run().
        # Fires when _detect_gap() missed (pre-synthesis, guard A) but the LLM
        # still could not answer from the available pages.
        if not _gap and full_answer.startswith("[GAP]"):
            _gap = True
            full_answer = full_answer[len("[GAP]"):].lstrip("\n")
            logger.debug("run_stream: guard B fired — post-synthesis gap detected")

        _gap = _guard_c_suppress(_gap, full_answer, "run_stream")

        # Strip any stray [MISSING: ...] text the LLM may have written; do not
        # use it to re-enable gap — Guard C's assessment is final.
        if _missing_slugs:
            logger.debug("run_stream: [MISSING] text stripped (Guard C decision preserved) — %s", _missing_slugs)

        yield {"event": "citations", "data": {"citations": [] if _gap else citations}}

        if _gap:
            # Use the standalone retrieval_question so gap suggestions are meaningful
            # when the user asked a context-dependent follow-up (e.g. "tell me more
            # about his death" → rewritten to "How did Alan Turing die?").
            _suggested = await SearchDecomposeAgent(self._provider).run(
                retrieval_question, domain_context=_purpose_ctx
            ) or [retrieval_question]
            logger.debug("run_stream: yielding gap event (%d searches)", len(_suggested))
            yield {"event": "gap", "data": {"suggested_searches": _suggested}}

        # Read exact token counts captured by the provider during streaming.
        # Providers that support usage reporting (OpenAI, Anthropic, Ollama) set
        # these after the generator is exhausted; others leave them at 0.
        _stream_input_tokens = self._provider.last_stream_input_tokens
        _stream_output_tokens = self._provider.last_stream_output_tokens

        next_hints = HintEngine.after_response(full_answer, session_mode)
        _done_data: dict = {
            "next_hints": next_hints,
            "cacheable": not _is_live_data,
            "routing_warning": routing_warning,
            "sub_questions_count": len(sub_questions),
            "tokens_used": _stream_input_tokens + _stream_output_tokens,
            "input_tokens": _stream_input_tokens,
            "output_tokens": _stream_output_tokens,
        }
        _pre_prompt = _build_pre_prompt(full_answer)
        if _pre_prompt:
            _done_data["pre_prompt"] = _pre_prompt
        yield {"event": "done", "data": _done_data}
