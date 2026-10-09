"""Query Pipeline Ã¢â¬â orchestrates Stages 12Ã¢â¬â14.

Takes a question, retrieves relevant chunks, reranks, and generates an answer.
"""

from __future__ import annotations

import asyncio
import logging
import re
from pathlib import Path

from src.core.config import settings
from src.core.pipeline_metrics import log_event as _log_pipeline_event
from src.core.provider_client import ProviderRouter
from src.core.rate_limiter import get_shared_rate_limiter
from src.models.schemas import QueryResult, RetrievedChunk, ThinkingStep
from src.stages.s10_embeddings import EmbeddingService
from src.stages.s11_vector_store import QdrantStore
from src.stages.s12_s13_s14_retrieval import (
    Generator,
    Reranker,
    Retriever,
    _enforce_document_diversity,
    _is_exhaustive_query,
    _source_mode,
)
from src.stages.s12b_sql_retrieval import SQLRetriever
from src.utils.query_classifier import QueryType, classify_query
from src.utils.semantic_cache import get_semantic_cache
from src.utils.sql_privacy import sanitize_assistant_turn
from src.utils.query_budget import get_or_create_budget_controller
from src.utils.telemetry import get_or_create_query_id, log_telemetry, set_current_query_id, timed_stage
from src.utils.feature_flags import is_feature_enabled
from src.guards.citation_guard import evaluate_rag_citations, sanitize_hallucinated_citations
from src.models.trace import Trace
from src.utils.trace_context import branch_context, get_current_span, start_trace
from src.utils.trace_writer import emit_trace

logger = logging.getLogger(__name__)

_MIN_RELEVANCE_SCORE = 0.01

# Shown when the live-database path found nothing NOT because the data is
# missing, but because the LLM providers needed to generate the SQL were all
# unreachable (rate-limited / dead models). Without this the user would see the
# misleading "not in my documents", implying their data doesn't have the answer.
_SQL_UNAVAILABLE_MSG = (
    "I couldn't answer this from your live database right now: the AI models "
    "needed to build the query are all unavailable at the moment (rate-limited "
    "or unreachable). Your data may well contain the answer — please try again "
    "shortly."
)


_DB_KEYWORDS = {
    "order", "orders", "sales", "purchase", "purchases", "supplier", "suppliers", "vendor", "vendors",
    "stock", "inventory", "warehouse", "warehouses", "carton", "cartons", "on hand",
    "production", "manufacture", "manufacturing", "batch", "batches", "machine", "machines",
    "yield", "output", "plant", "apq", "ppq", "color", "colors", "colour", "colours",
    "unit", "units", "uom", "measurement", "packaging", "packagings", "packing",
    "challan", "challans", "delivery", "dispatch", "shipment", "transporter", "vehicle", "driver", "dc",
    "invoice", "invoices", "proforma", "balance", "ledger", "credit", "debit", "party",
    "parties", "customer", "customers", "client", "clients", "lead", "leads", "inquiry",
    "inquiries", "adjustment", "adjustments", "stock-out", "stockout", "stock-in", "stockin", "product", "products",
    "category", "categories", "po", "po_no", "so_no", "dc_no", "pi", "pi_no", "batch_no",
    "qty", "quantity", "adjusted",
}

_DOC_KEYWORDS = {
    "rag", "ocr", "parser", "parsers", "pipeline", "architecture", "embedding",
    "embeddings", "rerank", "reranking", "chunk", "chunks", "chunking", "chunker", "vector",
    "policy", "policies", "procedure", "procedures", "sop", "sops", "guideline",
    "guidelines", "manual", "handbook", "contract", "contracts", "agreement",
    "apple", "iphone", "sec", "10-k", "10k", "filing", "filings", "annual report",
    "shareholder", "shareholders", "tax rate", "effective tax", "pdf", "docx", "doc", "document", "documents",
    "ticker", "hq", "headquarters", "fte", "headcount", "employee", "employees", "layers", "layer",
    "distribution", "indirect",
}


def _has_sql_signal(text: str) -> bool:
    t_lower = text.lower()
    tokens = set(re.findall(r"\b[a-zA-Z0-9_-]+\b", t_lower))
    if bool(tokens & _DB_KEYWORDS):
        return True
    if any(phrase in t_lower for phrase in ["due date", "po number", "po numbers", "stock-out", "stock-in", "on hand", "net sales"]):
        return True
    if bool(re.search(r"\b[a-zA-Z]+[0-9]+[a-zA-Z0-9_-]*\b", text)):
        return True
    return False


def _has_doc_signal(text: str) -> bool:
    t_lower = text.lower()
    tokens = set(re.findall(r"\b[a-zA-Z0-9_-]+\b", t_lower))
    if bool(tokens & _DOC_KEYWORDS):
        return True
    if any(phrase in t_lower for phrase in [
        "effective tax", "10-k", "10k", "tax rate", "net sales", "ticker symbol",
        "headquarters", "fte employees", "chunker purpose", "rag layers", "fiscal year end",
        "embedding model", "indirect distribution",
    ]):
        return True
    return False


def _decompose_hybrid_query(query: str) -> tuple[str, str]:
    """Decompose a compound hybrid query into distinct (sql_query, doc_query).

    If the query cannot be cleanly split or both halves refer to the same intent,
    returns (query, query).
    """
    delimiters = [r"\s+/\s+", r"\s+\|\s+", r"\s+;\s+", r"\s+--\s+"]
    for delim in delimiters:
        parts = re.split(delim, query, maxsplit=1)
        if len(parts) == 2:
            p1, p2 = parts[0].strip(), parts[1].strip()
            p1_sql, p1_doc = _has_sql_signal(p1), _has_doc_signal(p1)
            p2_sql, p2_doc = _has_sql_signal(p2), _has_doc_signal(p2)
            if p1_sql and p2_doc and not p1_doc:
                return p1, p2
            if p2_sql and p1_doc and not p2_doc:
                return p2, p1
            if p1_sql and p2_doc:
                return p1, p2
            if p2_sql and p1_doc:
                return p2, p1

    and_parts = re.split(r"\s+(?:and|&)\s+", query, flags=re.IGNORECASE)
    if len(and_parts) == 2:
        p1, p2 = and_parts[0].strip(), and_parts[1].strip()
        p1_sql, p1_doc = _has_sql_signal(p1), _has_doc_signal(p1)
        p2_sql, p2_doc = _has_sql_signal(p2), _has_doc_signal(p2)
        if p1_sql and p2_doc and not p1_doc:
            return p1, p2
        if p2_sql and p1_doc and not p2_doc:
            return p2, p1

    return query, query


def _classify_auto_mode(query: str) -> str:
    """Classify user query in Auto mode into 'sql', 'rag', or 'hybrid'."""
    q_lower = query.lower()
    has_sql_signal = _has_sql_signal(query)
    has_doc_signal = _has_doc_signal(query)

    if has_sql_signal and not has_doc_signal:
        return "sql"
    elif has_doc_signal and not has_sql_signal:
        return "rag"
    else:
        return "hybrid"


def _pin_sql_result_chunks(
    chunks: list[RetrievedChunk],
    sql_chunks: list[RetrievedChunk],
) -> list[RetrievedChunk]:
    """Keep live SQL result chunks at the front of the final context.

    sql_chunks only ever contains a chunk when the query returned real rows
    (see SQLRetriever.retrieve Ã¢â‚¬â€  a genuine zero-row result returns an empty
    list instead of a placeholder), so pinning here is always safe: there's
    nothing but confirmed data to pin.
    """
    if not sql_chunks:
        return chunks

    sql_ids = {chunk.chunk.chunk_id for chunk in sql_chunks}
    pinned = [chunk for chunk in chunks if chunk.chunk.chunk_id in sql_ids]
    if not pinned:
        return sql_chunks + chunks

    remainder = [chunk for chunk in chunks if chunk.chunk.chunk_id not in sql_ids]
    return pinned + remainder


class QueryPipeline:
    """Orchestrates the query flow: retrieve Ã¢â€ â€™ rerank Ã¢â€ â€™ generate."""

    def __init__(
        self,
        router: ProviderRouter | None = None,
        embedding_service: EmbeddingService | None = None,
        vector_store: QdrantStore | None = None,
        preferred_provider: str | None = None,
    ) -> None:
        # Shared process-wide limiter so provider quota and 429
        # backoff span requests, exactly like the LLM providers.
        self._rate_limiter = get_shared_rate_limiter()
        # A single router drives retrieval, reranking, and generation, so the
        # soft pin applies uniformly across the whole query.
        self._router = router or ProviderRouter(preferred_provider=preferred_provider)
        self._embeddings = embedding_service or EmbeddingService()
        self._store = vector_store or QdrantStore(embedding_service=self._embeddings)
        self._retriever = Retriever(self._store, self._embeddings)
        self._sql_retriever = SQLRetriever(self._router, self._store, self._embeddings)
        self._reranker = Reranker()
        self._generator = Generator(self._router)

    async def query(
        self,
        question: str,
        filters: dict | None = None,
        history: list[dict] | None = None,
        mode: str = "auto",
    ) -> QueryResult:
        """Run a full RAG query: retrieve → rerank → generate.

        Args:
            question: The user's natural-language question.
            filters: Optional metadata filters. Supported keys:
                     document_type, source_file, page_number, document_id, chunk_type.
            history: Prior conversation turns (dicts with role/content), used to
                     resolve follow-ups into standalone queries and to keep the
                     answer coherent with the conversation.
            mode: Knowledge source mode: "auto", "sql", "rag", or "mix".
        """
        import uuid
        query_id = f"gm-q-{uuid.uuid4()}"
        set_current_query_id(query_id)
        budget_ctrl = get_or_create_budget_controller(query_id=query_id, force_new=True)
        logger.info("=== Query [%s] [Budget Limit: %d] [Mode: %s]: %s ===", query_id, budget_ctrl.max_tokens, mode, question[:100])

        import os
        scope_key = (filters.get("scope_key") or filters.get("erp_instance_id")) if filters else None
        if not scope_key:
            scope_key = os.environ.get("Antarkosh_ERP_INSTANCE_ID", "").strip() or None
        if scope_key:
            scope_key = f"{scope_key}|{_cache_acl_signature(filters.get('user_id') if filters else None)}"

        query_type = classify_query(question)

        # Check Layer 1: Semantic Cache (Instant Path) — strictly requires isolated scope_key
        query_emb: list[float] | None = None
        if scope_key:
            try:
                dense_emb, _ = await self._embeddings.embed_query(question)
                query_emb = dense_emb
                cached = get_semantic_cache().lookup(question, query_emb, scope_key=scope_key)
                if cached is not None:
                    cached.query = question
                    return cached
            except Exception as e:
                logger.debug("SemanticCache lookup skipped/failed: %s", e)

        with timed_stage("final_response", query_id=query_id) as final_stage:
            # Short-circuit: "what files/documents do you have?" — answer from registry
            if _is_document_listing_query(question) and mode != "sql":
                # ARCH-9: registry reads block; run off the event loop.
                user_id = filters.get("user_id") if filters else None
                answer = await asyncio.to_thread(_build_document_list_answer, user_id)
                return QueryResult(
                    query=question,
                    answer=answer,
                    model_used="registry",
                    reasoning_task="document_listing",
                )

            # Consult the conversation ONLY when the message looks like it depends on
            # it. A self-contained or new-topic question skips history entirely and is
            # answered exactly as it would be with no conversation — so history never
            # biases an unrelated question. When it is a follow-up, rewrite it into a
            # standalone query so retrieval continues the current thread.
            needs_context = bool(history) and _looks_like_followup(question)
            search_query = question
            if needs_context:
                search_query = await _contextualize_query(question, history, self._router)
                if search_query != question:
                    logger.info("Contextualized query: '%s' -> '%s'", question, search_query)
            gen_history = history if needs_context else None

            exhaustive = _is_exhaustive_query(search_query)
            if exhaustive:
                logger.info("Exhaustive query detected — boosting top_k and skipping rerank")

            # Mode-aware retrieval execution:
            effective_mode = mode
            if mode == "auto":
                effective_mode = _classify_auto_mode(search_query)
                logger.info("Auto-classified query '%s' -> mode '%s'", search_query[:80], effective_mode)

            doc_subquery = search_query
            if effective_mode == "sql":
                logger.info("[Tokens: %d/%d] [Mode: SQL] Querying live database only", budget_ctrl.get_current_usage(), budget_ctrl.max_tokens)
                with branch_context("sql_branch"):
                    sql_chunks = await self._sql_retriever.retrieve(search_query)
                vector_chunks = []
                if not sql_chunks and mode == "auto":
                    logger.info("Auto mode SQL returned no rows; falling back to documents")
                    with branch_context("rag_branch"):
                        vector_chunks = await self._retriever.retrieve(
                            search_query,
                            top_k=settings.retrieval_top_k,
                            filters=filters,
                            exhaustive=exhaustive,
                        )
            elif effective_mode == "rag":
                logger.info("[Tokens: %d/%d] [Mode: RAG] Searching documents only", budget_ctrl.get_current_usage(), budget_ctrl.max_tokens)
                with branch_context("rag_branch"):
                    vector_chunks = await self._retriever.retrieve(
                        search_query,
                        top_k=settings.retrieval_top_k,
                        filters=filters,
                        exhaustive=exhaustive,
                    )
                sql_chunks = []
            else:
                # Concurrent independent retrieval tasks without shared mutable state (Phase L3)
                logger.info("[Tokens: %d/%d] [Stage 12] Parallel SQL & Vector Retrieval", budget_ctrl.get_current_usage(), budget_ctrl.max_tokens)
                sql_subquery, doc_subquery = _decompose_hybrid_query(search_query)
                if sql_subquery != search_query or doc_subquery != search_query:
                    logger.info("Decomposed hybrid query into SQL: '%s' | DOC: '%s'", sql_subquery, doc_subquery)

                async def _run_sql():
                    with branch_context("sql_branch"):
                        return await self._sql_retriever.retrieve(sql_subquery)

                async def _run_rag():
                    with branch_context("rag_branch"):
                        return await self._retriever.retrieve(
                            doc_subquery,
                            top_k=settings.retrieval_top_k,
                            filters=filters,
                            exhaustive=exhaustive,
                        )

                # Coordinator merges isolated outputs after gather completes
                sql_chunks, vector_chunks = await asyncio.gather(_run_sql(), _run_rag())

            logger.info("Retrieved %d vector chunks and %d SQL chunks", len(vector_chunks), len(sql_chunks))
            sql_infra_error = self._sql_retriever.last_infra_error
            if sql_chunks:
                logger.info("SQL query succeeded and returned rows.")
            else:
                logger.info("SQL query returned no results or failed.")

            if not vector_chunks and not sql_chunks:
                if sql_infra_error:
                    return QueryResult(
                        query=question,
                        answer=_SQL_UNAVAILABLE_MSG,
                        model_used="none",
                        reasoning_task="sql_unavailable",
                    )
                if mode == "sql":
                    fallback_msg = "No matching database records found for this query."
                elif mode == "rag":
                    fallback_msg = "No relevant documents found. Please upload documents first."
                else:
                    db_keywords = ["sales", "order", "delivery", "challan", "stock", "product", "lead", "party", "customer", "vendor", "invoice", "quotation", "production", "carton", "qty", "quantity", "price", "rate", "warehouse"]
                    if any(k in question.lower() for k in db_keywords):
                        fallback_msg = "No matching database records found for this query."
                    else:
                        fallback_msg = "No relevant documents found. Please upload documents first."

                return QueryResult(
                    query=question,
                    answer=fallback_msg,
                    model_used="none",
                    reasoning_task="no_results",
                )

            # Stage 13 — Reranking. SQL chunks NEVER go here — solo or blended.
            # A live-db table shouldn't leave your infra via the reranker's API call,
            # and there's only ever one SQL chunk, so ranking it is meaningless.
            # Only vector_chunks go to the reranker; _pin_sql_result_chunks (below)
            # re-attaches the SQL chunk to the front unconditionally afterward, so
            # it always survives to generation regardless of what the reranker did
            # with the documents.
            rerank_k = settings.rerank_top_k if settings.enable_deep_rerank else min(settings.rerank_top_k, 25)
            if exhaustive or not vector_chunks:
                reranked = _enforce_document_diversity(vector_chunks, rerank_k)
            else:
                logger.info("[Tokens: %d/%d] [Stage 13] Reranking", budget_ctrl.get_current_usage(), budget_ctrl.max_tokens)
                reranked = await self._reranker.rerank(doc_subquery, vector_chunks, top_k=rerank_k)
                reranked = _enforce_document_diversity(reranked, rerank_k)
            reranked = [c for c in reranked if c.score is None or c.score >= _MIN_RELEVANCE_SCORE]
            reranked = _pin_sql_result_chunks(reranked, sql_chunks)
            logger.info("Final context: %d chunks", len(reranked))

            # Everything the documents returned was filtered out as irrelevant, and
            # the SQL path went silent only because its models were unreachable — so
            # say that, instead of letting generation report "not in my documents".
            if not reranked and sql_infra_error:
                return QueryResult(
                    query=question,
                    answer=_SQL_UNAVAILABLE_MSG,
                    model_used="none",
                    reasoning_task="sql_unavailable",
                )

            # Stage 14 — Generation (the user's original question + conversation,
            # but only when the question actually depends on it)
            logger.info("[Tokens: %d/%d] [Stage 14] Generating answer", budget_ctrl.get_current_usage(), budget_ctrl.max_tokens)
            # Exhaustive queries keep every reranked chunk (recall matters); normal
            # queries feed only the top few into the prompt to save input tokens.
            context_limit = None if exhaustive else settings.generation_context_k
            mode = _source_mode(reranked)
            _log_pipeline_event("routing_decision", {
                "mode": mode,
                "sql_rows": len(sql_chunks),
                "doc_chunks": len(vector_chunks),
                "reranked": len(reranked),
            }, query=question)
            result = await self._generator.generate(
                question, reranked, history=gen_history, context_limit=context_limit, source_mode=mode
            )
            result.chunks_retrieved = len(vector_chunks + sql_chunks)
            result.chunks_after_rerank = len(reranked)

            # RAG Citation Guard Evaluation (Hard Enforced or Shadow)
            if reranked or (result and getattr(result, "citations", None)):
                citation_guard_res = evaluate_rag_citations(
                    answer=result.answer if result else "",
                    retrieved_chunks=reranked,
                    citations=[getattr(c, "chunk_id", None) or getattr(c, "source", None) or str(c) for c in (getattr(result, "citations", None) or [])],
                )
                curr_span = get_current_span()
                if curr_span:
                    curr_span.add_guard(citation_guard_res)

                # Hard Enforcement Graceful Degradation / Fallback
                if not citation_guard_res.passed and citation_guard_res.mode == "ENFORCED":
                    if is_feature_enabled("enable_fallback_on_guard_failure"):
                        if citation_guard_res.failure_category == "CITATION_MISMATCH":
                            hallucinated = citation_guard_res.metadata.get("hallucinated_citations", [])
                            result.answer = sanitize_hallucinated_citations(result.answer, hallucinated)
                            if hasattr(result, "citations") and result.citations:
                                result.citations = [c for c in result.citations if (getattr(c, "chunk_id", None) or getattr(c, "source", None) or str(c)) not in hallucinated]
                            if curr_span:
                                curr_span.status = "FALLBACK"
                                curr_span.metadata["citation_fallback_applied"] = True
                        elif citation_guard_res.failure_category == "UNSUPPORTED_ANSWER_CLAIM":
                            result.answer = (
                                "I could not verify sufficient factual grounding in the retrieved documents to answer this accurately.\n\n"
                                "*(Note: Some specific source citations could not be verified and have been omitted for accuracy.)*"
                            )
                            if curr_span:
                                curr_span.status = "FALLBACK"
                                curr_span.metadata["citation_fallback_applied"] = True

            total_used = budget_ctrl.get_current_usage()
            status_str = "Truncated" if budget_ctrl.counter.is_exceeded else "Success"
            logger.info(
                "Pipeline Complete | Total Tokens: %d | Limit: %d | Status: %s",
                total_used,
                budget_ctrl.max_tokens,
                status_str,
            )
            # Non-blocking background cache update after pipeline completes (strictly requires scope_key)
            if scope_key and query_emb is not None and result is not None and not getattr(result, "error", None):
                ast_passed = getattr(self._sql_retriever, "last_query_status", "success") != "failed"
                asyncio.create_task(
                    asyncio.to_thread(
                        get_semantic_cache().store,
                        question,
                        query_emb,
                        result,
                        scope_key,
                        query_type,
                        ast_passed,
                    )
                )

            return result

    async def query_with_trace(
        self,
        query: str,
        filters: dict | None = None,
        history: list[dict] | None = None,
        mode: str = "auto",
        request_id: str | None = None,
        trace_id: str | None = None,
    ) -> tuple[QueryResult, Trace]:
        """Execute a query wrapped in end-to-end distributed tracing with shadow and enforced guards."""
        trace = start_trace(
            query=query,
            mode=mode,
            request_id=request_id,
            trace_id=trace_id,
        )
        try:
            result = await self.query(question=query, filters=filters, history=history, mode=mode)
            trace.complete(
                status="SUCCESS" if not getattr(result, "error", None) else "FAILED",
                final_response=result.answer[:200] if result and result.answer else "",
            )
            if hasattr(result, "usage") and result.usage:
                trace.record_tokens(result.usage.input_tokens, result.usage.output_tokens)
            emit_trace(trace)
            return result, trace
        except Exception as exc:
            trace.complete(status="FAILED")
            emit_trace(trace)
            raise

    async def query_stream(
        self, question: str, filters: dict | None = None, history: list[dict] | None = None, mode: str = "auto"
    ):
        """Run a full RAG query and yield SSE stream chunks.

        Args:
            question: The user's natural-language question.
            filters: Optional metadata filters (same keys as query()).
            history: Prior conversation turns for follow-up resolution.
            mode: Knowledge source mode: "auto", "sql", "rag", or "mix".
        """
        from typing import AsyncGenerator
        from src.models.schemas import QueryResult

        logger.info("=== Query Stream [%s]: %s ===", mode, question[:100])

        # Short-circuit: document listing question — answer from registry
        if _is_document_listing_query(question) and mode != "sql":
            # ARCH-9: registry reads block; run off the event loop.
            user_id = filters.get("user_id") if filters else None
            answer = await asyncio.to_thread(_build_document_list_answer, user_id)
            yield answer
            yield QueryResult(
                query=question,
                answer=answer,
                model_used="registry",
                reasoning_task="document_listing",
            )
            return

        # Reasoning trace ("thinking") — each step is streamed live to the UI as
        # it happens and collected onto the final QueryResult so it persists.
        thinking: list[ThinkingStep] = []

        def _think(label: str, detail: str = "") -> ThinkingStep:
            step = ThinkingStep(label=label, detail=detail)
            thinking.append(step)
            return step

        # Consult the conversation ONLY when the message looks like a follow-up
        # (see query()) — a self-contained/new-topic question stays stateless so
        # history can't bias it.
        needs_context = bool(history) and _looks_like_followup(question)
        search_query = question
        if needs_context:
            search_query = await _contextualize_query(question, history, self._router)
            if search_query != question:
                logger.info("Contextualized query: '%s' -> '%s'", question, search_query)
                yield _think("Read the conversation", f"resolved to: {search_query}")
        gen_history = history if needs_context else None

        exhaustive = _is_exhaustive_query(search_query)
        if exhaustive:
            logger.info("Exhaustive query detected — boosting top_k and skipping rerank")

        effective_mode = mode
        if mode == "auto":
            effective_mode = _classify_auto_mode(search_query)
            logger.info("Auto-classified query '%s' -> mode '%s'", search_query[:80], effective_mode)

        doc_subquery = search_query
        if effective_mode == "sql":
            yield _think("Understanding the question", "querying live database")
            sql_chunks = await self._sql_retriever.retrieve(search_query)
            vector_chunks = []
            sql_infra_error = self._sql_retriever.last_infra_error
            if sql_chunks:
                sql_match = re.search(r"SQL Query Executed: `(.+?)`", sql_chunks[0].chunk.content)
                sql_detail = sql_match.group(1) if sql_match else "returned matching rows"
                yield _think("Queried the live database", sql_detail)
            elif mode == "auto":
                yield _think("Queried the live database", "no matching rows found in database -- checking documents")
                vector_chunks = await self._retriever.retrieve(
                    search_query,
                    top_k=settings.retrieval_top_k,
                    filters=filters,
                    exhaustive=exhaustive,
                )
                doc_names = list(dict.fromkeys(
                    Path(c.chunk.source_file).name for c in vector_chunks if c.chunk.source_file
                ))
                doc_detail = f"{len(vector_chunks)} passage(s) in {', '.join(doc_names[:3])}" if doc_names else "no matches"
                yield _think("Searched the documents", doc_detail)
            else:
                yield _think("Queried the live database", "no matching rows found in database")
        elif effective_mode == "rag":
            yield _think("Understanding the question", "searching documents")
            sql_chunks = []
            sql_infra_error = None
            vector_chunks = await self._retriever.retrieve(
                search_query,
                top_k=settings.retrieval_top_k,
                filters=filters,
                exhaustive=exhaustive,
            )
            doc_names = list(dict.fromkeys(
                Path(c.chunk.source_file).name for c in vector_chunks if c.chunk.source_file
            ))
            if doc_names:
                shown = ", ".join(doc_names[:3])
                more = f" +{len(doc_names) - 3} more" if len(doc_names) > 3 else ""
                doc_detail = f"{len(vector_chunks)} passage(s) in {shown}{more}"
            else:
                doc_detail = f"{len(vector_chunks)} passage(s)" if vector_chunks else "no matches"
            yield _think("Searched the documents", doc_detail)
        else:
            yield _think("Understanding the question", "checking live database and documents in parallel")
            sql_subquery, doc_subquery = _decompose_hybrid_query(search_query)
            if sql_subquery != search_query or doc_subquery != search_query:
                logger.info("Decomposed hybrid query into SQL: '%s' | DOC: '%s'", sql_subquery, doc_subquery)

            sql_task = asyncio.create_task(self._sql_retriever.retrieve(sql_subquery))

            vector_chunks = await self._retriever.retrieve(
                doc_subquery,
                top_k=settings.retrieval_top_k,
                filters=filters,
                exhaustive=exhaustive,
            )
            doc_names = list(dict.fromkeys(
                Path(c.chunk.source_file).name for c in vector_chunks if c.chunk.source_file
            ))
            if doc_names:
                shown = ", ".join(doc_names[:3])
                more = f" +{len(doc_names) - 3} more" if len(doc_names) > 3 else ""
                doc_detail = f"{len(vector_chunks)} passage(s) in {shown}{more}"
            else:
                doc_detail = f"{len(vector_chunks)} passage(s)" if vector_chunks else "no matches"
            yield _think("Searched the documents", doc_detail)

            sql_chunks = await sql_task
            sql_infra_error = self._sql_retriever.last_infra_error
            if sql_chunks:
                sql_match = re.search(r"SQL Query Executed: `(.+?)`", sql_chunks[0].chunk.content)
                sql_detail = sql_match.group(1) if sql_match else "returned matching rows"
                yield _think("Queried the live database", sql_detail)
            else:
                yield _think("Queried the live database", "no matching rows -- checking documents instead")

        if not vector_chunks and not sql_chunks:
            if sql_infra_error:
                yield _SQL_UNAVAILABLE_MSG
                yield QueryResult(
                    query=question,
                    answer=_SQL_UNAVAILABLE_MSG,
                    model_used="none",
                    reasoning_task="sql_unavailable",
                    thinking=thinking,
                )
                return

            if mode == "sql":
                fallback_msg = "No matching database records found for this query."
            elif mode == "rag":
                fallback_msg = "No relevant documents found. Please upload documents first."
            else:
                db_keywords = ["sales", "order", "delivery", "challan", "stock", "product", "lead", "party", "customer", "vendor", "invoice", "quotation", "production", "carton", "qty", "quantity", "price", "rate", "warehouse"]
                if any(k in question.lower() for k in db_keywords):
                    fallback_msg = "No matching database records found for this query."
                else:
                    fallback_msg = "No relevant documents found. Please upload documents first."

            yield fallback_msg
            yield QueryResult(
                query=question,
                answer=fallback_msg,
                model_used="none",
                reasoning_task="no_results",
                thinking=thinking,
            )
            return

        # Stage 13 — Reranking. SQL chunks NEVER go here — solo or blended.
        rerank_k = settings.rerank_top_k if settings.enable_deep_rerank else min(settings.rerank_top_k, 25)
        if exhaustive or not vector_chunks:
            reranked = _enforce_document_diversity(vector_chunks, rerank_k)
        else:
            reranked = await self._reranker.rerank(doc_subquery, vector_chunks, top_k=rerank_k)
            reranked = _enforce_document_diversity(reranked, rerank_k)
        reranked = [c for c in reranked if c.score is None or c.score >= _MIN_RELEVANCE_SCORE]
        reranked = _pin_sql_result_chunks(reranked, sql_chunks)

        # Documents all filtered as irrelevant and SQL went silent only because
        # its models were unreachable — tell the user that, don't imply the data
        # is missing.
        if not reranked and sql_infra_error:
            yield _SQL_UNAVAILABLE_MSG
            yield QueryResult(
                query=question,
                answer=_SQL_UNAVAILABLE_MSG,
                model_used="none",
                reasoning_task="sql_unavailable",
                thinking=thinking,
            )
            return

        top_source = Path(reranked[0].chunk.source_file).name if reranked and reranked[0].chunk.source_file else None
        rank_detail = f"kept the {len(reranked)} best Ã¢â‚¬â€  top match: {top_source}" if top_source else f"kept the top {len(reranked)}"
        yield _think("Ranked the most relevant sources", rank_detail)
        yield _think("Writing the answer")

        # Stage 14 Ã¢â‚¬â€  Generation. generate_stream yields answer text chunks and,
        # finally, the QueryResult Ã¢â‚¬â€  attach the collected thinking to it and
        # note which provider/model actually answered, so the trace closes out
        # with a real, per-question detail rather than a static label. The
        # user's original question drives the answer; history is included only
        # for genuine follow-ups (gen_history), never forced on new topics.
        # Exhaustive queries keep every reranked chunk; normal queries feed only
        # the top few into the prompt (saves input tokens without hurting quality).
        context_limit = None if exhaustive else settings.generation_context_k
        mode = _source_mode(reranked)
        _log_pipeline_event("routing_decision", {
            "mode": mode,
            "sql_rows": len(sql_chunks),
            "doc_chunks": len(vector_chunks),
            "reranked": len(reranked),
        }, query=question)
        async for chunk in self._generator.generate_stream(
            question, reranked, history=gen_history, context_limit=context_limit, source_mode=mode
        ):
            if isinstance(chunk, QueryResult):
                if chunk.model_used:
                    thinking.append(ThinkingStep(label="Answered using", detail=chunk.model_used))
                chunk.thinking = thinking
            yield chunk

        logger.info("=== Query stream complete ===")


# ---------------------------------------------------------------------------
# Document listing helpers
# ---------------------------------------------------------------------------

_LISTING_KEYWORDS = [
    "what files", "which files", "what documents", "which documents",
    "list files", "list documents", "list all documents", "list all files",
    "list all docs", "show files", "show documents",
    "what have you", "what do you have", "what have you ingested",
    "what documents do you", "what files do you", "documents uploaded",
    "files uploaded", "ingested files", "available documents", "available files",
    "what is in your", "what's in your", "knowledge base",
    # "doc"/"docs" phrasings Ã¢â¬â the colloquial shorthand for the above. Without
    # these, "what docs you have" falls through to RAG retrieval and only
    # describes the handful of chunks that happened to match, contradicting the
    # authoritative registry listing.
    "what docs", "which docs", "list docs", "show docs", "docs do you",
    "docs you have", "available docs", "docs uploaded", "ingested docs",
    # Count-style questions are also answered from the registry, not text-to-SQL.
    "how many documents", "how many docs", "how many files",
]


# A document-listing question is about the assistant's OWN ingested corpus. A
# question scoped to a business entity — a customer's files, invoices per
# product — is a live-data question even when it contains a listing phrase like
# "how many files". Without this guard, "how many files did customer Acme
# upload" substring-matches "how many files" and gets hijacked to the registry
# instead of the SQL path (a "switch to doc" the user never asked for).
_LISTING_ENTITY_SCOPE = re.compile(
    r"\b(customer|client|vendor|supplier|employee|order|invoice|product|"
    r"account|shipment|payment|transaction)s?\b",
    re.IGNORECASE,
)


def _is_document_listing_query(question: str) -> bool:
    """Return True if the question is asking to list the assistant's ingested documents."""
    q = question.lower().strip()
    if not any(kw in q for kw in _LISTING_KEYWORDS):
        return False
    # Scoped to business data → it's a DB question, not a corpus listing.
    if _LISTING_ENTITY_SCOPE.search(q):
        return False
    return True


def _build_document_list_answer(user_id: str | None = None) -> str:
    """Build a human-friendly answer from the ingestion registry."""
    from src.core.ingestion_registry import IngestionRegistry
    import datetime

    registry = IngestionRegistry()
    # Only the current (active) version of each document — superseded versions
    # are history, not part of the live knowledge base.
    entries = registry.get_active(user_id=user_id)

    if not entries:
        if user_id and user_id not in ("*", "all", "anonymous", "admin"):
            return "You do not have access to any documents in the knowledge base. Please ask an administrator to grant you access."
        return "I don't have any documents ingested yet. Please upload some files first."

    lines = [f"I currently have **{len(entries)} document(s)** in my knowledge base:\n"]
    for i, entry in enumerate(entries, 1):
        file_name = entry.get("filename", "Unknown")
        chunks = entry.get("total_chunks", "?")
        ingested_at = entry.get("created_at", "")
        # Format date nicely Ã¢â¬â convert to IST (UTC+5:30)
        try:
            dt = datetime.datetime.fromisoformat(ingested_at)
            ist = datetime.timezone(datetime.timedelta(hours=5, minutes=30))
            dt_ist = dt.astimezone(ist)
            date_str = dt_ist.strftime("%Y-%m-%d %I:%M %p IST")
        except Exception:
            date_str = ingested_at[:10] if ingested_at else "unknown"
        lines.append(f"{i}. **{file_name}** Ã¢â¬â {chunks} chunks (ingested {date_str})")

    return "\n".join(lines)


# ---------------------------------------------------------------------------
# Conversational memory
# ---------------------------------------------------------------------------

_CONTEXTUALIZE_PROMPT = """You rewrite a user's follow-up message into a standalone question, using the conversation ONLY to resolve references that genuinely need it.

Rules:
- If the message depends on the conversation (pronouns like "it"/"that"/"them", or continuations like "compare", "make a table", "the second one", "why is it better"), rewrite it into a self-contained question by pulling in the missing subject from the conversation.
- If the message is ALREADY self-contained, or introduces a NEW topic not discussed above, return it EXACTLY unchanged. Do not force the earlier subject onto an unrelated question.
- Never add facts or assumptions Ã¢â¬â only resolve references.
- Keep it concise. Output ONLY the resulting question Ã¢â¬â no preamble, no quotes.

Conversation:
{history}

Follow-up: {question}

Standalone question:"""


# Cues that a message leans on the prior conversation rather than standing
# alone. Deliberately excludes weak, ubiquitous words ("and", "also") to avoid
# flagging self-contained questions.
_FOLLOWUP_CUES = re.compile(
    r"\b(it|its|it'?s|that|those|these|them|they|the (?:first|second|third|last|other|same|above|previous|former|latter)"
    r"|compare|comparison|vs\.?|versus|make a table|make table|tabulate|chart it|graph it|plot it"
    r"|how about|what about|expand|elaborate|continue|instead|difference|again|rephrase|the rest)\b",
    re.IGNORECASE,
)


def _cache_acl_signature(user_id: str | None) -> str:
    """Cache partition for a user: their id plus a hash of the documents they may read."""
    import hashlib

    if not user_id:
        return "noauth"
    if user_id in ("*", "all", "admin"):
        return "admin"
    from src.core.ingestion_registry import IngestionRegistry

    ids = sorted(e["document_id"] for e in IngestionRegistry().get_active(user_id=user_id))
    return f"{user_id}:{hashlib.sha1(','.join(ids).encode()).hexdigest()[:12]}"


def _looks_like_followup(question: str) -> bool:
    """Heuristic: does this message likely depend on the prior conversation?

    Very short messages and referential/continuation cues suggest a follow-up.
    Anything else is treated as self-contained, so history is never consulted
    and a fresh, unrelated question is answered exactly as it would be with no
    conversation at all Ã¢â¬â no bias toward earlier topics.
    """
    q = question.strip()
    if not q:
        return False
    if len(q.split()) <= 4:
        return True
    return bool(_FOLLOWUP_CUES.search(q))


def _format_history(history: list[dict] | None, *, max_turns: int = 6, max_chars: int = 700) -> str:
    """Compact the last few conversation turns into a plain transcript."""
    if not history:
        return ""
    lines: list[str] = []
    for msg in history[-max_turns:]:
        if msg.get("kind") == "ingestion" or msg.get("status") == "loading":
            continue
        content = (msg.get("content") or "").strip()
        if not content:
            continue
        if msg.get("role") != "user":
            content = sanitize_assistant_turn(content, msg.get("modelUsed"), max_chars=max_chars)
        role = "User" if msg.get("role") == "user" else "Assistant"
        lines.append(f"{role}: {content[:max_chars]}")
    return "\n".join(lines)


async def _contextualize_query(
    question: str, history: list[dict] | None, router: ProviderRouter
) -> str:
    """Rewrite a follow-up into a standalone query for retrieval.

    Without this, a message like "make a table to compare" carries no subject,
    so retrieval matches arbitrary documents instead of continuing the current
    thread. Returns the original question when there's no history or the rewrite
    is unavailable.
    """
    convo = _format_history(history)
    if not convo:
        return question
    try:
        rewritten = await router.chat(
            task="fast_support",
            messages=[
                {"role": "user", "content": _CONTEXTUALIZE_PROMPT.format(history=convo, question=question)},
            ],
            max_tokens=120,
            temperature=0.0,
        )
        rewritten = (rewritten or "").strip().strip('"').strip()
        if rewritten and len(rewritten) <= 400:
            return rewritten
    except Exception as e:
        logger.warning("Query contextualization failed: %s Ã¢â¬â using original question", e)
    return question


# ---------------------------------------------------------------------------
# SQL vs. document routing
# ---------------------------------------------------------------------------
#
# There is deliberately NO upfront SQL-vs-document intent classifier here.
#
# An earlier version routed each question to VECTOR / SQL / BOTH before either
# retrieval path had run, using a keyword pre-filter plus an LLM fallback. That
# was removed (see the "fix intent routing" change) because a pre-guessed intent
# is non-deterministic and misroutes: regenerating the same question could flip
# between a correct document answer and a wrong SQL-only one, and a metric word
# like "total" in a document question would starve it of document context.
#
# QueryPipeline.query()/query_stream() now run BOTH retrieval paths
# unconditionally and concurrently, and let each abstain on its own signal:
#   * SQL abstains via NO_SQL or an empty/no-data result, judged against the
#     REAL schema — far more reliable than guessing before the query runs.
#   * Vector results are dropped below the relevance floor (_MIN_RELEVANCE_SCORE).
# The generator then blends whatever survived (see Generator.generate). This is
# both deterministic and strictly more accurate than the old pre-routing.
