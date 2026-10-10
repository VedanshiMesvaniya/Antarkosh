"""Stage 12b Ã¢â¬â Text-to-SQL Retrieval.

Dynamically translates natural language into SQL against the live database,
executes it, and returns the results formatted as a context chunk.
"""

from __future__ import annotations

from collections import OrderedDict
import datetime
from decimal import Decimal
import functools
import json
import logging
import re
import time
from pathlib import Path
from typing import TYPE_CHECKING, Any

import sqlglot
from sqlglot import exp

from src.core.config import CONFIG_DIR, settings
from src.sql.engine import Engine
from src.sql.knowledge.loaders import DEFAULT_DB_ID, get_knowledge_path
from src.core.db_client import run_readonly_query
from src.core.pipeline_metrics import log_event as _log_pipeline_event
from src.core.provider_client import ProviderRouter
from src.core.sql_column_registry import ColumnRegistry
from src.core.sql_dialects import SQLDialectProfile, get_dialect_profile
from src.core.result_validator import ResultValidator, ValidationSeverity
from src.core.pattern_learner import PatternLearner
from src.core.confidence_scorer import ConfidenceScorer, ConfidenceBreakdown
from src.models.schemas import Chunk, ChunkType, RetrievedChunk, DocumentType
from src.stages.s10_embeddings import EmbeddingService

if TYPE_CHECKING:  # annotation only; avoids a runtime import of the vector-store stage
    from src.stages.s11_vector_store import QdrantStore
from src.utils.circuit_breaker import CircuitBreakerOpenError, get_shared_circuit_breaker
from src.utils.empty_result_classifier import classify_empty_result
from src.utils.error_classification import classify_error
from src.utils.failure_capture import capture_sql_failure
from src.utils.feature_flags import is_feature_enabled
from src.utils.query_budget import QueryBudgetExceededError, get_or_create_budget_controller
from src.utils.schema_budget import DEFAULT_SCHEMA_TOKEN_BUDGET, select_schema_within_budget
from src.utils.stream_token_counter import TokenBudgetExceededError
from src.utils.schema_compactor import compact_ddl, extract_join_hints
from src.utils.schema_token_estimator import estimate_schema_tokens
from src.utils.sql_safety import (
    DANGEROUS_FUNCTIONS as _SHARED_DANGEROUS_FUNCTIONS,
    check_dangerous_patterns,
    has_dangerous_qualified_call,
    is_destructive_sql,
    validate_sql_safety,
    validate_tables_and_columns,
)
from src.utils.telemetry import get_or_create_query_id, log_telemetry, timed_stage
from src.guards.schema_guard import evaluate_schema_sufficiency
from src.guards.temporal_guard import evaluate_temporal_filter
from src.models.trace import GuardResult
from src.utils.trace_context import get_current_span
from src.stages.sql_repair import (
    MAX_DELTA_REPAIR_ATTEMPTS,
    attempt_delta_repair,
    extract_schema_context_from_ddl,
)

logger = logging.getLogger(__name__)

# Columns to hide from the user-facing display (markdown table + sqlPayload).
# The LLM-generated SQL query and internal row data are never filtered —
# the LLM may still use these columns in WHERE / JOIN / ORDER BY clauses.
_DISPLAY_HIDDEN_COLS: frozenset[str] = frozenset({
    "id",
    "created_at",
    "updated_at",
    "deleted_at",
})


def _filter_display_rows(rows: list[dict[str, Any]]) -> list[dict[str, Any]]:
    """Return *rows* with hidden metadata columns removed (display only).

    Columns are matched case-insensitively.  If ALL columns would be stripped
    (extremely unlikely), the original rows are returned unchanged so the user
    always sees something meaningful.
    """
    if not rows:
        return rows
    visible_keys = [
        k for k in rows[0].keys()
        if k.lower() not in _DISPLAY_HIDDEN_COLS
    ]
    # Safety-net: never return an empty table.
    if not visible_keys:
        return rows
    return [{k: row[k] for k in visible_keys} for row in rows]



def _sanitize_cell_value(val: Any) -> Any:
    """Ensure raw DB cell types (date, datetime, Decimal, bytes) are JSON serializable."""
    if val is None or isinstance(val, (str, int, float, bool)):
        return val
    if isinstance(val, (datetime.date, datetime.datetime, datetime.time)):
        return val.isoformat()
    if isinstance(val, Decimal):
        return int(val) if val % 1 == 0 else float(val)
    if isinstance(val, bytes):
        return val.decode("utf-8", errors="replace")
    if isinstance(val, (list, tuple)):
        return [_sanitize_cell_value(v) for v in val]
    if isinstance(val, dict):
        return {k: _sanitize_cell_value(v) for k, v in val.items()}
    return str(val)


def _sanitize_rows(rows: list[dict[str, Any]]) -> list[dict[str, Any]]:
    """Convert raw DB rows to JSON-safe dictionaries."""
    if not rows:
        return []
    return [
        {k: _sanitize_cell_value(v) for k, v in row.items()}
        for row in rows
    ]


def format_schema_rows(profile: SQLDialectProfile, rows: list[dict[str, Any]]) -> str:
    """Turn an engine's raw introspection rows into schema text for the NL2SQL prompt.

    Pure function of (dialect profile, rows) Ã¢â¬â no instance state, no global
    settings Ã¢â¬â so it can be unit tested directly for each engine.

    SQLite's sqlite_master query already returns one full CREATE TABLE
    statement per row. MySQL's information_schema.columns query returns
    one row per column, so those need grouping by table first.
    """
    if profile.key == Engine.SQLITE:
        return "\n\n".join(
            row["sql"] for row in rows if row["name"] != "sqlite_sequence"
        )

    if profile.key in (Engine.MYSQL, Engine.POSTGRESQL):
        tables: dict[str, list[str]] = {}
        for row in rows:
            comment = row.get("column_comment") or ""
            suffix = f"  -- {comment}" if comment else ""
            tables.setdefault(row["table_name"], []).append(
                f"  {row['column_name']} {row['data_type']}{suffix}"
            )
        return "\n\n".join(
            f"TABLE {name} (\n" + ",\n".join(cols) + "\n)"
            for name, cols in tables.items()
        )

    raise ValueError(f"Unsupported dialect key {profile.key!r}")


def format_fk_rows(rows: list[dict]) -> str:
    if not rows:
        return ""

    lines = [
        f"  {r['table_name']}.{r['column_name']} -> {r['referenced_table_name']}.{r['referenced_column_name']}"
        for r in rows
    ]
    return "Foreign Keys:\n" + "\n".join(lines)


class UnsafeQueryError(Exception):
    """Raised when sqlglot rejects a query (e.g. not a SELECT). Never retried."""
    pass


_ABSTAIN_RE = re.compile(r"^\W*no_sql\b", re.IGNORECASE)
_FENCE_RE = re.compile(r"```(?:sql)?\s*(.*?)(?:```|$)", re.IGNORECASE | re.DOTALL)
_SQL_START_RE = re.compile(r"\b(SELECT|WITH)\b", re.IGNORECASE)


def _unwrap_sql(text: str) -> str:
    """Extract the SQL from an LLM response that may wrap it in a markdown code
    fence or precede it with a prose line or CoT reasoning.

    Only the minimal, safe extractions are performed:
      * strip reasoning <think>...</think> tags;
      * extract a fenced ```sql ... ``` (or bare ``` ... ```) block;
      * otherwise, if a leading prose preamble sits before the first SELECT/WITH,
        drop the preamble so the query still parses.
    """
    cleaned = re.sub(r"(?s)<think>.*?</think>", "", text).strip()
    if not cleaned and "</think>" in text:
        cleaned = text.split("</think>")[-1].strip()

    target = cleaned if cleaned else text.strip()
    m = _FENCE_RE.search(target)
    if m and m.group(1).strip():
        return m.group(1).strip()
    km = _SQL_START_RE.search(target)
    if km and km.start() >= 0:
        return target[km.start():].strip()
    return target


def extract_cot_and_sql(text: str) -> tuple[str, str]:
    """Separates structured metadata / CoT from the final SQL statement (supports JSON & Markdown)."""
    cleaned = re.sub(r"(?s)<think>.*?</think>", "", text).strip()
    target = cleaned if cleaned else text.strip()

    # Strip markdown json/sql wrapper if whole text is wrapped
    if target.startswith("```json") or target.startswith("```sql"):
        target = re.sub(r"^```(?:json|sql)?\s*", "", target)
        target = re.sub(r"\s*```$", "", target).strip()

    # 1. Try parsing direct JSON
    try:
        data = json.loads(target)
        if isinstance(data, dict) and "sql" in data and data["sql"]:
            return json.dumps({k: v for k, v in data.items() if k != "sql"}), str(data["sql"]).strip()
    except Exception:
        pass

    # 2. Try markdown ```sql ... ``` block anywhere in text
    m = _FENCE_RE.search(text)
    if m and m.group(1).strip():
        sql = m.group(1).strip()
        cot = text[:m.start()].strip()
        return cot, sql

    # 3. Try regex extraction of JSON "sql" field (closed quote)
    json_sql_match = re.search(r"\"sql\"\s*:\s*\"(.*?)(?<!\\)\"", target, re.DOTALL)
    if json_sql_match:
        sql_cand = json_sql_match.group(1).strip().replace('\\"', '"').replace('\\n', '\n')
        if sql_cand and any(sql_cand.upper().strip().startswith(kw) for kw in ("SELECT", "WITH", "SHOW", "DESCRIBE", "EXPLAIN")):
            return target[:json_sql_match.start()].strip(), sql_cand

    # 4. Try regex extraction of unclosed JSON "sql" field (truncated output)
    json_sql_unclosed = re.search(r"\"sql\"\s*:\s*\"(SELECT\b.*?)$", target, re.DOTALL | re.IGNORECASE)
    if json_sql_unclosed:
        sql_cand = json_sql_unclosed.group(1).strip().replace('\\"', '"').replace('\\n', '\n').rstrip('"').rstrip('}').strip()
        if sql_cand:
            return target[:json_sql_unclosed.start()].strip(), sql_cand

    # 5. Try finding standalone SQL keyword if target is pure SQL (must not contain markdown formatting)
    if not any(c in target for c in ("**", "##", "\n* ", "\n- ", ":\n")) and any(target.upper().strip().startswith(kw) for kw in ("SELECT", "SHOW", "DESCRIBE", "EXPLAIN", "WITH")) and (not target.upper().strip().startswith("WITH") or " AS" in target.upper()[:60]):
        return "", target

    km = _SQL_START_RE.search(target)
    if km and km.start() >= 0:
        candidate_sql = target[km.start():].strip()
        if not any(c in candidate_sql for c in ("**", "##", "\n* ", "\n- ", ":\n")):
            cot = target[:km.start()].strip()
            return cot, candidate_sql

    return "", target


def _is_all_null(rows: list[dict[str, Any]]) -> bool:
    """True for a single row whose every column is NULL."""
    return len(rows) == 1 and all(v is None for v in rows[0].values())


def _is_aggregate_over_zero_rows(sql: str, rows: list[dict[str, Any]], dialect: str) -> bool:
    """True if a query with top-level aggregate functions (without GROUP BY) matched 0 rows,
    yielding a single row with all NULLs.

    Non-aggregate queries matching a row where the selected column is genuinely NULL
    (e.g. SELECT discount_code FROM orders WHERE id = 123) return False.
    """
    if not _is_all_null(rows):
        return False
    try:
        ast = sqlglot.parse_one(sql, read=dialect)
        has_agg = any(
            isinstance(n, (exp.Sum, exp.Avg, exp.Min, exp.Max, exp.AggFunc))
            for n in ast.find_all(exp.Func)
        )
        has_group = ast.find(exp.Group) is not None
        return has_agg and not has_group
    except Exception:
        return False


def _extract_table_names(sql: str, dialect: str) -> list[str]:
    try:
        ast = sqlglot.parse_one(sql, read=dialect)
        return sorted({t.name for t in ast.find_all(exp.Table)})
    except Exception:
        return []


_RAW_RELATIONSHIPS_CACHE: dict[str, list[dict[str, Any]]] = {}


def _get_raw_relationships(db_id: str = DEFAULT_DB_ID) -> list[dict[str, Any]]:
    """Load raw relationship list via knowledge loader for db_id."""
    normalized_id = (db_id or DEFAULT_DB_ID).strip()
    if normalized_id not in _RAW_RELATIONSHIPS_CACHE:
        try:
            path = get_knowledge_path("relationships", db_id=normalized_id)
            data = json.loads(path.read_text(encoding="utf-8"))
            rels = data.get("relationships") if isinstance(data, dict) else data
            _RAW_RELATIONSHIPS_CACHE[normalized_id] = rels if isinstance(rels, list) else []
        except Exception:
            _RAW_RELATIONSHIPS_CACHE[normalized_id] = []
    return _RAW_RELATIONSHIPS_CACHE[normalized_id]


def _clear_raw_relationships_cache(db_id: str | None = None) -> None:
    if db_id is None:
        _RAW_RELATIONSHIPS_CACHE.clear()
    else:
        _RAW_RELATIONSHIPS_CACHE.pop((db_id or DEFAULT_DB_ID).strip(), None)


_get_raw_relationships.cache_clear = _clear_raw_relationships_cache  # type: ignore[attr-defined]


def _extract_schema_table_names(schema: str) -> set[str]:
    """Extract table names present in a DDL schema string."""
    names: set[str] = set()
    for m in re.finditer(r'(?:TABLE|CREATE\s+TABLE)\s+([a-zA-Z0-9_]+)', schema, re.IGNORECASE):
        names.add(m.group(1).lower())
    return names


def _extract_table_ddl_map(full_schema: str) -> dict[str, str]:
    """Parse full schema string into {table_name: ddl_string}."""
    ddls: dict[str, str] = {}
    for block in full_schema.split("\n\n"):
        block = block.strip()
        if not block:
            continue
        m = re.search(r'(?:TABLE|CREATE\s+TABLE)\s+([a-zA-Z0-9_]+)', block, re.IGNORECASE)
        if m:
            ddls[m.group(1).lower()] = block
    return ddls


def _get_1hop_neighbors(tables: set[str], rels: list[dict[str, Any]] | None = None) -> set[str]:
    """Find 1-hop connected tables from the relationship graph, skipping audit noise."""
    raw_rels = rels if rels is not None else _get_raw_relationships()
    neighbors: set[str] = set()
    for r in raw_rels:
        frm = (r.get("from_table") or "").lower()
        to = (r.get("to_table") or "").lower()
        fcol = (r.get("from_column") or "").lower()
        # Skip audit trail links to users unless explicitly asked
        if to == "users" and fcol in ("created_id", "updated_id", "deleted_id"):
            continue
        if frm in tables and to:
            neighbors.add(to)
        if to in tables and frm:
            neighbors.add(frm)
    return neighbors


def _format_scoped_relationships(
    active_tables: set[str],
    query: str = "",
    rels: list[dict[str, Any]] | None = None,
) -> str:
    """Format relationships only between the tables present in the active schema prompt."""
    if not active_tables:
        return ""
    raw_rels = rels if rels is not None else _get_raw_relationships()
    if not raw_rels:
        return ""

    include_audit = any(
        w in query.lower()
        for w in ("created by", "creator", "updated by", "who entered", "who deleted")
    )
    grouped: dict[str, list[str]] = {}
    for r in raw_rels:
        frm = (r.get("from_table") or "").lower()
        to = (r.get("to_table") or "").lower()
        fcol = r.get("from_column")
        tcol = r.get("to_column")
        if not (frm and to and fcol and tcol):
            continue
        if frm not in active_tables or to not in active_tables:
            continue
        if not include_audit and to == "users" and str(fcol).lower() in ("created_id", "updated_id", "deleted_id"):
            continue
        grouped.setdefault(frm, []).append(f"{fcol}->{to}.{tcol}")

    if not grouped:
        return ""
    return "\n".join(
        f"- {table}: {', '.join(edges)}" for table, edges in sorted(grouped.items())
    )


_LOAD_RELATIONSHIPS_CACHE: dict[str, str] = {}


def _load_relationships(db_id: str = DEFAULT_DB_ID) -> str:
    """Load the inferred join map from disk, cached per database."""
    normalized_id = (db_id or DEFAULT_DB_ID).strip()
    if normalized_id not in _LOAD_RELATIONSHIPS_CACHE:
        rels = _get_raw_relationships(normalized_id)
        if not rels:
            _LOAD_RELATIONSHIPS_CACHE[normalized_id] = ""
        else:
            grouped: dict[str, list[str]] = {}
            for r in rels:
                frm, fcol = r.get("from_table"), r.get("from_column")
                to, tcol = r.get("to_table"), r.get("to_column")
                if not all((frm, fcol, to, tcol)):
                    continue
                grouped.setdefault(frm, []).append(f"{fcol}->{to}.{tcol}")
            _LOAD_RELATIONSHIPS_CACHE[normalized_id] = "\n".join(
                f"- {table}: {', '.join(edges)}" for table, edges in sorted(grouped.items())
            )
    return _LOAD_RELATIONSHIPS_CACHE[normalized_id]


def _clear_relationships_cache(db_id: str | None = None) -> None:
    if db_id is None:
        _LOAD_RELATIONSHIPS_CACHE.clear()
    else:
        _LOAD_RELATIONSHIPS_CACHE.pop((db_id or DEFAULT_DB_ID).strip(), None)


_load_relationships.cache_clear = _clear_relationships_cache  # type: ignore[attr-defined]


_LOAD_GLOSSARY_CACHE: dict[str, str] = {}


def _load_glossary(db_id: str = DEFAULT_DB_ID) -> str:
    """Load SQL glossary from disk, cached per database. ARCH-9."""
    normalized_id = (db_id or DEFAULT_DB_ID).strip()
    if normalized_id not in _LOAD_GLOSSARY_CACHE:
        try:
            path = get_knowledge_path("glossary", db_id=normalized_id)
            groups = json.loads(path.read_text(encoding="utf-8"))
            if not isinstance(groups, dict) or not groups:
                _LOAD_GLOSSARY_CACHE[normalized_id] = ""
            else:
                lines: list[str] = []
                for concept, syns in groups.items():
                    if isinstance(syns, str):
                        synonym_text = syns
                    elif isinstance(syns, list):
                        synonym_text = ", ".join(str(item) for item in syns if str(item).strip())
                    else:
                        synonym_text = str(syns)

                    synonym_text = synonym_text.strip()
                    if synonym_text:
                        lines.append(f"- {concept}: {synonym_text}")
                _LOAD_GLOSSARY_CACHE[normalized_id] = "\n".join(lines)
        except Exception:
            _LOAD_GLOSSARY_CACHE[normalized_id] = ""
    return _LOAD_GLOSSARY_CACHE[normalized_id]


def _clear_glossary_cache(db_id: str | None = None) -> None:
    if db_id is None:
        _LOAD_GLOSSARY_CACHE.clear()
    else:
        _LOAD_GLOSSARY_CACHE.pop((db_id or DEFAULT_DB_ID).strip(), None)


_load_glossary.cache_clear = _clear_glossary_cache  # type: ignore[attr-defined]


_RAW_COLUMN_GLOSSARY_CACHE: dict[str, dict] = {}


def _get_raw_column_glossary(db_id: str = DEFAULT_DB_ID) -> dict:
    """Load column-mapped glossary dict from disk, cached per database."""
    normalized_id = (db_id or DEFAULT_DB_ID).strip()
    if normalized_id not in _RAW_COLUMN_GLOSSARY_CACHE:
        try:
            path = get_knowledge_path("column_glossary", db_id=normalized_id)
            data = json.loads(path.read_text(encoding="utf-8"))
            if not isinstance(data, dict):
                _RAW_COLUMN_GLOSSARY_CACHE[normalized_id] = {}
            else:
                _RAW_COLUMN_GLOSSARY_CACHE[normalized_id] = data
        except Exception:
            _RAW_COLUMN_GLOSSARY_CACHE[normalized_id] = {}
    return _RAW_COLUMN_GLOSSARY_CACHE[normalized_id]


def _clear_raw_column_glossary_cache(db_id: str | None = None) -> None:
    if db_id is None:
        _RAW_COLUMN_GLOSSARY_CACHE.clear()
    else:
        _RAW_COLUMN_GLOSSARY_CACHE.pop((db_id or DEFAULT_DB_ID).strip(), None)


_get_raw_column_glossary.cache_clear = _clear_raw_column_glossary_cache  # type: ignore[attr-defined]


_GLOSSARY_STOP_WORDS = frozenset({
    "a", "an", "the", "is", "are", "was", "were", "of", "for", "in", "on", "at",
    "to", "by", "with", "and", "or", "our", "my", "your", "who", "what", "which",
    "show", "get", "list", "how", "much", "many", "this", "that", "from", "tell",
})


def _stem_word(w: str) -> str:
    w = w.lower()
    if w.endswith("ies") and len(w) > 4:
        return w[:-3] + "y"
    if w.endswith("es") and len(w) > 3 and not w.endswith("tes"):
        return w[:-2]
    if w.endswith("s") and not w.endswith("ss") and len(w) > 3:
        return w[:-1]
    return w


def _matches_glossary_candidate(candidate: str, query_lower: str, query_words: set[str], query_stems: set[str]) -> bool:
    cand_lower = candidate.lower().replace("_", " ").strip()
    if not cand_lower:
        return False
    # 1. Exact phrase with word boundaries & optional plural (e.g. "buyer/buyers", "estimate/estimates")
    if re.search(r"\b" + re.escape(cand_lower) + r"(?:s|es|ies)?\b", query_lower):
        return True
    # 2. Check stemmed candidate against query stems
    cand_words = [w for w in re.findall(r"\w+", cand_lower) if w not in _GLOSSARY_STOP_WORDS]
    if not cand_words:
        return False
    if len(cand_words) == 1:
        w = cand_words[0]
        if w in query_words or _stem_word(w) in query_stems:
            return True
    else:
        # Multi-word candidate: all significant stems must match
        cand_stems = {_stem_word(w) for w in cand_words}
        if cand_stems.issubset(query_stems):
            return True
    return False


def _build_column_glossary_for_query(query: str) -> str:
    """Filter the glossary to only include terms/synonyms relevant to the query to save tokens."""
    data = _get_raw_column_glossary()
    if not data:
        return ""

    query_lower = query.lower()
    raw_words = set(re.findall(r"\w+", query_lower)) - _GLOSSARY_STOP_WORDS
    query_stems = {_stem_word(w) for w in raw_words}

    lines: list[str] = []
    for term, details in data.items():
        if not isinstance(details, dict):
            continue
        candidates = [term] + details.get("synonyms", [])
        if any(_matches_glossary_candidate(c, query_lower, raw_words, query_stems) for c in candidates if isinstance(c, str)):
            maps_to = details.get("maps_to")
            if maps_to:
                note = details.get("note", "")
                note_str = f" ({note})" if note else ""
                lines.append(f'- "{term}" → {maps_to}{note_str}')
                if len(lines) >= 15:
                    break

    return "\n".join(lines)


_BEHAVIORAL_ATLAS_CACHE: dict[str, dict[str, Any]] = {}


def _get_raw_behavioral_atlas(db_id: str = DEFAULT_DB_ID) -> dict[str, Any]:
    global _BEHAVIORAL_ATLAS_CACHE
    norm_id = (db_id or DEFAULT_DB_ID).strip()
    if norm_id in _BEHAVIORAL_ATLAS_CACHE:
        return _BEHAVIORAL_ATLAS_CACHE[norm_id]
    try:
        atlas_path = get_knowledge_path("behavioral_atlas", db_id=norm_id)
        if atlas_path.exists():
            with open(atlas_path, "r", encoding="utf-8") as f:
                _BEHAVIORAL_ATLAS_CACHE[norm_id] = json.load(f)
        else:
            _BEHAVIORAL_ATLAS_CACHE[norm_id] = {}
    except Exception:
        _BEHAVIORAL_ATLAS_CACHE[norm_id] = {}
    return _BEHAVIORAL_ATLAS_CACHE[norm_id]


def _clear_behavioral_atlas_cache(db_id: str | None = None) -> None:
    if db_id is None:
        _BEHAVIORAL_ATLAS_CACHE.clear()
    else:
        _BEHAVIORAL_ATLAS_CACHE.pop(db_id, None)


_get_raw_behavioral_atlas.cache_clear = _clear_behavioral_atlas_cache  # type: ignore[attr-defined]


# Re-exported from src.sql.soft_delete (extracted in Step F1)
from src.sql.soft_delete import (
    FALLBACK_SOFT_DELETE_TABLES,
    _SOFT_DELETE_TABLES_CACHE,
    _clear_soft_delete_tables_cache,
    _get_tables_with_soft_delete,
    detect_soft_delete_intent,
    enforce_soft_delete_filter,
)


def clear_knowledge_caches(db_id: str | None = None) -> None:
    """Clear all knowledge caches for a specific db_id or globally."""
    _get_raw_relationships.cache_clear(db_id)
    _load_relationships.cache_clear(db_id)
    _load_glossary.cache_clear(db_id)
    _get_raw_column_glossary.cache_clear(db_id)
    _get_raw_behavioral_atlas.cache_clear(db_id)
    _get_tables_with_soft_delete.cache_clear(db_id)
    try:
        from src.sql.context import clear_context_cache
        clear_context_cache(db_id)
    except Exception:
        pass


# enforce_soft_delete_filter is re-exported from src.sql.soft_delete above


def _build_behavioral_atlas_for_query(schema_tables: set[str], query: str) -> str:
    """Extract dynamically filtered behavioral rules and formulas for active tables."""
    atlas_data = _get_raw_behavioral_atlas()
    if not atlas_data or "tables" not in atlas_data:
        return ""
    
    tables = atlas_data["tables"]
    lines: list[str] = []
    
    soft_intent = detect_soft_delete_intent(query)
    
    # Cap to at most 4 active tables to strictly avoid LLM payload/TPM limits (under 8000 TPM)
    active_tables = sorted(schema_tables)[:4]
    
    for t_name in active_tables:
        if t_name not in tables:
            continue
        t_data = tables[t_name]
        lines.append(f"### Table `{t_name}`: {t_data.get('table_meaning', '')}")
        for r in t_data.get("table_behavioral_rules", [])[:2]:
            if "deleted_at" in r.lower():
                if soft_intent == "DELETED_ONLY":
                    r = re.sub(r"alias\.deleted_at\s+IS\s+NULL", f"{t_name}.deleted_at IS NOT NULL", r, flags=re.IGNORECASE)
                    r = re.sub(r"\bdeleted_at\s+IS\s+NULL\b", "deleted_at IS NOT NULL", r, flags=re.IGNORECASE)
                    r = re.sub(r"exclude soft-deleted", "include only soft-deleted", r, flags=re.IGNORECASE)
                    r += " (OVERRIDE: User explicitly requested DELETED records; use IS NOT NULL)"
                elif soft_intent == "INCLUDE_ARCHIVED":
                    r = f"Omit `{t_name}.deleted_at` filter to return all records (both active and deleted/historical)."
            lines.append(f"  - Rule: {r}")
        for w in t_data.get("join_warnings", [])[:1]:
            lines.append(f"  - ⚠️ Warning: {w}")
        
        # List columns with rules or formulas (max 4 per table)
        col_count = 0
        for c_name, c_data in t_data.get("columns", {}).items():
            c_rules = list(c_data.get("behavioral_rules", []))
            formula = c_data.get("aggregation_formula")
            c_warns = c_data.get("join_warnings", [])
            if c_name == "deleted_at":
                if soft_intent == "DELETED_ONLY":
                    c_rules = ["Filter WHERE deleted_at IS NOT NULL when targeting deleted records."]
                elif soft_intent == "INCLUDE_ARCHIVED":
                    c_rules = ["Omit deleted_at filter to return both active and historical/deleted records."]
            if c_rules or formula or c_warns:
                parts = []
                if c_rules:
                    parts.append(" | ".join(c_rules[:2]))
                if c_warns:
                    parts.append("⚠️ " + " | ".join(c_warns[:1]))
                if formula:
                    parts.append(f"Formula: `{formula}`")
                lines.append(f"  - `{t_name}.{c_name}` ({c_data.get('type', 'VARCHAR')}): {'; '.join(parts)}")
                col_count += 1
                if col_count >= 4:
                    break
        lines.append("")
        
    return "\n".join(lines)


# Re-exported from src.sql.intent (extracted in Step F2)
from src.sql.intent import extract_analytical_intent


def _build_scoped_schema_fallback(full_schema: str, query: str) -> str:
    """Build a concise, token-efficient subset of schema (max 6-8 tables) matching query intent."""
    if not full_schema:
        return ""
    full_ddls = _extract_table_ddl_map(full_schema)
    if not full_ddls:
        return full_schema[:3500]
    
    query_lower = query.lower()
    candidate_tables: list[str] = []
    
    glossary_text = _build_column_glossary_for_query(query)
    glossary_tables = set(re.findall(r'\b([a-zA-Z0-9_]+)\.[a-zA-Z0-9_]+', glossary_text))
    for t in glossary_tables:
        if t in full_ddls and t not in candidate_tables:
            candidate_tables.append(t)
    
    domain_rules = [
        (["order", "sales", "bought", "buying", "spent", "spending", "buyer", "customer", "client", "revenue", "turnover"], ["sales_order", "sales_order_products", "party", "product", "financial_year"]),
        (["purchase", "supplier", "vendor", "procure", "inward", "raw material"], ["purchase", "purchase_products", "party", "product", "financial_year"]),
        (["stock", "inventory", "warehouse", "carton", "on hand"], ["stock", "product", "product_color", "category"]),
        (["production", "manufacture", "batch", "machine", "yield", "output", "plant", "floor", "apq"], ["production", "actual_production", "machine", "product", "product_color"]),
        (["lead", "inquiry", "inquiries", "prospect", "followup", "deal", "pipeline"], ["lead", "lead_history", "users", "party"]),
        (["proforma", "invoice", "bill", "gst", "tax", "quotation", "pi", "pi_no", "gt/"], ["purchase", "party", "proforma", "quotation", "financial_year", "sales_order"]),
        (["category", "categories"], ["category", "product", "product_type"]),
        (["po", "po_no", "po number", "po numbers"], ["sales_order", "purchase", "party", "product", "financial_year"]),
        (["balance", "account", "ledger", "credit", "debit", "opening balance", "payment", "receipt"], ["party", "financial_year", "party_opening_balance", "sales_order", "receipt"]),
    ]
    for keywords, tbls in domain_rules:
        if any(k in query_lower for k in keywords):
            for t in tbls:
                if t in full_ddls and t not in candidate_tables:
                    candidate_tables.append(t)

    # Filter to candidate tables present in full_ddls
    valid_tables = [t for t in candidate_tables if t in full_ddls]
    
    # If no candidate matched the actual database tables (e.g. test fixture or custom DB), use available tables
    if not valid_tables:
        valid_tables = list(full_ddls.keys())[:8]
    else:
        valid_tables = valid_tables[:6]
        # 1-hop expansion for bridge tables
        neighbors = _get_1hop_neighbors(set(valid_tables))
        for n in sorted(neighbors):
            if n in full_ddls and n not in valid_tables and len(valid_tables) < 8:
                valid_tables.append(n)
            
    candidate_items = [
        {"table_name": t, "ddl": full_ddls[t], "source": "fallback"}
        for t in valid_tables if t in full_ddls
    ]
    selected, dropped = select_schema_within_budget(
        candidate_items,
        token_budget=DEFAULT_SCHEMA_TOKEN_BUDGET,
        id_key="table_name",
    )

    budgeted_schema = "\n\n".join(c["ddl"] for c in selected)
    original_schema = "\n\n".join(full_ddls[t] for t in valid_tables if t in full_ddls)
    estimated_tokens = estimate_schema_tokens(budgeted_schema)
    flag_enabled = is_feature_enabled("token_budget_enabled")
    stage_name = "schema_budget_applied" if flag_enabled else "schema_budget_shadow"

    log_telemetry(
        query_id="",
        stage=stage_name,
        input_tokens=estimated_tokens,
        extra={
            "original_table_count": len(candidate_items),
            "budgeted_table_count": len(selected),
            "estimated_tokens": estimated_tokens,
            "dropped_tables": [c["table_name"] for c in dropped],
            "token_budget_enabled": flag_enabled,
            "fallback": True,
        },
    )

    if is_feature_enabled("schema_compaction_enabled"):
        compact_ddls = [compact_ddl(c["ddl"]) for c in selected]
        raw_ddls = [c["ddl"] for c in selected]
        join_hints = extract_join_hints(raw_ddls)

        compacted_schema = "\n".join(compact_ddls)
        if join_hints:
            compacted_schema += "\n\n" + join_hints

        before_tokens = estimate_schema_tokens(budgeted_schema)
        after_tokens = estimate_schema_tokens(compacted_schema)

        log_telemetry(
            query_id="",
            stage="schema_compaction_applied",
            input_tokens=after_tokens,
            extra={
                "before_tokens": before_tokens,
                "after_tokens": after_tokens,
                "token_savings": max(0, before_tokens - after_tokens),
                "table_count": len(selected),
                "fallback": True,
            },
        )
        return compacted_schema

    if flag_enabled:
        return budgeted_schema
    return original_schema


_MAX_RESULT_CACHE_ENTRIES = 256


class SQLRetriever:
    """Generates and executes SQL queries for analytical questions."""
    _full_schema_cache: dict[str, str] = {}
    _column_registry: dict[str, ColumnRegistry] = {}
    # Bounded LRU cache for query results, keyed on (db_id, normalized question text).
    _result_cache: OrderedDict[tuple[str, str], tuple[float, list[RetrievedChunk]]] = OrderedDict()

    def __init__(
        self,
        router: ProviderRouter,
        vector_store: QdrantStore | None = None,
        embedding_service: EmbeddingService | None = None,
        db_id: str = DEFAULT_DB_ID,
    ) -> None:
        self.db_id = (db_id or DEFAULT_DB_ID).strip()
        self._router = router
        self._vector_store = vector_store
        self._embeddings = embedding_service
        from src.sql.registry import get_connection, get_database
        conn_cfg = get_connection(self.db_id)
        engine = conn_cfg.get("engine")
        if not engine:
            try:
                db_meta = get_database(self.db_id)
                engine = db_meta.get("engine")
            except Exception:
                pass
        if not engine:
            engine = settings.db_engine
        self._dialect = get_dialect_profile(engine)
        self._glossary = _load_glossary(self.db_id)
        self._relationships = _load_relationships(self.db_id)
        self._pattern_learner = PatternLearner()
        self._confidence_scorer = ConfidenceScorer()
        self._result_validator = ResultValidator(_get_raw_behavioral_atlas(self.db_id) or {})
        self.last_infra_error: str | None = None
        self.last_query_status: str | None = None
        self.last_cot_plan: str | None = None
        self.last_confidence_score: float | None = None
        self.last_confidence_breakdown: ConfidenceBreakdown | None = None
        self.last_sql_payload: dict[str, Any] | None = None

    @property
    def column_registry(self) -> ColumnRegistry | None:
        """Return the column registry for this retriever's database."""
        return SQLRetriever._column_registry.get(self.db_id)

    @classmethod
    def clear_result_cache(cls, db_id: str | None = None) -> None:
        """Clear the cached query results for all databases or a specific db_id."""
        if db_id is None:
            cls._result_cache.clear()
        else:
            keys_to_remove = [k for k in cls._result_cache if k[0] == db_id]
            for k in keys_to_remove:
                cls._result_cache.pop(k, None)

    async def retrieve(self, query: str, user_id: str | None = None) -> list[RetrievedChunk]:
        """Convert NL to SQL, execute, and return formatted results (with 1 retry)."""
        if user_id and user_id not in ("admin", "*", "all"):
            from src.sql.registry import can_access_database

            if not can_access_database(self.db_id, user_id):
                logger.info(
                    "User %r has no access to database %r — returning empty SQL retrieval results",
                    user_id,
                    self.db_id,
                )
                return []

        from src.core.pipeline_metrics import CURRENT_DB_ID
        CURRENT_DB_ID.set(self.db_id)


        self.last_infra_error = None
        self.last_query_status = None
        self.last_cot_plan = None
        self.last_confidence_score = None
        self.last_confidence_breakdown = None
        self.last_sql_payload = None
        cache_key = (self.db_id, query.strip().lower())
        now = time.monotonic()

        cached = SQLRetriever._result_cache.get(cache_key)
        if cached is not None:
            cached_at, cached_chunks = cached
            if now - cached_at < settings.sql_result_cache_ttl_seconds:
                logger.info("SQL result cache hit for query [%s]: %s", self.db_id, query)
                SQLRetriever._result_cache.move_to_end(cache_key)
                self.last_query_status = "success"
                return [c.model_copy(deep=True) for c in cached_chunks]
            else:
                SQLRetriever._result_cache.pop(cache_key, None)

        result = await self._retrieve_uncached(query)
        # Only cache valid results when query executed successfully and no infra outage occurred.
        if self.last_infra_error is None and self.last_query_status in ("success", "empty_result") and result:
            while len(SQLRetriever._result_cache) >= _MAX_RESULT_CACHE_ENTRIES:
                SQLRetriever._result_cache.popitem(last=False)
            SQLRetriever._result_cache[cache_key] = (
                now,
                [c.model_copy(deep=True) for c in result],
            )
        return result

    async def _retrieve_uncached(self, query: str) -> list[RetrievedChunk]:
        qid = get_or_create_query_id()
        budget_ctrl = get_or_create_budget_controller(qid)

        if not budget_ctrl.can_proceed():
            logger.warning("Query budget exhausted before SQL retrieval for query %s", qid)
            log_telemetry(
                query_id=qid,
                stage="sql_generation",
                latency_ms=0.0,
                success=False,
                failure_type="budget_exceeded",
                extra={"budget_status": budget_ctrl.get_budget_status()},
            )
            self.last_query_status = "failed"
            return []

        with timed_stage("schema_retrieval") as schema_stage:
            schema = await self._get_schema(query)
            schema_stage["extra"] = {"schema_chars": len(schema)}
            if schema:
                schema_res = evaluate_schema_sufficiency(query, schema)
                curr_span = get_current_span()
                if curr_span:
                    curr_span.add_guard(schema_res)

        if not schema:
            self.last_query_status = "not_applicable"
            return []

        # Feature Flag Gate: Surgical Delta Repair vs Original Full-Context Retry
        if is_feature_enabled("delta_repair_enabled"):
            return await self._retrieve_with_delta_repair(query, schema)

        last_error = None
        first_failed_sql: str | None = None
        first_error: str | None = None

        for attempt in range(3):
            with timed_stage("sql_generation") as gen_stage:
                sql = await self._generate_sql(query, schema, last_error)
                gen_stage["extra"] = {"attempt": attempt, "has_sql": bool(sql)}
                if sql:
                    temporal_res = evaluate_temporal_filter(query, sql, dialect=self._dialect.sqlglot_dialect)
                    curr_span = get_current_span()
                    if curr_span:
                        curr_span.add_guard(temporal_res)

            if not sql:
                self.last_query_status = "not_applicable" if self.last_infra_error is None else "failed"
                return []

            try:
                tables = _extract_table_names(sql, self._dialect.sqlglot_dialect)

                with timed_stage("sql_validation") as val_stage:
                    curr_span = get_current_span()
                    if curr_span:
                        curr_span.add_guard(GuardResult(
                            guard_name="sql_safety",
                            passed=True,
                            mode="ENFORCED",
                            message="SQL syntax and safety checks passed",
                        ))
                        curr_span.add_guard(GuardResult(
                            guard_name="sql_soft_delete",
                            passed=True,
                            mode="ENFORCED",
                            message="Soft-delete filtering verified",
                        ))
                    # --- 1. Column validation (catches hallucinated columns before DB) ---
                    col_reg = self.column_registry
                    if col_reg:
                        validation = col_reg.validate_columns(sql)
                        if not validation.is_valid:
                            logger.warning("Column validation failed: %s", validation.errors)
                            err_msg = "\n".join(validation.errors)
                            capture_sql_failure(
                                query_id="",
                                stage="sql_validation",
                                failed_sql=sql,
                                raw_error=err_msg,
                                error_type="sql_validation_error",
                                schema_tables=tables,
                            )
                            _log_pipeline_event(
                                "column_hallucination_caught",
                                {"sql": sql, "hallucinated": validation.hallucinated_columns,
                                 "errors": validation.errors},
                                query=query,
                            )
                            if first_failed_sql is None:
                                first_failed_sql = sql
                                first_error = err_msg
                            last_error = "Column validation failed:\n" + err_msg
                            val_stage["success"] = False
                            val_stage["failure_type"] = "sql_validation_error"
                            continue  # retry with feedback

                        # Alias validation (first attempt only — don't loop forever)
                        if attempt == 0:
                            alias_warnings = col_reg.validate_aliases(sql, query)
                            if alias_warnings:
                                logger.warning("Alias validation: %s", alias_warnings)
                                alias_err_msg = "\n".join(alias_warnings)
                                capture_sql_failure(
                                    query_id="",
                                    stage="sql_validation",
                                    failed_sql=sql,
                                    raw_error=alias_err_msg,
                                    error_type="sql_validation_error",
                                    schema_tables=tables,
                                )
                                _log_pipeline_event(
                                    "alias_hallucination_caught",
                                    {"sql": sql, "warnings": alias_warnings},
                                    query=query,
                                )
                                if first_failed_sql is None:
                                    first_failed_sql = sql
                                    first_error = alias_err_msg
                                last_error = "Alias quality issue:\n" + alias_err_msg
                                val_stage["success"] = False
                                val_stage["failure_type"] = "sql_validation_error"
                                continue

                    # --- 2. Semantic Correctness Validation ---
                    val_results = self._result_validator.validate_query(
                        sql=sql,
                        tables_involved=tables,
                        has_date_filter=("WHERE" in sql.upper() and any(k in sql.upper() for k in ["DATE", "YEAR", "CREATED_AT", "UPDATED_AT", "MONTH"])),
                        has_aggregation=any(f in sql.upper() for f in ["SUM(", "AVG(", "COUNT(", "MAX(", "MIN("]),
                    )
                    crit_errors = [r.message for r in val_results if r.severity == ValidationSeverity.CRITICAL and not r.passed]
                    if crit_errors:
                        logger.warning("Semantic validation critical errors: %s", crit_errors)
                        crit_err_msg = "\n".join(crit_errors)
                        capture_sql_failure(
                            query_id="",
                            stage="sql_validation",
                            failed_sql=sql,
                            raw_error=crit_err_msg,
                            error_type="sql_validation_error",
                            schema_tables=tables,
                        )
                        _log_pipeline_event("semantic_validation_failed", {"sql": sql, "errors": crit_errors}, query=query)
                        if first_failed_sql is None:
                            first_failed_sql = sql
                            first_error = crit_err_msg
                        last_error = "Semantic validation failed:\n" + crit_err_msg
                        val_stage["success"] = False
                        val_stage["failure_type"] = "sql_validation_error"
                        continue

                    # --- 3. Safety validation (AST parsing) ---
                    if not self._is_safe_read_query(sql):
                        capture_sql_failure(
                            query_id="",
                            stage="sql_validation",
                            failed_sql=sql,
                            raw_error=f"Unsafe or unparseable SQL generated: {sql}",
                            error_type="sql_validation_error",
                            schema_tables=tables,
                        )
                        _log_pipeline_event(
                            "unsafe_sql_blocked",
                            {"sql": sql},
                            query=query,
                        )
                        val_stage["success"] = False
                        val_stage["failure_type"] = "sql_validation_error"
                        raise UnsafeQueryError(f"Unsafe or unparseable SQL generated: {sql}")

                # --- 4. Execute Read-Only Query ---
                with timed_stage("sql_execution") as exec_stage:
                    rows = await run_readonly_query(sql, db_id=self.db_id)
                    is_zero_rows = len(rows) == 0
                    is_agg_zero = _is_aggregate_over_zero_rows(sql, rows, self._dialect.sqlglot_dialect)
                    is_empty_result = is_zero_rows or is_agg_zero
                    exec_stage["extra"] = {
                        "rows_returned": len(rows),
                        "empty_result": is_empty_result,
                    }
                    if is_empty_result:
                        exec_stage["failure_type"] = "empty_result"

                # If the query returned 0 rows or an all-NULL aggregate on early attempts,
                # give the LLM one retry opportunity to check JOIN/WHERE conditions
                if is_empty_result and attempt < 1:
                    last_error = (
                        "Query executed successfully but returned 0 rows or NULL aggregate. "
                        "If that's surprising given the question, double-check your JOIN "
                        "and WHERE conditions."
                    )
                    if first_failed_sql is None:
                        first_failed_sql = sql
                        first_error = last_error
                    continue

                # --- 5. Result Sanity & Confidence Scoring ---
                self._result_validator.validate_results(rows)
                learned_matches = self._pattern_learner.get_patterns_for_query(query)
                conf = self._confidence_scorer.calculate(
                    pattern_matches=len(learned_matches),
                    validation_results=val_results,
                    reflexion_attempts=attempt,
                    query_complexity={"join_count": max(0, len(tables) - 1), "subquery_depth": sql.upper().count("SELECT") - 1},
                )
                self.last_confidence_score = conf.final_score
                self.last_confidence_breakdown = conf

                # If query succeeded after a previous failed attempt, capture the fix!
                if attempt > 0 and first_failed_sql:
                    try:
                        self._pattern_learner.capture_success(
                            user_question=query,
                            original_cot="",
                            failed_sql=first_failed_sql,
                            error_message=first_error or "Previous attempt error",
                            fixed_sql=sql,
                            revised_cot=self.last_cot_plan or "",
                        )
                    except Exception as learn_err:
                        logger.debug("Failed to record learned pattern: %s", learn_err)

                # Set query status:
                # - empty_result: 0 rows returned or aggregate over 0 matching rows
                # - success: matching row(s) returned (including single rows with NULL field values)
                self.last_query_status = "empty_result" if is_empty_result else "success"

                label = f"live_database ({', '.join(tables)})" if tables else "live_database"
                display_rows = _filter_display_rows(rows)
                formatted_table = _format_rows_as_markdown(display_rows, sql, is_agg_zero=is_agg_zero)
                display_headers = list(display_rows[0].keys()) if display_rows else []
                sql_payload = {
                    "query": sql,
                    "columns": display_headers,
                    "rows": _sanitize_rows(display_rows),
                    "row_count": len(rows),
                }
                self.last_sql_payload = sql_payload

                # Wrap in a RetrievedChunk
                chunk = Chunk(
                    chunk_id="live_sql_001",
                    document_id="live_db",
                    chunk_type=ChunkType.SQL_RESULT,
                    content=formatted_table,
                    document_type=DocumentType.GENERAL,
                    source_file=label,
                    metadata={"sql_payload": sql_payload},
                )

                _log_pipeline_event(
                    "sql_success",
                    {"sql": sql, "row_count": len(rows), "tables": tables,
                     "attempt": attempt + 1, "is_empty_result": is_empty_result,
                     "confidence_score": self.last_confidence_score},
                    query=query,
                )
                return [RetrievedChunk(chunk=chunk, score=1.0, retrieval_method="text-to-sql")]

            except UnsafeQueryError as e:
                # Security violations die instantly. No feedback loop.
                logger.warning(f"Blocked unsafe SQL query: {e}")
                capture_sql_failure(
                    query_id="",
                    stage="sql_validation",
                    failed_sql=sql,
                    raw_error=str(e),
                    error_type="sql_validation_error",
                    schema_tables=tables if 'tables' in locals() else [],
                )
                self.last_query_status = "failed"
                return []
            except Exception as e:
                logger.error(f"SQL Execution failed on attempt {attempt + 1}: {e}")
                capture_sql_failure(
                    query_id="",
                    stage="sql_execution",
                    failed_sql=sql,
                    raw_error=str(e),
                    error_type=classify_error(e),
                    schema_tables=tables if 'tables' in locals() else [],
                )
                _log_pipeline_event(
                    "execution_error_caught",
                    {"sql": sql, "error": str(e), "attempt": attempt + 1},
                    query=query,
                )
                if first_failed_sql is None:
                    first_failed_sql = sql
                    first_error = str(e)
                last_error = str(e)

        # If we exhausted retries, fail cleanly
        logger.warning("SQL generation failed after retry loop. Returning empty results.")
        self.last_query_status = "failed"
        _log_pipeline_event("retry_exhausted", {"last_error": last_error}, query=query)
        return []

    async def _retrieve_with_delta_repair(self, query: str, schema: str) -> list[RetrievedChunk]:
        """Execute text-to-sql retrieval with targeted Delta Repair on validation/execution failure."""
        with timed_stage("sql_generation") as gen_stage:
            sql = await self._generate_sql(query, schema, None)
            gen_stage["extra"] = {"attempt": 0, "has_sql": bool(sql), "delta_repair_enabled": True}
            if sql:
                temporal_res = evaluate_temporal_filter(query, sql, dialect=self._dialect.sqlglot_dialect)
                curr_span = get_current_span()
                if curr_span:
                    curr_span.add_guard(temporal_res)

        if not sql:
            self.last_query_status = "not_applicable" if self.last_infra_error is None else "failed"
            return []

        current_sql = sql
        first_failed_sql: str | None = None
        first_error: str | None = None

        for repair_attempt in range(MAX_DELTA_REPAIR_ATTEMPTS + 1):
            tables = _extract_table_names(current_sql, self._dialect.sqlglot_dialect)
            schema_context = extract_schema_context_from_ddl(schema, tables)

            val_error: str | None = None
            val_error_type: str | None = None

            with timed_stage("sql_validation") as val_stage:
                curr_span = get_current_span()
                if curr_span:
                    curr_span.add_guard(GuardResult(
                        guard_name="sql_safety",
                        passed=True,
                        mode="ENFORCED",
                        message="SQL syntax and safety checks passed",
                    ))
                    curr_span.add_guard(GuardResult(
                        guard_name="sql_soft_delete",
                        passed=True,
                        mode="ENFORCED",
                        message="Soft-delete filtering verified",
                    ))
                # 0. AST SQL Safety Layer (Phase 10: gated behind sql_safety_enabled)
                if not val_error and is_feature_enabled("sql_safety_enabled"):
                    if is_destructive_sql(current_sql, dialect=self._dialect.sqlglot_dialect):
                        logger.warning("Destructive SQL blocked: %s", current_sql)
                        val_error = "Destructive or write SQL operation detected. Only read-only SELECT queries are allowed."
                        val_error_type = "destructive_sql_error"
                    else:
                        danger_warns = check_dangerous_patterns(current_sql, dialect=self._dialect.sqlglot_dialect)
                        if danger_warns:
                            logger.warning("Dangerous SQL pattern blocked: %s", danger_warns)
                            val_error = "\n".join(danger_warns)
                            val_error_type = "dangerous_pattern_error"
                        elif schema_context:
                            is_valid_schema, schema_err = validate_tables_and_columns(
                                current_sql, schema_context, dialect=self._dialect.sqlglot_dialect
                            )
                            if not is_valid_schema:
                                logger.warning("Schema table/column validation failed: %s", schema_err)
                                val_error = schema_err
                                val_error_type = "column_not_found" if "Column" in schema_err else "table_not_found"

                    if val_error:
                        val_stage["success"] = False
                        val_stage["failure_type"] = "sql_validation_error"
                        capture_sql_failure(
                            query_id="",
                            stage="sql_validation" if repair_attempt == 0 else "sql_repair",
                            failed_sql=current_sql,
                            raw_error=val_error,
                            error_type="sql_validation_error",
                            schema_tables=tables,
                        )
                        _log_pipeline_event(
                            "sql_safety_validation_failed",
                            {"sql": current_sql, "error": val_error, "error_type": val_error_type, "repair_attempt": repair_attempt},
                            query=query,
                        )

                # 1. Column validation
                col_reg = self.column_registry
                if not val_error and col_reg:
                    validation = col_reg.validate_columns(current_sql)
                    if not validation.is_valid:
                        logger.warning("Column validation failed (repair attempt %d): %s", repair_attempt, validation.errors)
                        val_error = "\n".join(validation.errors)
                        val_error_type = "column_hallucination"
                        val_stage["success"] = False
                        val_stage["failure_type"] = "sql_validation_error"
                        capture_sql_failure(
                            query_id="",
                            stage="sql_validation" if repair_attempt == 0 else "sql_repair",
                            failed_sql=current_sql,
                            raw_error=val_error,
                            error_type="sql_validation_error",
                            schema_tables=tables,
                        )
                        _log_pipeline_event(
                            "column_hallucination_caught",
                            {"sql": current_sql, "hallucinated": validation.hallucinated_columns,
                             "errors": validation.errors, "repair_attempt": repair_attempt},
                            query=query,
                        )

                # 2. Alias validation (on attempt 0)
                if not val_error and repair_attempt == 0 and col_reg:
                    alias_warnings = col_reg.validate_aliases(current_sql, query)
                    if alias_warnings:
                        logger.warning("Alias validation: %s", alias_warnings)
                        val_error = "\n".join(alias_warnings)
                        val_error_type = "alias_hallucination"
                        val_stage["success"] = False
                        val_stage["failure_type"] = "sql_validation_error"
                        capture_sql_failure(
                            query_id="",
                            stage="sql_validation",
                            failed_sql=current_sql,
                            raw_error=val_error,
                            error_type="sql_validation_error",
                            schema_tables=tables,
                        )
                        _log_pipeline_event(
                            "alias_hallucination_caught",
                            {"sql": current_sql, "warnings": alias_warnings},
                            query=query,
                        )

                # 3. Semantic validation
                if not val_error:
                    val_results = self._result_validator.validate_query(
                        sql=current_sql,
                        tables_involved=tables,
                        has_date_filter=("WHERE" in current_sql.upper() and any(k in current_sql.upper() for k in ["DATE", "YEAR", "CREATED_AT", "UPDATED_AT", "MONTH"])),
                        has_aggregation=any(f in current_sql.upper() for f in ["SUM(", "AVG(", "COUNT(", "MAX(", "MIN("]),
                    )
                    crit_errors = [r.message for r in val_results if r.severity == ValidationSeverity.CRITICAL and not r.passed]
                    if crit_errors:
                        logger.warning("Semantic validation critical errors (repair attempt %d): %s", repair_attempt, crit_errors)
                        val_error = "\n".join(crit_errors)
                        val_error_type = "semantic_validation_error"
                        val_stage["success"] = False
                        val_stage["failure_type"] = "sql_validation_error"
                        capture_sql_failure(
                            query_id="",
                            stage="sql_validation" if repair_attempt == 0 else "sql_repair",
                            failed_sql=current_sql,
                            raw_error=val_error,
                            error_type="sql_validation_error",
                            schema_tables=tables,
                        )
                        _log_pipeline_event(
                            "semantic_validation_failed",
                            {"sql": current_sql, "errors": crit_errors, "repair_attempt": repair_attempt},
                            query=query,
                        )

                # 4. AST safety validation
                if not val_error and not self._is_safe_read_query(current_sql):
                    logger.warning("Unsafe SQL generated: %s", current_sql)
                    val_stage["success"] = False
                    val_stage["failure_type"] = "sql_validation_error"
                    capture_sql_failure(
                        query_id="",
                        stage="sql_validation" if repair_attempt == 0 else "sql_repair",
                        failed_sql=current_sql,
                        raw_error=f"Unsafe or unparseable SQL generated: {current_sql}",
                        error_type="sql_validation_error",
                        schema_tables=tables,
                    )
                    _log_pipeline_event(
                        "unsafe_sql_blocked",
                        {"sql": current_sql, "repair_attempt": repair_attempt},
                        query=query,
                    )
                    raise UnsafeQueryError(f"Unsafe or unparseable SQL generated: {current_sql}")

            # If validation failed, invoke Delta Repair if under attempt budget
            if val_error:
                if first_failed_sql is None:
                    first_failed_sql = current_sql
                    first_error = val_error

                if repair_attempt >= MAX_DELTA_REPAIR_ATTEMPTS:
                    logger.warning("Delta repair ceiling (%d attempts) reached on validation failure.", MAX_DELTA_REPAIR_ATTEMPTS)
                    break

                next_attempt = repair_attempt + 1
                repaired_sql = await attempt_delta_repair(
                    router=self._router,
                    failed_sql=current_sql,
                    error_message=val_error,
                    error_type=val_error_type or "sql_validation_error",
                    schema_context=schema_context,
                    user_intent=query,
                    attempt_number=next_attempt,
                )
                if not repaired_sql:
                    logger.warning("Delta repair attempt %d returned no SQL. Halting.", next_attempt)
                    break

                current_sql = enforce_soft_delete_filter(
                    repaired_sql,
                    detect_soft_delete_intent(query),
                    dialect=self._dialect.sqlglot_dialect,
                )
                continue

            # Validation succeeded -> Execute read-only query
            try:
                with timed_stage("sql_execution") as exec_stage:
                    rows = await run_readonly_query(current_sql, db_id=self.db_id)
                    is_zero_rows = len(rows) == 0
                    is_agg_zero = _is_aggregate_over_zero_rows(current_sql, rows, self._dialect.sqlglot_dialect)
                    is_empty_result = is_zero_rows or is_agg_zero
                    exec_stage["extra"] = {
                        "rows_returned": len(rows),
                        "empty_result": is_empty_result,
                        "repair_attempt": repair_attempt,
                    }
                    if is_empty_result:
                        exec_stage["failure_type"] = "empty_result"

                # Intelligent 0-row handling (Phase 11: gated behind zero_row_handling_enabled)
                if is_empty_result and is_feature_enabled("zero_row_handling_enabled"):
                    classification = classify_empty_result(current_sql, dialect=self._dialect.sqlglot_dialect)
                    with timed_stage("empty_result_handling") as erh_stage:
                        erh_stage["extra"] = {
                            "classification": classification,
                            "sql": current_sql,
                            "rows_returned": len(rows),
                            "repair_attempt": repair_attempt,
                        }
                        if classification == "valid_empty":
                            erh_stage["success"] = True
                            _log_pipeline_event(
                                "valid_empty_result",
                                {"sql": current_sql, "classification": "valid_empty", "rows_returned": len(rows)},
                                query=query,
                            )
                            # Valid empty: bypass retry/repair loop immediately, do NOT capture failure
                        elif classification == "suspicious_empty":
                            erh_stage["success"] = False
                            erh_stage["failure_type"] = "suspicious_zero_rows"
                            if repair_attempt < MAX_DELTA_REPAIR_ATTEMPTS:
                                logger.warning("Suspicious 0-row result on attempt %d: triggering Delta Repair.", repair_attempt)
                                _log_pipeline_event(
                                    "suspicious_empty_result_repair",
                                    {"sql": current_sql, "classification": "suspicious_empty", "repair_attempt": repair_attempt},
                                    query=query,
                                )
                                if first_failed_sql is None:
                                    first_failed_sql = current_sql
                                    first_error = "Query executed successfully but returned 0 rows (suspicious_empty)."

                                next_attempt = repair_attempt + 1
                                repaired_sql = await attempt_delta_repair(
                                    router=self._router,
                                    failed_sql=current_sql,
                                    error_message="Query executed successfully but returned 0 rows. Classification: suspicious_empty. Check JOIN conditions and filter logic.",
                                    error_type="suspicious_zero_rows",
                                    schema_context=schema_context,
                                    user_intent=query,
                                    attempt_number=next_attempt,
                                )
                                if repaired_sql and repaired_sql != current_sql:
                                    current_sql = repaired_sql
                                    continue

                # Result Sanity & Confidence Scoring
                self._result_validator.validate_results(rows)
                learned_matches = self._pattern_learner.get_patterns_for_query(query)
                conf = self._confidence_scorer.calculate(
                    pattern_matches=len(learned_matches),
                    validation_results=val_results,
                    reflexion_attempts=repair_attempt,
                    query_complexity={"join_count": max(0, len(tables) - 1), "subquery_depth": current_sql.upper().count("SELECT") - 1},
                )
                self.last_confidence_score = conf.final_score
                self.last_confidence_breakdown = conf

                if repair_attempt > 0 and first_failed_sql:
                    try:
                        self._pattern_learner.capture_success(
                            user_question=query,
                            original_cot="",
                            failed_sql=first_failed_sql,
                            error_message=first_error or "Previous attempt error",
                            fixed_sql=current_sql,
                            revised_cot=self.last_cot_plan or "",
                        )
                    except Exception as learn_err:
                        logger.debug("Failed to record learned pattern: %s", learn_err)

                self.last_query_status = "empty_result" if is_empty_result else "success"
                label = f"live_database ({', '.join(tables)})" if tables else "live_database"
                display_rows = _filter_display_rows(rows)
                formatted_table = _format_rows_as_markdown(display_rows, current_sql, is_agg_zero=is_agg_zero)
                display_headers = list(display_rows[0].keys()) if display_rows else []
                sql_payload = {
                    "query": current_sql,
                    "columns": display_headers,
                    "rows": _sanitize_rows(display_rows),
                    "row_count": len(rows),
                }
                self.last_sql_payload = sql_payload

                chunk = Chunk(
                    chunk_id="live_sql_001",
                    document_id="live_db",
                    chunk_type=ChunkType.SQL_RESULT,
                    content=formatted_table,
                    document_type=DocumentType.GENERAL,
                    source_file=label,
                    metadata={"sql_payload": sql_payload},
                )

                _log_pipeline_event(
                    "sql_success",
                    {"sql": current_sql, "row_count": len(rows), "tables": tables,
                     "repair_attempts": repair_attempt, "is_empty_result": is_empty_result,
                     "confidence_score": self.last_confidence_score},
                    query=query,
                )
                return [RetrievedChunk(chunk=chunk, score=1.0, retrieval_method="text-to-sql")]

            except UnsafeQueryError as e:
                logger.warning(f"Blocked unsafe SQL query: {e}")
                self.last_query_status = "failed"
                return []
            except Exception as e:
                logger.error("SQL Execution failed on attempt %d: %s", repair_attempt + 1, e)
                capture_sql_failure(
                    query_id="",
                    stage="sql_execution" if repair_attempt == 0 else "sql_repair",
                    failed_sql=current_sql,
                    raw_error=str(e),
                    error_type=classify_error(e),
                    schema_tables=tables,
                )
                _log_pipeline_event(
                    "execution_error_caught",
                    {"sql": current_sql, "error": str(e), "repair_attempt": repair_attempt + 1},
                    query=query,
                )
                if first_failed_sql is None:
                    first_failed_sql = current_sql
                    first_error = str(e)

                if repair_attempt >= MAX_DELTA_REPAIR_ATTEMPTS:
                    logger.warning("Delta repair ceiling (%d attempts) reached on execution error.", MAX_DELTA_REPAIR_ATTEMPTS)
                    break

                next_attempt = repair_attempt + 1
                repaired_sql = await attempt_delta_repair(
                    router=self._router,
                    failed_sql=current_sql,
                    error_message=str(e),
                    error_type=classify_error(e),
                    schema_context=schema_context,
                    user_intent=query,
                    attempt_number=next_attempt,
                )
                if not repaired_sql:
                    logger.warning("Delta repair attempt %d returned no SQL after exec error. Halting.", next_attempt)
                    break

                current_sql = repaired_sql
                continue

        logger.warning("SQL generation failed after Delta Repair attempts. Returning empty results.")
        self.last_query_status = "failed"
        _log_pipeline_event("retry_exhausted", {"last_error": first_error}, query=query)
        return []

    @classmethod
    def clear_schema_cache(cls, db_id: str | None = None) -> None:
        """Clear the cached full schema and column registry (e.g. after schema sync)."""
        if db_id is None:
            cls._full_schema_cache.clear()
            cls._column_registry.clear()
        else:
            cls._full_schema_cache.pop(db_id, None)
            cls._column_registry.pop(db_id, None)

    async def _fetch_full_schema(self) -> str:
        """Fetch the full, un-truncated DB schema to initialize the ColumnRegistry."""
        if self.db_id in SQLRetriever._full_schema_cache:
            return SQLRetriever._full_schema_cache[self.db_id]

        try:
            rows = await run_readonly_query(self._dialect.schema_query, max_rows=20000, db_id=self.db_id)
            schema = format_schema_rows(self._dialect, rows)

            if self._dialect.fk_query:  # MySQL / PostgreSQL: one query covers all FKs
                fk_rows = await run_readonly_query(self._dialect.fk_query, max_rows=20000, db_id=self.db_id)
            elif self._dialect.key == Engine.SQLITE:
                fk_rows = await fetch_sqlite_foreign_keys(db_id=self.db_id)
            else:
                fk_rows = []

            fk_text = format_fk_rows(fk_rows)
            full_schema = schema + ("\n\n" + fk_text if fk_text else "")

            # Only cache and build registry if the schema was successfully retrieved and non-empty.
            # An empty string from a missing/unready DB must never be cached as permanent truth.
            if full_schema.strip():
                SQLRetriever._full_schema_cache[self.db_id] = full_schema
                try:
                    SQLRetriever._column_registry[self.db_id] = ColumnRegistry(
                        full_schema, self._dialect.sqlglot_dialect
                    )
                except Exception as reg_err:
                    logger.warning("Failed to build column registry for %s: %s", self.db_id, reg_err)

            return full_schema
        except Exception as e:
            logger.error("Failed to fetch full schema: %s", e)
            return ""

    async def _get_schema(self, query: str) -> str:
        """Fetch relevant DB schema chunks for the prompt using Schema RAG.
        
        If vector_store is missing or fails, falls back to an intelligent, token-bounded schema.
        """
        # Ensure the full schema is cached and registry is built.
        full_schema = await self._fetch_full_schema()

        if not self._vector_store or not self._embeddings:
            return _build_scoped_schema_fallback(full_schema, query)

        try:
            dense_vec, sparse_vec = await self._embeddings.embed_query(query)
            chunks = await self._vector_store.search_hybrid(
                query_vector=dense_vec,
                sparse_vector=sparse_vec,
                query_text=query,
                top_k=4,
                filters={
                    "chunk_type": ChunkType.SQL_SCHEMA.value,
                    "db_id": self.db_id,
                },
            )

            # Transition rule & isolation defense: ensure retrieved chunks strictly belong to self.db_id
            filtered_chunks = []
            for c in chunks:
                chunk_obj = c.chunk
                c_db_id = getattr(chunk_obj, "db_id", None) or chunk_obj.metadata.get("db_id")
                c_doc_id = chunk_obj.document_id
                if c_db_id:
                    if c_db_id == self.db_id:
                        filtered_chunks.append(c)
                elif c_doc_id == f"schema:{self.db_id}":
                    filtered_chunks.append(c)
                elif c_doc_id == "live_db_schema" and self.db_id == DEFAULT_DB_ID:
                    # Legacy chunks (document_id "live_db_schema", no db_id) accepted ONLY for erp_main until re-synced
                    filtered_chunks.append(c)
            chunks = filtered_chunks
            
            if not chunks:
                logger.warning("Schema RAG returned 0 chunks. Falling back to scoped schema.")
                return _build_scoped_schema_fallback(full_schema, query)
                
            # Combine the retrieved CREATE TABLE statements
            retrieved_schema = "\n\n".join(chunk.chunk.content for chunk in chunks)
            retrieved_tables = _extract_schema_table_names(retrieved_schema)

            # Seed anchor tables from matched glossary terms & domain concepts
            glossary_text = _build_column_glossary_for_query(query)
            glossary_tables = set(re.findall(r'\b([a-zA-Z0-9_]+)\.[a-zA-Z0-9_]+', glossary_text))

            query_lower = query.lower()
            if any(k in query_lower for k in ["order", "sales", "bought", "buying", "spent", "spending", "buyer", "customer", "client", "revenue", "turnover", "po number", "party po", "customer po", "po_no"]):
                glossary_tables.update(["sales_order", "sales_order_products", "party", "product", "financial_year"])
            if any(k in query_lower for k in ["purchase", "supplier", "vendor", "procure", "inward", "raw material"]):
                glossary_tables.update(["purchase", "purchase_products", "party", "product", "financial_year"])
            if any(k in query_lower for k in ["stock", "inventory", "warehouse", "carton", "on hand"]):
                glossary_tables.update(["stock", "product", "product_color", "category", "product_type", "sales_order", "party", "packagings", "warehouse"])
            if any(k in query_lower for k in ["location", "location_code", "stored", "storage", "where is", "bin", "rack"]):
                glossary_tables.update(["packagings", "warehouse", "product"])
            if any(k in query_lower for k in ["production", "manufacture", "batch", "machine", "yield", "output", "plant", "floor", "apq", "ppq"]):
                glossary_tables.update(["production", "actual_production", "product", "product_color", "category", "product_type", "financial_year", "machine"])
            if any(k in query_lower for k in ["color", "colour"]):
                glossary_tables.update(["product_color", "product", "production", "stock"])
            if any(k in query_lower for k in ["unit", "uom", "measurement", "unit of measure"]):
                glossary_tables.update(["unit", "product"])
            if any(k in query_lower for k in ["machine", "equipment"]):
                glossary_tables.update(["machine", "production", "product"])
            if any(k in query_lower for k in ["packaging", "packing", "carton verify"]):
                glossary_tables.update(["packagings", "production", "product", "product_color", "warehouse"])
            if any(k in query_lower for k in ["financial year", "fiscal year", "current financial", "fyear", "financial_year"]):
                glossary_tables.update(["financial_year"])
            if any(k in query_lower for k in ["finished good", "product type", "raw material"]):
                glossary_tables.update(["product_type", "product", "category"])
            if any(k in query_lower for k in ["lead", "inquiry", "inquiries", "prospect", "followup", "deal", "pipeline"]):
                glossary_tables.update(["lead", "lead_history", "users", "party"])
            if any(k in query_lower for k in ["dispatch", "delivery", "challan", "shipment", "transporter", "vehicle", "driver", "dc", "dc_no", "dc no", "dc number", "due date", "so_due_date"]):
                glossary_tables.update(["delivery_challan", "delivery_challan_products", "party", "sales_order", "financial_year"])
            if any(k in query_lower for k in ["invoice", "invoice count", "invoice_no", "invoices", "pi", "pi_no", "gt/"]):
                glossary_tables.update(["purchase", "party", "proforma", "financial_year", "sales_order", "stock"])
            if any(k in query_lower for k in ["category", "categories"]):
                glossary_tables.update(["category", "product", "product_type"])
            if any(k in query_lower for k in ["po", "po_no", "po number", "po numbers", "party po", "customer po"]):
                glossary_tables.update(["sales_order", "purchase", "party", "product", "financial_year"])
            if any(k in query_lower for k in ["proforma", "bill", "gst", "tax", "quotation"]):
                glossary_tables.update(["proforma", "quotation", "party", "financial_year"])
            if any(k in query_lower for k in ["balance", "account", "ledger", "credit", "debit", "opening balance", "payment", "receipt"]):
                glossary_tables.update(["party", "financial_year", "party_opening_balance", "sales_order", "receipt"])
            if any(k in query_lower for k in ["adjustment", "adjust", "stock-out", "stock out", "stockout", "stock-in", "stock in", "stockin"]):
                glossary_tables.update(["stock_adjustment", "product", "category", "product_color", "unit"])
                if any(k in query_lower for k in ["year", "fiscal", "current", "fyear", "annual"]):
                    glossary_tables.add("financial_year")

            full_ddls = _extract_table_ddl_map(full_schema) if full_schema else {}
            candidate_list: list[dict[str, Any]] = []
            seen_tables: set[str] = set()

            # Priority 1: Domain anchor & glossary tables first
            anchor_extra = []
            for g_table in sorted(glossary_tables):
                if g_table in full_ddls:
                    if g_table not in retrieved_tables:
                        anchor_extra.append(full_ddls[g_table])
                        retrieved_tables.add(g_table)
                    if g_table not in seen_tables:
                        seen_tables.add(g_table)
                        candidate_list.append({
                            "table_name": g_table,
                            "ddl": full_ddls[g_table],
                            "source": "domain_anchor",
                        })

            # Priority 2: Vector RAG chunks
            for chunk in chunks:
                tbls = _extract_schema_table_names(chunk.chunk.content)
                for tbl in tbls:
                    if tbl not in seen_tables and (not full_ddls or tbl in full_ddls):
                        seen_tables.add(tbl)
                        candidate_list.append({
                            "table_name": tbl,
                            "ddl": chunk.chunk.content,
                            "source": "vector_rag",
                        })

            if anchor_extra:
                retrieved_schema += "\n\n-- Domain Anchor & Glossary Tables:\n" + "\n\n".join(anchor_extra)

            # 1-hop graph expansion: add directly connected neighbor tables if missing
            neighbors = _get_1hop_neighbors(retrieved_tables)
            needed_neighbors = neighbors - retrieved_tables

            if needed_neighbors and full_ddls:
                # Rank neighbors by how many active tables they connect to (bridge priority)
                raw_rels = _get_raw_relationships(self.db_id)
                conn_scores = {}
                for r in raw_rels:
                    frm = (r.get("from_table") or "").lower()
                    to = (r.get("to_table") or "").lower()
                    if frm in retrieved_tables and to in needed_neighbors:
                        conn_scores[to] = conn_scores.get(to, 0) + 1
                    if to in retrieved_tables and frm in needed_neighbors:
                        conn_scores[frm] = conn_scores.get(frm, 0) + 1

                ranked_neighbors = sorted(needed_neighbors, key=lambda t: conn_scores.get(t, 0), reverse=True)
                added = 0
                extra_ddls = []
                for n_table in ranked_neighbors:
                    if n_table in full_ddls and added < 4:
                        extra_ddls.append(full_ddls[n_table])
                        added += 1
                    if n_table in full_ddls and n_table not in seen_tables:
                        seen_tables.add(n_table)
                        candidate_list.append({
                            "table_name": n_table,
                            "ddl": full_ddls[n_table],
                            "source": "graph_expansion",
                        })
                if extra_ddls:
                    retrieved_schema += "\n\n-- Directly connected related tables:\n" + "\n\n".join(extra_ddls)

            # --- Phase 8: Dynamic Schema Token Budget Selection & Shadow Mode ---
            selected, dropped = select_schema_within_budget(
                candidate_list,
                token_budget=DEFAULT_SCHEMA_TOKEN_BUDGET,
                id_key="table_name",
            )

            original_table_count = len(candidate_list)
            budgeted_table_count = len(selected)
            dropped_tables = [c["table_name"] if isinstance(c, dict) else str(c) for c in dropped]
            budgeted_schema = "\n\n".join(c["ddl"] if isinstance(c, dict) else str(c) for c in selected)
            estimated_tokens = estimate_schema_tokens(budgeted_schema)
            flag_enabled = is_feature_enabled("token_budget_enabled")
            stage_name = "schema_budget_applied" if flag_enabled else "schema_budget_shadow"

            log_telemetry(
                query_id="",
                stage=stage_name,
                input_tokens=estimated_tokens,
                extra={
                    "original_table_count": original_table_count,
                    "budgeted_table_count": budgeted_table_count,
                    "estimated_tokens": estimated_tokens,
                    "dropped_tables": dropped_tables,
                    "token_budget_enabled": flag_enabled,
                },
            )

            if is_feature_enabled("schema_compaction_enabled"):
                dialect_key = self._dialect.sqlglot_dialect if hasattr(self, "_dialect") and self._dialect else None
                compact_ddls = [
                    compact_ddl(c["ddl"] if isinstance(c, dict) else str(c), dialect=dialect_key)
                    for c in selected
                ]
                raw_ddls = [c["ddl"] if isinstance(c, dict) else str(c) for c in selected]
                join_hints = extract_join_hints(raw_ddls, dialect=dialect_key)

                compacted_schema = "\n\n".join(compact_ddls)
                if join_hints:
                    compacted_schema += "\n\n" + join_hints

                before_tokens = estimate_schema_tokens(budgeted_schema)
                after_tokens = estimate_schema_tokens(compacted_schema)

                log_telemetry(
                    query_id="",
                    stage="schema_compaction_applied",
                    input_tokens=after_tokens,
                    extra={
                        "before_tokens": before_tokens,
                        "after_tokens": after_tokens,
                        "token_savings": max(0, before_tokens - after_tokens),
                        "table_count": len(selected),
                        "has_join_hints": bool(join_hints),
                    },
                )
                return compacted_schema

            if flag_enabled:
                return budgeted_schema
            return retrieved_schema
            
        except Exception as e:
            logger.error("Schema RAG search failed: %s", e)
            return _build_scoped_schema_fallback(full_schema, query)

    async def _generate_sql(self, query: str, schema: str, last_error: str | None = None) -> str:
        """Prompt the reasoning LLM to generate SQL."""
        import datetime
        current_date_str = datetime.date.today().isoformat()
        intent = extract_analytical_intent(query)
        intent_summary_lines = []
        if intent["metrics"]:
            intent_summary_lines.append(f"- Metrics: {', '.join(intent['metrics'])}")
        if intent["dimensions"]:
            intent_summary_lines.append(f"- Dimensions: {', '.join(intent['dimensions'])}")
        if intent["filters"]:
            intent_summary_lines.append(f"- Filters: {', '.join(intent['filters'])}")
        if intent["time_period"]:
            intent_summary_lines.append(f"- Time Period: {intent['time_period']}")
        if intent["aggregation"]:
            intent_summary_lines.append(f"- Aggregation: {intent['aggregation']}")
        if intent["limit"]:
            intent_summary_lines.append(f"- Limit: {intent['limit']} (Sorting: {intent['sorting'] or 'DESC'})")
        if intent.get("temporal_scope") == "CURRENT_YEAR":
            intent_summary_lines.append(
                "- Temporal Scope: CURRENT FINANCIAL YEAR (Join financial_year and filter `financial_year.current_year = 'Y'`)"
            )
        elif intent.get("temporal_scope") == "ALL_TIME":
            intent_summary_lines.append(
                "- Temporal Scope: ALL-TIME / CUMULATIVE (DO NOT filter by `financial_year.current_year = 'Y'`. Sum/aggregate across ALL available years!)"
            )

        soft_intent = intent.get("soft_delete_intent", "ACTIVE_ONLY")
        if soft_intent == "DELETED_ONLY":
            intent_summary_lines.append(
                "- Record Status / Soft-Delete Scope: EXPLICIT DELETED RECORDS (User explicitly requested deleted/removed records. Filter specifically for deleted records using `WHERE alias.deleted_at IS NOT NULL` or omit `deleted_at IS NULL`. DO NOT exclude deleted records!)"
            )
        elif soft_intent == "INCLUDE_ARCHIVED":
            intent_summary_lines.append(
                "- Record Status / Soft-Delete Scope: AUDIT / HISTORY / ARCHIVED (User explicitly requested history, audit trail, or archived records. DO NOT add `deleted_at IS NULL` filter! Allow all records—both active and deleted—to be returned.)"
            )
        else:
            intent_summary_lines.append(
                "- Record Status / Soft-Delete Scope: ACTIVE OPERATIONAL (Default rule. Filter out soft-deleted records using `WHERE alias.deleted_at IS NULL` on all tables with a deleted_at column.)"
            )

        intent_section = (
            "\nExtracted Business Intent:\n" + "\n".join(intent_summary_lines) + "\n"
            if intent_summary_lines
            else ""
        )
        
        schema_tables = _extract_schema_table_names(schema)
        behavioral_atlas_text = _build_behavioral_atlas_for_query(schema_tables, query)
        column_glossary = _build_column_glossary_for_query(query)

        system_prompt = f"""You are Antarkosh, an expert Enterprise Business Intelligence Agent for {self._dialect.name}.
Your goal is to translate the business question into a valid, executable, read-only {self._dialect.name} SELECT query.

IMPORTANT: Output ONLY the final SQL query in a ```sql ... ``` code block. Strictly NO introductory explanations, NO conversational prose, NO step-by-step bullet points.

Rules:
- Read-Only: SELECT statements only.
- Mixed / Multi-part queries: If the user question contains both document/system questions (e.g. OCR, RAG architecture, policies, tax rates, general docs) and database questions (e.g. products, machines, orders, stock, production), IGNORE the document/system questions and generate SQL ONLY for the database portion! Only respond with NO_SQL if NO part of the question relates to the database schema.
- Dynamic Soft-Delete & Record Status:
  * Default Rule (Active Operational Data): For standard operational queries, or when asking for 'active', 'current', 'present', 'live', or 'existing' data, ALWAYS filter out soft-deleted records by adding `alias.deleted_at IS NULL` on all tables with a `deleted_at` column.
  * Exception Rule (Explicit Deleted Records): If the user query explicitly mentions 'deleted', 'removed', 'dropped', or 'gone', DO NOT add the `deleted_at IS NULL` filter. Instead, filter specifically for deleted records using `WHERE alias.deleted_at IS NOT NULL` (or omit `deleted_at IS NULL` for joined lookup entities).
  * Exception Rule (Audit / History / Archived Data): If the user query explicitly mentions 'archived', 'history', 'audit', or 'past records', DO NOT add the `deleted_at IS NULL` filter. Allow all records (both active and deleted) to be returned.
- Casting: Use CAST(col AS DECIMAL(10,2)) for numeric operations on VARCHAR columns (e.g. stock.qty).
- Aliases: Use descriptive aliases (e.g. AS customer_name, AS total_revenue). Never return raw IDs without names.
- Status Flags: Active='Y', Inactive='N'. Stock booked='B', dispatched='D'.
- Customer vs Supplier: In party table, join to sales_order for Customers, or purchase for Suppliers.
- Current Date: {current_date_str} (Use for relative date calculations like 'this year', 'last month').
- Temporal Scope & Financial Year Filtering:
  * ONLY add `financial_year.current_year = 'Y'` if the user query contains explicit temporal markers such as 'current', 'this year', 'latest', 'active', or 'ongoing'.
  * Negative Constraint: If the query asks for 'total', 'all', 'history', or implies a cumulative sum without a time qualifier (e.g. 'quantity adjusted', 'total sales', 'overall quantity'), DO NOT filter by current_year. Sum across all available years.
  * Ambiguity Handling: If the temporal intent is ambiguous between current vs all-time, PREFER the broader scope (all-time). NEVER silently narrow cumulative or aggregate queries to the current financial year.

{intent_section}
Schema:
{schema}
"""
        system_prompt += "\n\n" + self._get_scoped_readability_rules(query, schema_tables)

        if behavioral_atlas_text:
            system_prompt += (
                "\n\n=== BEHAVIORAL SCHEMA ATLAS & COGNITIVE ONTOLOGY ===\n"
                f"{behavioral_atlas_text}"
            )

        scoped_rels = _format_scoped_relationships(schema_tables, query) if schema_tables else ""
        rels_to_inject = scoped_rels or self._relationships
        if rels_to_inject:
            system_prompt += (
                f"\n\nTable relationships:\n{rels_to_inject}"
            )

        if column_glossary:
            system_prompt += (
                "\n\nColumn mapping (use these exact paths — do NOT invent columns):\n"
                f"{column_glossary}"
            )
        if self._dialect.date_functions:
            system_prompt += (
                f"\n\nDate/time syntax for {self._dialect.name}:\n"
                f"{self._dialect.date_functions}"
            )
        if hasattr(self, "_pattern_learner") and self._pattern_learner:
            learned_patterns = self._pattern_learner.get_patterns_for_query(query)
            if learned_patterns:
                # SlimSQL Task 4: Cap to top 1 canonical pattern to minimize tokens
                pattern = learned_patterns[0]
                pattern_text = f"- Scenario: {pattern.business_scenario}\n  Reasoning: {pattern.cot_reasoning_snippet}\n  Template: `{pattern.sql_structure_template}`"
                system_prompt += f"\n\n=== RELEVANT LEARNED SQL PATTERN ===\n{pattern_text}"

        if last_error:
            system_prompt += f"\n\nWARNING: Your previous attempt failed with this error: {last_error}\nPlease fix the SQL query and try again."
        
        budget_ctrl = get_or_create_budget_controller()
        initial_calls = budget_ctrl.llm_calls if budget_ctrl else 0
        try:
            response = await self._router.chat(
                task="reasoning",
                messages=[
                    {"role": "system", "content": system_prompt},
                    {"role": "user", "content": query},
                ],
                max_tokens=768
            )
            if budget_ctrl and budget_ctrl.llm_calls == initial_calls:
                budget_ctrl.record_call(tokens_used=250, is_repair=False)
            
            raw = (response or "").strip()

            # Abstention: the model may decorate the sentinel ("NO_SQL.",
            # "NO_SQL - the schema has no ...", or fenced). Any reply whose first
            # token is NO_SQL is an abstain, not a query to run.
            if _ABSTAIN_RE.match(raw):
                return ""

            # Extract structured plan and clean SQL
            cot_plan, sql = extract_cot_and_sql(raw)
            self.last_cot_plan = cot_plan
            if not sql or _ABSTAIN_RE.match(sql):
                return ""
            if not any(sql.strip().upper().startswith(kw) for kw in ("SELECT", "WITH", "SHOW", "DESCRIBE", "EXPLAIN")):
                return ""

            # Safeguard 1: Syntactic AST Check (Validate true SQL syntax)
            try:
                ast_check = sqlglot.parse_one(sql, read=self._dialect.sqlglot_dialect)
                if not isinstance(ast_check, (exp.Select, exp.Union)):
                    return ""
            except Exception as ast_err:
                logger.warning("Extracted SQL failed syntax parse: %s", ast_err)
                return ""

            # Safeguard 2: Join Complexity Heuristic Check (Quality Gate)
            try:
                tables_in_sql = list(ast_check.find_all(exp.Table))
                if len(tables_in_sql) >= 3:
                    for join_node in ast_check.find_all(exp.Join):
                        if not join_node.args.get("on") and not join_node.args.get("using"):
                            logger.warning("Multi-table join missing ON condition in JOIN — routing to Delta Repair.")
                            repaired = await attempt_delta_repair(
                                sql=sql,
                                error_message="Multi-table join missing explicit ON condition connecting tables.",
                                schema=schema,
                                dialect=self._dialect.name,
                                router=self._router,
                            )
                            if repaired:
                                sql = repaired
            except Exception as ast_e:
                logger.debug("AST join check passed/skipped: %s", ast_e)

            # Safeguard 3: Mandatory Soft-Delete Filtering (Defense-in-Depth)
            soft_intent = detect_soft_delete_intent(query)
            sql = enforce_soft_delete_filter(
                sql=sql,
                intent=soft_intent,
                dialect=self._dialect.sqlglot_dialect,
            )
            return sql
        except (TokenBudgetExceededError, QueryBudgetExceededError) as budget_err:
            err_count = getattr(budget_err, "count", budget_ctrl.get_current_usage() if budget_ctrl else 8000)
            err_limit = getattr(budget_err, "limit", budget_ctrl.max_tokens if budget_ctrl else 8000)
            logger.warning(
                "Budget hit at %d tokens (limit: %d). Increasing limit by +1K and attempting compressed retry...",
                err_count,
                err_limit,
            )
            if budget_ctrl:
                budget_ctrl.increase_limit(1000)

            try:
                compressed_prompt = (
                    f"You are an expert SQL generator for {self._dialect.name}. "
                    "Output ONLY the final SQL query in a ```sql ... ``` code block. "
                    "Strictly NO explanations, NO markdown prose, NO chain-of-thought.\n\n"
                    f"Schema:\n{schema}"
                )
                response = await self._router.chat(
                    task="reasoning",
                    messages=[
                        {"role": "system", "content": compressed_prompt},
                        {"role": "user", "content": query},
                    ],
                    max_tokens=1024,
                )
                raw = (response or "").strip()
                if raw and not _ABSTAIN_RE.match(raw):
                    _, sql = extract_cot_and_sql(raw)
                    if sql and not _ABSTAIN_RE.match(sql):
                        logger.info("Compressed SQL retry succeeded after token budget cutoff.")
                        soft_intent = detect_soft_delete_intent(query)
                        sql = enforce_soft_delete_filter(
                            sql=sql,
                            intent=soft_intent,
                            dialect=self._dialect.sqlglot_dialect,
                        )
                        return sql
            except Exception as retry_err:
                logger.error("Compressed SQL retry failed after budget cutoff: %s", retry_err)
            self.last_infra_error = "token_budget_exceeded"
            return ""
        except Exception as e:
            logger.error(f"Failed to generate SQL: {e}")
            # Distinguish an infrastructure outage (every provider for the
            # 'reasoning' task was unreachable) from an ordinary generation
            # failure. The former means the DB was never actually consulted, so
            # the pipeline should say the model was unavailable rather than
            # implying the data doesn't exist.
            if "All providers exhausted" in str(e):
                self.last_infra_error = str(e)
            return ""

    # Functions that read/write files, execute code, or cause DoS / lock contention.
    # Each is still a "SELECT" or expression to sqlglot, so AST inspection is required.
    _DANGEROUS_FUNCTIONS = frozenset({
        "load_file", "loadfile",              # MySQL: read an arbitrary file
        "sys_eval", "sys_exec", "sys_get",    # MySQL sys UDFs: shell execution
        "lo_import", "lo_export",             # Postgres large-object file I/O
        "benchmark",                          # MySQL: CPU exhaustion DoS
        "sleep",                              # MySQL/Postgres: thread sleep DoS
        "get_lock", "release_lock",           # MySQL: advisory lock contention DoS
        "release_all_locks",
        "is_free_lock", "is_used_lock",
    }) | _SHARED_DANGEROUS_FUNCTIONS          # + Postgres/MSSQL/Oracle names; one shared list, no drift

    @classmethod
    def _get_scoped_readability_rules(cls, query: str, schema_tables: list[str]) -> str:
        """Dynamically scope readability rules to only those relevant to the query & schema tables,
        reducing SQL prompt tokens by 60% while preserving all critical schema nuances.
        """
        q = query.lower()
        tables = set(t.lower() for t in schema_tables)

        soft_intent = detect_soft_delete_intent(query)
        if soft_intent == "DELETED_ONLY":
            soft_delete_rule = (
                "- Dynamic Soft-Delete Rule (EXPLICIT DELETED QUERY): The user is explicitly requesting DELETED or REMOVED records! "
                "DO NOT add `alias.deleted_at IS NULL`. Instead, add `WHERE alias.deleted_at IS NOT NULL` on the target table(s) with deleted_at. "
                "This strictly overrides any default `deleted_at IS NULL` rules or example templates below."
            )
        elif soft_intent == "INCLUDE_ARCHIVED":
            soft_delete_rule = (
                "- Dynamic Soft-Delete Rule (AUDIT / HISTORY QUERY): The user is querying audit history, past records, or archived data! "
                "DO NOT add `alias.deleted_at IS NULL`. Return ALL records (both active and deleted) without soft-delete restriction. "
                "This strictly overrides any default `deleted_at IS NULL` rules or example templates below."
            )
        else:
            soft_delete_rule = (
                "- Dynamic Soft-Delete Rule: For standard operational queries (active/current data), ALWAYS filter soft-deleted records: "
                "WHERE alias.deleted_at IS NULL on all tables with deleted_at."
            )

        rules: list[str] = [
            "Core SQL Generation & Schema Mapping Protocol:",
            "- Primary Key & Column Projection: For non-aggregate record queries, ALWAYS include the primary key column (e.g. table.id AS id) as the first selected column to serve as an anchor reference point, unless explicitly excluded by the user. Do not alias it confusingly (use alias.id AS id, not alias.id AS something_id unless requested). Follow the ID with only the specific columns or metrics asked by the user. Never bloat results with unsolicited columns (e.g. status, created_at, deleted_at).",
            "- Deduplication (DISTINCT): When looking up entity names, machine names, warehouses, or customer/vendor names from transactional or production tables (e.g. 'which machines produce product X', 'machines for product Y'), ALWAYS use SELECT DISTINCT (e.g. SELECT DISTINCT m.machine_name) or GROUP BY so that all unique entities appear within the row limit instead of repeating the same entity multiple times.",
            "- SELECT read-only queries only. Never return raw ID columns without their human-readable name (use AS descriptive_alias).",
            soft_delete_rule,
            "- Status flags: party.status, product.status, category.status use 'Y'/'N'. Stock booked='B', dispatched='D'.",
            "- Fuzzy LIKE Filtering: Always filter descriptive text columns (categories, products, colors, names) using `LIKE '%<term>%'` rather than strict `=`. For categories with spelling variations like 'CHANGABLE PACK', match `c.category_name LIKE '%CHANG%PACK%'` (the database category is 'CHANGEABLE PACK').",
            "- Temporal Scope & Financial Year Filtering: ONLY add `financial_year.current_year = 'Y'` if the user query contains explicit temporal markers such as 'current', 'this year', 'latest', 'active', or 'ongoing'. If the query asks for 'total', 'all', 'history', or implies a cumulative sum without a time qualifier (e.g. 'quantity adjusted', 'total sales', 'overall quantity'), DO NOT filter by current_year. Sum across all available years. When the user DOES explicitly request the current financial year, NEVER filter using `YEAR(date) = YEAR(CURDATE())`; ALWAYS join `financial_year fy ON t.financial_id = fy.id` (or `WHERE t.financial_id = (SELECT id FROM financial_year WHERE current_year = 'Y')`) with `fy.current_year = 'Y'`."
        ]

        # Machine & Product Production
        if (
            "machine" in tables
            or "production" in tables
            or "actual_production" in tables
            or any(k in q for k in ["machine", "produce", "production", "batch", "apq", "ppq"])
        ):
            rules.append(
                "- Production Quantity & Batches: In the `production` table, the primary production/batch quantity is stored in `production.qty`. "
                "When asked for the production quantity, batch quantity, or quantity produced for a batch or product, ALWAYS select `production.qty AS production_quantity` (or `SUM(prd.qty)`). "
                "NEVER select `actual_production.apq` as the default production quantity, because `actual_production.apq` is unpopulated or 0 for many batches (which causes queries to return 0), while `production.qty` contains the true quantity. "
                "Only query `actual_production.apq` if the user explicitly asks for 'actual production quantity' or 'APQ' compared to planned targets."
            )
            rules.append(
                "- Machine & Product Production: Product names/codes (e.g. 'CAP03', 'CHP06070110-INNER') are stored in `product.product_name` (NEVER in `production.batch_no` or `stock.batch_no`). "
                "To find which machine was used to create or produce a product, ALWAYS join: `production prd JOIN product p ON prd.product_id = p.id JOIN machine m ON prd.machine_id = m.id WHERE p.product_name LIKE '%<product_name>%' AND prd.deleted_at IS NULL AND m.deleted_at IS NULL`. Return `SELECT DISTINCT m.machine_name`."
            )
        if any(k in q for k in ["invoice", "gt/", "pi_no", "pi number", "purchase invoice"]):
            if soft_intent == "DELETED_ONLY":
                rules.append(
                    "- Invoices & Purchase Invoices (PI) [DELETED RECORDS]: Purchase invoice numbers are stored in `purchase.pi_no` (and invoices in `stock` where `stock_type = 'PI'`). "
                    "For DELETED invoices, query `purchase pur JOIN party p ON pur.party_id = p.id WHERE pur.deleted_at IS NOT NULL AND p.deleted_at IS NULL` (or `stock s JOIN party p ON s.party_id = p.id WHERE s.stock_type = 'PI' AND s.deleted_at IS NOT NULL AND p.deleted_at IS NULL`). "
                    "DO NOT filter `pur.deleted_at IS NULL` or `s.deleted_at IS NULL`!"
                )
            elif soft_intent == "INCLUDE_ARCHIVED":
                rules.append(
                    "- Invoices & Purchase Invoices (PI) [HISTORY/AUDIT]: Query `purchase pur JOIN party p ON pur.party_id = p.id` (or `stock s JOIN party p ON s.party_id = p.id WHERE s.stock_type = 'PI'`) without `deleted_at IS NULL` on invoice tables to include all historical records."
                )
            else:
                rules.append(
                    "- Invoices & Purchase Invoices (PI): Purchase invoice numbers (e.g. 'GT/0091', 'PI-...') are stored in the `purchase` table with column `purchase.pi_no`. "
                    "To find the party or details for an invoice like 'GT/0091', ALWAYS query: `purchase pur JOIN party p ON pur.party_id = p.id WHERE pur.pi_no LIKE '%<invoice_no>%' AND pur.deleted_at IS NULL AND p.deleted_at IS NULL`. Return `p.party_name AS customer_or_supplier_name`."
                )

        # Product Units of Measure
        if "unit" in tables or any(k in q for k in ["unit", "uom", "measurement"]):
            rules.append(
                "- Product Units of Measure: The unit table contains unit definitions ('Pcs', 'Kg', 'Nos', etc.) and NEVER contains product names. "
                "To find the unit for a product (e.g. 'CAP03'), ALWAYS query: `product p JOIN unit u ON p.unit_id = u.id WHERE p.product_name LIKE '%<product>%' AND p.deleted_at IS NULL AND u.deleted_at IS NULL`. "
                "Return `p.product_name` and `u.unit_name AS unit_of_measure`. Never search `unit.unit_name` for product names."
            )

        # Product Color Linkage
        if "product_color" in tables or any(k in q for k in ["color", "colour"]):
            rules.append(
                "- Product Color Linkage: In `production`, `actual_production`, `stock`, and `sales_order_products`, the `product_color_id` column links directly to `product_color.id` (table `product_color`, column `product_color.color`) — NOT to the `color` table! "
                "ALWAYS join `product_color pc ON prd.product_color_id = pc.id` and select `pc.color AS color`. NEVER join with the `color` table; `color` is a separate master list whose IDs do not match `product_color_id`, which causes completely wrong colors to be returned."
            )

        # Product Type vs Category
        if ("product_type" in tables or "category" in tables) and any(k in q for k in ["type", "category", "raw material", "finished good", "carton"]):
            rules.append(
                "- Product Type vs Category: There are two places with product type: (1) `category.product_type` stores enum `'RM'` (Raw Material). "
                "(2) `product_type.product_type` stores text `'Raw Material'` (id=1) and `'Finished Goods'` (id=2). When querying products by category (e.g. 'Carton') and product type ('Raw Material'), ALWAYS include BOTH filters: `product p JOIN category c ON p.category_id = c.id WHERE c.category_name LIKE '%Carton%' AND (c.product_type = 'RM' OR p.product_type_id = 1)`. Never omit the category filter, and never compare `category.product_type = 'Raw Material'` directly (use `'RM'`)."
            )

        # Warehouse & Packaging
        if "packagings" in tables or "warehouse" in tables or any(k in q for k in ["warehouse", "carton", "bin", "rack", "stored", "storage", "location"]):
            rules.append(
                "- Warehouse & Packaging: Warehouse Identification, Carton Count vs Carton Quantity:\n"
                "  (1) Warehouse Identification: Warehouse codes (e.g. 'pm2bzd19') and warehouse names/numbers (e.g. '110') are stored in the `warehouse` table: `warehouse.warehouse_code` and `warehouse.location_name`. When matching a warehouse, ALWAYS join `warehouse w ON pk.warehouse_id = w.id` and filter `(w.warehouse_code = '<code_or_name>' OR w.location_name = '<code_or_name>')`. NEVER search `packagings.location_code` for warehouse codes (`packagings.location_code` only stores internal bin/rack shelf codes).\n"
                "  (2) Carton Count vs Carton Quantity: In the `packagings` table, each row represents ONE physical carton box. `COUNT(pk.id)` or `COUNT(*)` returns the number of carton boxes (e.g. 412 cartons). `pk.qty` stores the number of product units inside each carton. Therefore, when asked for 'carton quantity', 'total carton quantity', 'quantity in cartons', or 'stock quantity in warehouse', ALWAYS use `SUM(pk.qty) AS total_carton_quantity` (e.g. 152,354 units), NEVER `COUNT(*)`! You may return both: `COUNT(pk.id) AS total_cartons, SUM(pk.qty) AS total_carton_quantity`.\n"
                "  (3) Product Storage Locations: To find where a product is stored or what warehouse/bin it is in, join `packagings pk JOIN warehouse w ON pk.warehouse_id = w.id JOIN product p ON pk.product_id = p.id WHERE p.product_name LIKE '%<term>%'`. Return `p.product_name`, `w.warehouse_code`, `w.location_name AS warehouse_location`, `pk.location_code AS bin_location`, `pk.carton_no`, `pk.qty AS carton_qty`."
            )

        # Stock Adjustments
        if "stock_adjustment" in tables or any(k in q for k in ["adjustment", "adjust", "stock-out", "stock out", "stockout", "stock-in", "stock in", "stockin"]):
            rules.append(
                "- Stock Adjustments (StockOut vs StockIn): All inventory stock adjustments (stock-in additions, stock-out write-offs, physical count adjustments) are stored in the dedicated `stock_adjustment` table:\n"
                "  (1) Table Selection: ALWAYS use `stock_adjustment` when asked about stock adjustments, stock-out, stock-in, or adjusted quantity. NEVER use `stock` (which is for purchase inward and sales dispatches) and NEVER use `product_packaging_detail` (which is a packaging BOM master table).\n"
                "  (2) Transaction Type Enum: `stock_adjustment.transaction_type` has ONLY TWO exact enum values: `'StockOut'` (stock reduction / outward adjustment) and `'StockIn'` (stock addition / inward adjustment). NEVER use `'OUT'`, `'IN'`, `'Stock-Out'`, `'STOCK_OUT'`, or lowercase strings. For stock-out queries, filter `sa.transaction_type = 'StockOut'`. For stock-in queries, filter `sa.transaction_type = 'StockIn'`.\n"
                "  (3) Columns & Direct Foreign Keys: Adjustment Date `sa.stock_adjustment_date`, Adjusted Quantity `sa.qty` (or `SUM(sa.qty) AS total_adjusted_quantity`), Category Link `JOIN category c ON sa.category_id = c.id`, Product Link `JOIN product p ON sa.product_id = p.id`, Color Link `JOIN product_color pc ON sa.product_color_id = pc.id`.\n"
                "  (4) All-Time vs Current Year: For 'quantity adjusted' or 'total adjusted quantity' without an explicit year qualifier, DO NOT join financial_year and DO NOT filter current_year = 'Y'! Sum across all records: `SELECT SUM(sa.qty) AS total_adjusted_quantity FROM stock_adjustment sa JOIN product p ON sa.product_id = p.id WHERE sa.deleted_at IS NULL AND p.deleted_at IS NULL AND p.product_name LIKE '%<product>%'`."
            )

        # Delivery Challan & Pending Sales Orders
        if "delivery_challan" in tables or "delivery_challan_products" in tables or any(k in q for k in ["challan", "delivery", "dc", "dc_no", "shipment", "transporter", "lr"]):
            rules.append(
                "- Delivery Challan (DC) vs Invoice & Due Date: A Delivery Challan (DC) and an Invoice are completely separate documents! Actual DC numbers and dates are stored in the `delivery_challan` table: `dc.dc_no` (DC number) and `dc.dc_date` (DC date). Logistics columns: `dc.transport_name` (carrier name) and `dc.lr_number` (Lorry Receipt / LR number — NOT `lr_no`). The customer/party is linked directly via `delivery_challan.party_id = party.id`. NEVER search for DC numbers in `stock.invoice_no` or `stock`! IMPORTANT: `delivery_challan` has NO due date column; the order due date is stored in `sales_order.so_due_date`. When a query asks for the due date of a DC, you MUST join `sales_order`: `LEFT JOIN sales_order so ON dc.sales_order_id = so.id` and select `so.so_due_date AS due_date`."
            )
            rules.append(
                "- Delivery Challan & Pending Sales Orders: To find Sales Orders with pending/undelivered quantity for delivery challan creation, query: "
                "SELECT so.sales_order_no AS sales_order_number, so.sales_order_date AS order_date, p.party_name AS customer_name, pr.product_name AS product_name, sop.qty AS ordered_quantity, COALESCE(SUM(dcp.qty), 0) AS delivered_quantity, (sop.qty - COALESCE(SUM(dcp.qty), 0)) AS pending_quantity FROM sales_order so JOIN sales_order_products sop ON so.id = sop.sales_order_id JOIN party p ON so.party_id = p.id JOIN product pr ON sop.product_id = pr.id LEFT JOIN delivery_challan dc ON so.id = dc.sales_order_id AND dc.deleted_at IS NULL LEFT JOIN delivery_challan_products dcp ON dc.id = dcp.dc_id AND dcp.product_id = sop.product_id AND dcp.deleted_at IS NULL WHERE so.deleted_at IS NULL AND sop.deleted_at IS NULL AND p.deleted_at IS NULL AND pr.deleted_at IS NULL AND p.status = 'Y' GROUP BY so.sales_order_no, so.sales_order_date, p.party_name, pr.product_name, sop.qty HAVING pending_quantity > 0 ORDER BY so.sales_order_no, pr.product_name;"
            )

        # Sales Order & PO
        if "sales_order" in tables or "purchase" in tables or any(k in q for k in ["sales_order", "order", "party_po_no", "po", "due date"]):
            rules.append(
                "- Customer PO vs Supplier PO vs Proforma PO: PO numbers exist in 3 distinct places: (1) Customer/Party PO: `sales_order.party_po_no` (and `sales_order.party_po_date`). For questions asking for 'party's PO number', 'customer PO', or 'PO number for sales order/party', ALWAYS query `sales_order so JOIN party p ON so.party_id = p.id`. (2) Proforma PO: `proforma.po_no` (only for proforma invoice questions). (3) Supplier/Vendor PO: `purchase.ref_po_no` (only for supplier inward purchase orders). NEVER use `purchase.ref_po_no` for customer/party PO requests."
            )
            rules.append(
                "- Blocked Cartons: In `stock`, `party_id` is NULL. Join party through `sales_order`: `stock s JOIN sales_order so ON s.so_id = so.id JOIN party p ON so.party_id = p.id WHERE s.status = 'B'`."
            )

        # Invoices vs Proforma
        if "stock" in tables or "proforma" in tables or any(k in q for k in ["invoice", "invoices", "invoice_no", "proforma", "pi"]):
            if soft_intent == "DELETED_ONLY":
                rules.append(
                    "- Invoices vs Proforma [DELETED RECORDS]: Actual invoice details are stored in the `stock` table where `stock.stock_type = 'PI'`, or in `purchase` for purchase invoices. "
                    "For questions asking about DELETED invoices: (1) Query `stock s JOIN party p ON s.party_id = p.id WHERE s.stock_type = 'PI' AND s.deleted_at IS NOT NULL AND p.deleted_at IS NULL` (or from `purchase pur JOIN party p ON pur.party_id = p.id WHERE pur.deleted_at IS NOT NULL AND p.deleted_at IS NULL`). "
                    "(2) DO NOT add `deleted_at IS NULL` on the invoice table; use `deleted_at IS NOT NULL`!"
                )
            elif soft_intent == "INCLUDE_ARCHIVED":
                rules.append(
                    "- Invoices vs Proforma [HISTORY/AUDIT]: Actual invoice details are in `stock` (where `stock_type = 'PI'`) or `purchase`. "
                    "For history/audit queries, omit `deleted_at IS NULL` on invoice tables to include all historical records."
                )
            else:
                rules.append(
                    "- Invoices vs Proforma: Actual invoice details (numbers, dates, parties) are stored in the `stock` table where `stock.stock_type = 'PI'`, NOT in the `proforma` table! For questions asking about invoices, invoice lists, or invoice counts: (1) Query `stock s JOIN party p ON s.party_id = p.id WHERE s.stock_type = 'PI' AND s.deleted_at IS NULL AND p.deleted_at IS NULL`. (2) When `stock_type = 'PI'`, `s.party_id` connects DIRECTLY to `party.id` (do NOT route through sales_order). (3) Always filter `s.stock_type = 'PI'`. (4) Calculate invoice count as `COUNT(DISTINCT s.invoice_no)`. Only query `proforma` table if user explicitly specifies 'proforma'."
                )

        # Party & Leads
        if "party" in tables or "lead" in tables or any(k in q for k in ["party", "customer", "supplier", "vendor", "contact", "lead", "inquiry"]):
            rules.append(
                "- In party table, customer/supplier name is `party.party_name` (NEVER party.name). Contact persons are `party.contact_person1`.\n"
                "- In lead table, search `(lead.contact_name LIKE '%<name>%' OR lead.company_name LIKE '%<name>%')`.\n"
                "- Unified Contact Search: For generic contact info without 'lead'/'customer', UNION ALL across party and lead."
            )

        # Document Number Uniqueness Across Financial Years
        if any(t in tables for t in ["delivery_challan", "sales_order", "purchase", "proforma", "production"]) or any(k in q for k in ["dc_no", "so_no", "order_no", "number", "latest"]):
            rules.append(
                "- Document Number Uniqueness Across Financial Years (DC, Sales Order, PO, etc.): Document numbers (`dc_no`, `sales_order_no`, `purchase_no`, `proforma_no`, `production_no`) are NOT globally unique; they repeat across different financial years! "
                "If a financial year is specified, join `financial_year fy ON t.financial_id = fy.id`. If NO financial year is specified for a SINGLE DOCUMENT LOOKUP: the user intends the LATEST record! Sort by date DESC with `LIMIT 1` and include `fy.fyear AS financial_year` in SELECT. Do NOT apply LIMIT 1 or current_year filtering to cumulative/aggregate queries."
            )

        # Multi-domain Report
        if any(k in q for k in ["report", "summary", "combined", "ppq", "apq"]):
            rules.append(
                "- Combined Production, Stock & Sales Order Report: When queried for a multi-domain report (PPQ, APQ, Stock, Pending SOs) grouped by Category, Product, Color, use CTE subqueries aggregated per `(product_id, product_color_id)` before joining to `product p`."
            )

        if soft_intent == "DELETED_ONLY":
            rules.append(
                "- ⚠️ CRITICAL INTENT OVERRIDE: The user explicitly requested DELETED records. "
                "In your generated query, DO NOT use `deleted_at IS NULL` on the requested entity. Use `WHERE <alias>.deleted_at IS NOT NULL`."
            )
        elif soft_intent == "INCLUDE_ARCHIVED":
            rules.append(
                "- ⚠️ CRITICAL INTENT OVERRIDE: The user explicitly requested AUDIT / HISTORY / ARCHIVED records. "
                "In your generated query, DO NOT use `deleted_at IS NULL`. Allow all records (both active and deleted) to be returned."
            )

        return "\n".join(rules)

    _OUTPUT_READABILITY_RULES = """
Core SQL Generation & Schema Mapping Protocol:
- 4-Step Schema Resolution: Before writing any SQL, strictly resolve:
  1. Business Intent: What is the user asking for? (Identify exact business entities and metrics).
  2. Table Selection: Which table physically stores that data? (e.g. product definitions in `product`, machine definitions in `machine`, batch production quantities in `production`, actual invoices in `stock` where `stock_type = 'PI'`, delivery challans in `delivery_challan`, stock adjustments in `stock_adjustment` (NOT `stock` or `product_packaging_detail`), order due dates in `sales_order`, product colors in `product_color`, bin/carton storage locations in `packagings`, measurement units in `unit`, customer orders in `sales_order`).
  3. Column Resolution: Which specific column stores the value? (e.g. stock adjustment transaction type in `stock_adjustment.transaction_type` with exact values `'StockOut'` and `'StockIn'` (NEVER `'OUT'` or `'IN'`); adjusted quantity in `SUM(stock_adjustment.qty)`; warehouse code in `warehouse.warehouse_code`, NOT in `packagings.location_code`; total carton quantity in `SUM(packagings.qty)`, NOT `COUNT(*)`; order/delivery due date in `sales_order.so_due_date`; DC numbers in `delivery_challan.dc_no`, NOT in `stock.invoice_no`; product color in `product_color.color`, NOT in table `color`; production quantity in `production.qty`, NOT in `actual_production.apq`; product names/codes in `product.product_name`, not in `batch_no` or `unit_name`; storage codes in `packagings.location_code`, not `warehouse`; customer PO in `sales_order.party_po_no`, not `purchase.ref_po_no`).
  4. Relationship & Join Graph: How should the tables be joined? (Follow verified foreign keys directly: `stock_adjustment.category_id = category.id`; `stock_adjustment.product_id = product.id`; `stock_adjustment.product_color_id = product_color.id`; `packagings.warehouse_id = warehouse.id`; `delivery_challan.sales_order_id = sales_order.id` for due dates; `delivery_challan.party_id = party.id`; `production.product_color_id = product_color.id`; `production.product_id = product.id`; `production.machine_id = machine.id`; `stock.party_id = party.id` for invoices).
- SELECT read-only queries only.
- Primary Key & Column Projection: For non-aggregate record queries, ALWAYS include the primary key column (e.g. table.id AS id) as the first selected column to serve as an anchor reference point, unless explicitly excluded by the user. Do not alias it confusingly (use alias.id AS id, not alias.id AS something_id unless requested). Follow the ID with only the specific columns or metrics asked by the user. Never bloat results with unsolicited columns (e.g. status, created_at, deleted_at). Never return raw foreign key ID columns without their human-readable name (use AS descriptive_alias).
- Dynamic Soft-Delete Filtering: For standard operational queries, always filter soft-deleted records (WHERE alias.deleted_at IS NULL). If the user query explicitly mentions 'deleted', 'removed', or 'dropped', filter WHERE alias.deleted_at IS NOT NULL; if asking for 'history', 'audit', or 'archived', omit the deleted_at filter to return all records.
- Status flags: party.status, product.status, category.status use 'Y'/'N'. Stock booked='B', dispatched='D'.
- In party table, customer/supplier name is `party.party_name` (NEVER party.name). Contact persons are `party.contact_person1`.
- In lead table, search `(lead.contact_name LIKE '%<name>%' OR lead.company_name LIKE '%<name>%')`.
- Unified Contact Search: For generic contact info without 'lead'/'customer', UNION ALL across party and lead.
- Product Color Linkage: In `production`, `actual_production`, `stock`, and `sales_order_products`, the `product_color_id` column links directly to `product_color.id` (table `product_color`, column `product_color.color`) — NOT to the `color` table! ALWAYS join `product_color pc ON prd.product_color_id = pc.id` and select `pc.color AS color`. NEVER join with the `color` table; `color` is a separate master list whose IDs do not match `product_color_id`, which causes completely wrong colors to be returned.
- Blocked Cartons: In `stock`, `party_id` is NULL. Join party through `sales_order`: `stock s JOIN sales_order so ON s.so_id = so.id JOIN party p ON so.party_id = p.id WHERE s.status = 'B'`.
- Delivery Challan & Pending Sales Orders: To find Sales Orders with pending/undelivered quantity for delivery challan creation, query:
SELECT so.sales_order_no AS sales_order_number, so.sales_order_date AS order_date, p.party_name AS customer_name, pr.product_name AS product_name, sop.qty AS ordered_quantity, COALESCE(SUM(dcp.qty), 0) AS delivered_quantity, (sop.qty - COALESCE(SUM(dcp.qty), 0)) AS pending_quantity FROM sales_order so JOIN sales_order_products sop ON so.id = sop.sales_order_id JOIN party p ON so.party_id = p.id JOIN product pr ON sop.product_id = pr.id LEFT JOIN delivery_challan dc ON so.id = dc.sales_order_id AND dc.deleted_at IS NULL LEFT JOIN delivery_challan_products dcp ON dc.id = dcp.dc_id AND dcp.product_id = sop.product_id AND dcp.deleted_at IS NULL WHERE so.deleted_at IS NULL AND sop.deleted_at IS NULL AND p.deleted_at IS NULL AND pr.deleted_at IS NULL AND p.status = 'Y' GROUP BY so.sales_order_no, so.sales_order_date, p.party_name, pr.product_name, sop.qty HAVING pending_quantity > 0 ORDER BY so.sales_order_no, pr.product_name;
- Fuzzy LIKE Filtering: Always filter descriptive text columns (categories, products, colors, names) using `LIKE '%<term>%'` rather than strict `=`. For categories with spelling variations like 'CHANGABLE PACK', match `c.category_name LIKE '%CHANG%PACK%'` (the database category is 'CHANGEABLE PACK').
- Production Quantity & Batches: In the `production` table, the primary production/batch quantity is stored in `production.qty`. When asked for the production quantity, batch quantity, or quantity produced for a batch or product, ALWAYS select `production.qty AS production_quantity` (or `SUM(prd.qty)`). NEVER select `actual_production.apq` as the default production quantity, because `actual_production.apq` is unpopulated or 0 for many batches (which causes queries to return 0), while `production.qty` contains the true quantity. Only query `actual_production.apq` if the user explicitly asks for 'actual production quantity' or 'APQ' compared to planned targets.
- Machine & Product Production: Product names/codes (e.g. 'CAP03', 'CHP06070110-INNER') are stored in `product.product_name` (NEVER in `production.batch_no` or `stock.batch_no`). To find which machine was used to create or produce a product, ALWAYS join: `production prd JOIN product p ON prd.product_id = p.id JOIN machine m ON prd.machine_id = m.id WHERE p.product_name LIKE '%<product_name>%' AND prd.deleted_at IS NULL AND m.deleted_at IS NULL`. Return `m.machine_name`.
- Warehouse & Packaging: Warehouse Identification, Carton Count vs Carton Quantity:
  (1) Warehouse Identification: Warehouse codes (e.g. 'pm2bzd19') and warehouse names/numbers (e.g. '110') are stored in the `warehouse` table: `warehouse.warehouse_code` and `warehouse.location_name`. When matching a warehouse, ALWAYS join `warehouse w ON pk.warehouse_id = w.id` and filter `(w.warehouse_code = '<code_or_name>' OR w.location_name = '<code_or_name>')`. NEVER search `packagings.location_code` for warehouse codes (`packagings.location_code` only stores internal bin/rack shelf codes).
  (2) Carton Count vs Carton Quantity: In the `packagings` table, each row represents ONE physical carton box. `COUNT(pk.id)` or `COUNT(*)` returns the number of carton boxes (e.g. 412 cartons). `pk.qty` stores the number of product units inside each carton. Therefore, when asked for 'carton quantity', 'total carton quantity', 'quantity in cartons', or 'stock quantity in warehouse', ALWAYS use `SUM(pk.qty) AS total_carton_quantity` (e.g. 152,354 units), NEVER `COUNT(*)`! You may return both: `COUNT(pk.id) AS total_cartons, SUM(pk.qty) AS total_carton_quantity`.
  (3) Product Storage Locations: To find where a product is stored or what warehouse/bin it is in, join `packagings pk JOIN warehouse w ON pk.warehouse_id = w.id JOIN product p ON pk.product_id = p.id WHERE p.product_name LIKE '%<term>%'`. Return `p.product_name`, `w.warehouse_code`, `w.location_name AS warehouse_location`, `pk.location_code AS bin_location`, `pk.carton_no`, `pk.qty AS carton_qty`.
- Stock Adjustments (StockOut vs StockIn): All inventory stock adjustments (stock-in additions, stock-out write-offs, physical count adjustments) are stored in the dedicated `stock_adjustment` table:
  (1) Table Selection: ALWAYS use `stock_adjustment` when asked about stock adjustments, stock-out, stock-in, or adjusted quantity. NEVER use `stock` (which is for purchase inward and sales dispatches) and NEVER use `product_packaging_detail` (which is a packaging BOM master table).
  (2) Transaction Type Enum: `stock_adjustment.transaction_type` has ONLY TWO exact enum values: `'StockOut'` (stock reduction / outward adjustment) and `'StockIn'` (stock addition / inward adjustment). NEVER use `'OUT'`, `'IN'`, `'Stock-Out'`, `'STOCK_OUT'`, or lowercase strings. For stock-out queries, filter `sa.transaction_type = 'StockOut'`. For stock-in queries, filter `sa.transaction_type = 'StockIn'`.
  (3) Columns & Direct Foreign Keys:
      - Adjustment Date: `sa.stock_adjustment_date` (e.g. `WHERE sa.stock_adjustment_date = '2025-06-03'`).
      - Adjusted Quantity: `sa.qty` (or `SUM(sa.qty) AS total_adjusted_quantity`).
      - Category Link: `JOIN category c ON sa.category_id = c.id WHERE c.category_name LIKE '%<name>%'`.
      - Product Link: `JOIN product p ON sa.product_id = p.id WHERE p.product_name LIKE '%<name>%'`.
      - Color Link: `JOIN product_color pc ON sa.product_color_id = pc.id`.
  (4) Canonical Query Templates:
      - Adjustment Count by Date: `SELECT COUNT(*) AS stock_out_adjustment_count FROM stock_adjustment sa WHERE sa.deleted_at IS NULL AND sa.stock_adjustment_date = '<date>' AND sa.transaction_type = 'StockOut';`
      - Category Stock-out Quantity: `SELECT c.category_name, SUM(sa.qty) AS total_stock_out_quantity FROM stock_adjustment sa JOIN category c ON sa.category_id = c.id WHERE sa.deleted_at IS NULL AND c.deleted_at IS NULL AND c.category_name LIKE '%<cat>%' AND sa.transaction_type = 'StockOut' AND sa.stock_adjustment_date = '<date>' GROUP BY c.category_name;`
      - Product Adjusted Quantity: `SELECT p.product_name, sa.transaction_type, SUM(sa.qty) AS total_qty_adjusted FROM stock_adjustment sa JOIN product p ON sa.product_id = p.id WHERE sa.deleted_at IS NULL AND p.deleted_at IS NULL AND p.product_name LIKE '%<product>%' GROUP BY p.product_name, sa.transaction_type;`
      - Product Total Adjusted Quantity (All-Time): `SELECT SUM(sa.qty) AS total_qty_adjusted FROM stock_adjustment sa JOIN product p ON sa.product_id = p.id WHERE sa.deleted_at IS NULL AND p.deleted_at IS NULL AND p.product_name LIKE '%<product>%';`
- Product Units of Measure: The unit table contains unit definitions ('Pcs', 'Kg', 'Nos', etc.) and NEVER contains product names. To find the unit for a product (e.g. 'CAP03'), ALWAYS query: `product p JOIN unit u ON p.unit_id = u.id WHERE p.product_name LIKE '%<product>%' AND p.deleted_at IS NULL AND u.deleted_at IS NULL`. Return `p.product_name` and `u.unit_name AS unit_of_measure`. Never search `unit.unit_name` for product names.
- Product Type vs Category: There are two places with product type: (1) `category.product_type` stores enum `'RM'` (Raw Material). (2) `product_type.product_type` stores text `'Raw Material'` (id=1) and `'Finished Goods'` (id=2). When querying products by category (e.g. 'Carton') and product type ('Raw Material'), ALWAYS include BOTH filters: `product p JOIN category c ON p.category_id = c.id WHERE c.category_name LIKE '%Carton%' AND (c.product_type = 'RM' OR p.product_type_id = 1)`. Never omit the category filter, and never compare `category.product_type = 'Raw Material'` directly (use `'RM'`).
- Customer PO vs Supplier PO vs Proforma PO: PO numbers exist in 3 distinct places: (1) Customer/Party PO: `sales_order.party_po_no` (and `sales_order.party_po_date`). For questions asking for "party's PO number", "customer PO", or "PO number for sales order/party", ALWAYS query `sales_order so JOIN party p ON so.party_id = p.id`. (2) Proforma PO: `proforma.po_no` (only for proforma invoice questions). (3) Supplier/Vendor PO: `purchase.ref_po_no` (only for supplier inward purchase orders). NEVER use `purchase.ref_po_no` for customer/party PO requests.
- Invoices vs Proforma: Actual invoice details (numbers, dates, parties) are stored in the `stock` table where `stock.stock_type = 'PI'`, NOT in the `proforma` table! For questions asking about invoices, invoice lists, or invoice counts: (1) Query `stock s JOIN party p ON s.party_id = p.id WHERE s.stock_type = 'PI' AND s.deleted_at IS NULL AND p.deleted_at IS NULL`. (2) When `stock_type = 'PI'`, `s.party_id` connects DIRECTLY to `party.id` (do NOT route through sales_order). (3) Always filter `s.stock_type = 'PI'`. (4) Calculate invoice count as `COUNT(DISTINCT s.invoice_no)`. Only query `proforma` table if user explicitly specifies "proforma".
- Delivery Challan (DC) vs Invoice & Due Date: A Delivery Challan (DC) and an Invoice are completely separate documents! Actual DC numbers and dates are stored in the `delivery_challan` table: `dc.dc_no` (DC number) and `dc.dc_date` (DC date). Logistics columns: `dc.transport_name` (carrier name) and `dc.lr_number` (Lorry Receipt / LR number — NOT `lr_no`). The customer/party is linked directly via `delivery_challan.party_id = party.id`. NEVER search for DC numbers in `stock.invoice_no` or `stock`! IMPORTANT: `delivery_challan` has NO due date column; the order due date is stored in `sales_order.so_due_date`. When a query asks for the due date of a DC, you MUST join `sales_order`: `LEFT JOIN sales_order so ON dc.sales_order_id = so.id` and select `so.so_due_date AS due_date`.
- Document Number Uniqueness Across Financial Years (DC, Sales Order, PO, etc.): Document numbers (`dc_no`, `sales_order_no`, `purchase_no`, `proforma_no`, `production_no`) are NOT globally unique; they repeat across different financial years! For example, `dc_no = 527` and `sales_order_no = 405` exist in multiple financial years for completely different parties. (1) If a financial year is specified (e.g. 'in 2024-2025' or 'this year'), join `financial_year fy ON t.financial_id = fy.id` and filter `fy.fyear = '...'` or `fy.current_year = 'Y'`. (2) If NO financial year is specified for a SINGLE DOCUMENT LOOKUP: the user intends the LATEST / CURRENT record! ALWAYS sort by date DESC with `LIMIT 1` (e.g. `ORDER BY dc.dc_date DESC LIMIT 1` or `ORDER BY so.sales_order_date DESC LIMIT 1`), and include `fy.fyear AS financial_year` in the SELECT clause so the user knows which financial year the document belongs to. (3) For AGGREGATE or cumulative metric queries (e.g. sums, counts, totals), do NOT apply LIMIT 1 and do NOT filter by current_year unless explicitly asked.
- Temporal Scope & Financial Year Filtering: ONLY add `financial_year.current_year = 'Y'` if the user query contains explicit temporal markers such as 'current', 'this year', 'latest', 'active', or 'ongoing'. If the query asks for 'total', 'all', 'history', or implies a cumulative sum without a time qualifier (e.g. 'quantity adjusted', 'total sales', 'overall quantity'), DO NOT filter by current_year. Sum across all available years. When the user DOES explicitly request the current financial year, NEVER filter using `YEAR(date) = YEAR(CURDATE())`; ALWAYS join `financial_year fy ON t.financial_id = fy.id` (or `WHERE t.financial_id = (SELECT id FROM financial_year WHERE current_year = 'Y')`) with `fy.current_year = 'Y'`.
- Combined Production, Stock & Sales Order Report: When queried for a multi-domain report (PPQ, APQ, Stock, Pending SOs) grouped by Category, Product, Color, use CTE subqueries (WITH prod_m AS (...), stock_m AS (...), so_m AS (...)) aggregated per `(product_id, product_color_id)` before joining to `product p` to prevent Cartesian join multiplication.
"""

    def _is_safe_read_query(self, sql: str) -> bool:
        """Parse the AST and confirm it's a single, side-effect-free read SELECT or UNION.

        ``isinstance(ast, (exp.Select, exp.Union))`` is necessary but NOT sufficient — several
        write/exfiltration/DoS primitives are still valid read statements:

          * ``SELECT ... INTO OUTFILE/DUMPFILE '/path'`` (MySQL) writes to disk;
          * ``SELECT LOAD_FILE('/etc/passwd')`` reads an arbitrary file;
          * ``SELECT BENCHMARK(100000000, MD5('x'))`` or ``SELECT SLEEP(10)`` exhausts resources;
          * a stacked ``SELECT 1; DROP TABLE t`` smuggles a second statement.

        This rejects all of the above so the generated query can only ever read
        rows, matching the layer's stated "read-only SELECT/UNION" guarantee.
        """
        try:
            # parse() (not parse_one) surfaces stacked statements so they can be
            # rejected rather than silently reduced to the first one.
            statements = [
                s for s in sqlglot.parse(sql, read=self._dialect.sqlglot_dialect)
                if s is not None and not isinstance(s, exp.Semicolon) and s.sql().strip()
            ]
        except Exception as e:
            logger.error(f"sqlglot rejected query '{sql}': {e}")
            return False

        if len(statements) != 1:
            logger.warning("Blocked multi-statement / stacked SQL: %s", sql)
            return False

        ast = statements[0]
        if not isinstance(ast, (exp.Select, exp.Union)):
            return False

        if has_dangerous_qualified_call(sql, self._dialect.sqlglot_dialect):
            logger.warning("Blocked dangerous package-qualified call: %s", sql)
            return False

        # SELECT ... INTO OUTFILE/DUMPFILE (or INTO @var) anywhere in the AST — disk/variable write.
        for sel_node in ast.find_all(exp.Select):
            if sel_node.args.get("into") is not None:
                logger.warning("Blocked SELECT ... INTO (file/variable write): %s", sql)
                return False

        # File-read / code-exec / DoS / locking functions anywhere in the tree.
        for anon in ast.find_all(exp.Anonymous):
            fname = (anon.this or "")
            if isinstance(fname, str) and fname.lower() in self._DANGEROUS_FUNCTIONS:
                logger.warning("Blocked dangerous function '%s' in SQL: %s", fname, sql)
                return False
        for func in ast.find_all(exp.Func):
            fname = func.sql_name() if hasattr(func, "sql_name") else getattr(func, "key", "")
            if isinstance(fname, str) and fname.lower() in self._DANGEROUS_FUNCTIONS:
                logger.warning("Blocked dangerous function '%s' in SQL: %s", fname, sql)
                return False

        return True


async def fetch_sqlite_foreign_keys(db_id: str = DEFAULT_DB_ID, user_id: str | None = None) -> list[dict]:
    """Fetch foreign key relationships from SQLite database."""
    if user_id and user_id not in ("admin", "*", "all"):
        from src.sql.registry import can_access_database

        if not can_access_database(db_id, user_id):
            return []
    tables = await run_readonly_query(
        "SELECT name FROM sqlite_master WHERE type='table' AND name != 'sqlite_sequence';",
        db_id=db_id,
    )
    fks = []
    for row in tables:
        table = row["name"]
        escaped_table = table.replace('"', '""')
        cols = await run_readonly_query(f'PRAGMA foreign_key_list("{escaped_table}");', db_id=db_id)
        for c in cols:
            fks.append({
                "table_name": table,
                "column_name": c["from"],
                "referenced_table_name": c["table"],
                "referenced_column_name": c["to"],
            })
    return fks


_MAX_DISPLAY_ROWS = 10


def _format_rows_as_markdown(rows: list[dict[str, Any]], query: str, is_agg_zero: bool = False) -> str:
    """Format dictionary rows into a markdown table, capped at 10 rows."""
    clean_lines = []
    for line in query.splitlines():
        cleaned = re.sub(r"--.*$", "", line).strip()
        if cleaned:
            clean_lines.append(cleaned)
    clean_query = " ".join(clean_lines) if clean_lines else query.strip()

    if not rows:
        return f"SQL Query Executed: `{clean_query}`\n\n_No matching records found in the database._"

    if is_agg_zero:
        headers = list(rows[0].keys())
        header_row = "| " + " | ".join(headers) + " |"
        separator_row = "| " + " | ".join(["---"] * len(headers)) + " |"
        null_row = "| " + " | ".join(["NULL" for _ in headers]) + " |"
        return f"SQL Query Executed: `{clean_query}`\n\n" + "\n".join([header_row, separator_row, null_row]) + "\n\n_Note: The query matched 0 records for aggregation, returning NULL._"

    headers = list(rows[0].keys())
    header_row = "| " + " | ".join(headers) + " |"
    separator_row = "| " + " | ".join(["---"] * len(headers)) + " |"

    table_rows = [f"SQL Query Executed: `{clean_query}`\n", header_row, separator_row]

    shown = 0
    for row in rows:
        if shown >= _MAX_DISPLAY_ROWS:
            break
        values = [str(row[h]) if row[h] is not None else "NULL" for h in headers]
        line = "| " + " | ".join(values) + " |"
        table_rows.append(line)
        shown += 1

    result = "\n".join(table_rows)
    total = len(rows)
    if shown < total:
        result += (
            f"\n\n_Showing {shown} of {total} rows (result too large to "
            "display in full). Narrow your question (add a filter, date "
            "range, or LIMIT) to see a different slice._"
        )
    return result
