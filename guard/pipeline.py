"""Step 6 — Router / pipeline orchestrator.

Ties the six pipeline stages together:
  - Safe prompts take a fast path (rewrite and validation skipped).
  - Risky prompts enter the remediation loop (rewrite → validate → verify)
    before they can proceed.
  - Every routing decision is appended to ``audit_log`` for traceability.
  - The verification step re-runs the detector on the rewritten prompt to
    confirm disguised-risk signals are gone.

``_LRUCache``
    Thread-safe in-memory LRU cache (default 256 slots) keyed on a SHA-256
    prefix of ``(execute, prompt)``.  Repeated identical prompts — common
    in agentic systems with templated requests — are served at ~0 ms.

``check_async()``
    asyncio wrapper via ``run_in_executor`` for use from FastAPI / aiohttp
    without blocking the event loop.  Results share the same LRU cache.
"""

from __future__ import annotations

import asyncio
import hashlib
import logging
import threading
from collections import OrderedDict
from typing import Optional

from .cache import PIPELINE_VERSION, get_cache, make_key
from .detector import ThreatDetector
from .health import check_strict, format_layer_status, is_degraded, layer_status
from .ingestion import ingest
from .llm import OllamaClient
from .rewriter import SafeRewriter
from .sandbox import SafeSandbox
from .schemas import Category, GuardResult, RewriteStatus, ThreatType
from .semantic import get_matcher
from .validator import validate

log = logging.getLogger("guard.pipeline")

# Threats that must ALWAYS result in a hard block regardless of whether a
# safe rewrite can be generated.  For these, the rewrite is produced for
# user guidance only, but the request itself is NEVER allowed through.
#
# In a production pharma/compliance system, false-safes (letting a risky
# prompt slip through as safe) are far more dangerous than false-blocks.
# Every pharma compliance threat and every explicit bypass/jailbreak signal
# is therefore unconditionally hard-blocked here.
_HARD_BLOCK_THREATS: frozenset[ThreatType] = frozenset({
    # Pharma / clinical compliance — hard-block always
    ThreatType.PII_PHI_EXPOSURE,
    ThreatType.SAFETY_DATA_TAMPERING,
    ThreatType.OFF_LABEL_PROMOTION,
    ThreatType.MISLEADING_CLAIM,
    ThreatType.MEDICAL_ADVICE,
    ThreatType.UNSAFE_TARGETING,
    # Explicit bypass / adversarial framing — hard-block always
    ThreatType.JAILBREAK,
    ThreatType.ROLEPLAY_EXPLOIT,
    ThreatType.HYPOTHETICAL_BYPASS,
    ThreatType.ENCODED_PAYLOAD,
    ThreatType.PROMPT_OVERLOAD,
    # Ingestion-decisive, non-rewriteable (P2-6): like JAILBREAK/ENCODED_PAYLOAD
    # above, this is only ever set by _verdict_from_ingestion as a decisive
    # signal (see P1-5) — there is no safe rewrite for "we cannot reliably
    # analyze this language", so it must hard-block rather than fall through
    # to the remediation loop, where it previously landed on INVALID anyway.
    ThreatType.UNSUPPORTED_LANGUAGE,
})


# ---------------------------------------------------------------------------
# Thread-safe LRU cache
# ---------------------------------------------------------------------------


class _LRUCache:
    """Simple thread-safe LRU cache backed by an ``OrderedDict``.

    Stores and returns independent deep copies of each
    :class:`~guard.schemas.GuardResult` — never the live object a caller
    was handed — so mutating a returned result can never affect what a
    later ``get``/``put`` sees, in either direction.

    Parameters
    ----------
    maxsize:
        Maximum number of entries to keep in the cache.  When the limit is
        reached, the least-recently-used entry is evicted.
    """

    def __init__(self, maxsize: int = 256) -> None:
        self._cache: OrderedDict[str, GuardResult] = OrderedDict()
        self._maxsize = maxsize
        self._lock = threading.Lock()

    def get(self, key: str) -> Optional[GuardResult]:
        with self._lock:
            if key not in self._cache:
                return None
            self._cache.move_to_end(key)
            stored = self._cache[key]
        hit = stored.model_copy(deep=True)
        hit.audit_log.append("cache=lru_hit")
        return hit

    def put(self, key: str, value: GuardResult) -> None:
        stored = value.model_copy(deep=True)
        with self._lock:
            if key in self._cache:
                self._cache.move_to_end(key)
            self._cache[key] = stored
            if len(self._cache) > self._maxsize:
                self._cache.popitem(last=False)  # evict least-recently-used

    def clear(self) -> None:
        with self._lock:
            self._cache.clear()

    def __len__(self) -> int:
        with self._lock:
            return len(self._cache)


# ---------------------------------------------------------------------------
# PromptGuard
# ---------------------------------------------------------------------------


class PromptGuard:
    """The main entry point for the agentic prompt guard.

    Parameters
    ----------
    model:
        Ollama model name to use for LLM-based detection/rewriting.
    use_llm:
        Set to ``False`` to force the deterministic heuristic path (useful
        for testing and offline environments).
    host:
        Ollama HTTP server address.
    cache_size:
        Maximum number of prompt results to keep in the in-memory LRU cache.
        Set to ``0`` to disable caching.
    strict:
        When ``True``, raise :class:`~guard.health.LayerUnavailable` at
        construction time if the LLM (when ``use_llm=True``) or the
        semantic matcher is requested but not actually available, instead
        of silently falling back to a weaker deterministic path. See
        :mod:`guard.health`. Default ``False`` (fail-open, as before).

    Redis cache
    -----------
    If the ``REDIS_URL`` environment variable is set, ``check()`` probes
    Redis *before* the in-memory LRU cache and the Ollama pipeline.  On a
    cache hit the **full** :class:`~guard.schemas.GuardResult` (including
    rationale, threat types, confidence, all sub-verdicts, and audit_log)
    is returned directly without running Ollama.  A
    ``"cache=redis_hit"`` entry is appended to the returned audit_log.

    On a Redis miss the result produced by the live pipeline is stored in
    Redis with the TTL configured by ``CACHE_TTL`` (default 86400 s).
    Redis being unavailable never affects the guard — all errors are caught
    and logged under ``guard.cache``.
    """

    def __init__(
        self,
        model: str = "llama3.2:latest",
        use_llm: bool = True,
        host: str = "http://localhost:11434",
        cache_size: int = 256,
        strict: bool = False,
    ) -> None:
        llm: Optional[OllamaClient] = None
        if use_llm:
            candidate = OllamaClient(model=model, host=host)
            if candidate.available():
                llm = candidate
        self.llm_active = llm is not None
        semantic_active = get_matcher() is not None

        check_strict(
            strict=strict,
            llm_requested=use_llm,
            llm_active=self.llm_active,
            semantic_active=semantic_active,
        )
        self.strict = strict
        self._layer_status = layer_status(
            llm_requested=use_llm,
            llm_active=self.llm_active,
            model=model,
            semantic_active=semantic_active,
            redis_active=get_cache() is not None,
        )
        if not strict and is_degraded(
            llm_requested=use_llm, llm_active=self.llm_active, semantic_active=semantic_active
        ):
            log.warning("guard.pipeline — running with degraded layer(s): %s", self._layer_status)

        self.detector = ThreatDetector(llm)
        self.rewriter = SafeRewriter(llm)
        self.sandbox = SafeSandbox(llm)
        self._cache = _LRUCache(maxsize=cache_size) if cache_size > 0 else None

        # Cache version: PIPELINE_VERSION plus a hash of the config that
        # actually affects detection output (llm on/off, model name), so
        # changing either naturally invalidates every stale cache entry —
        # old results for a different config can never be served as if
        # they came from this one. Shared by both the Redis and LRU caches
        # via guard.cache.make_key, so there is exactly one key scheme.
        config_hash = hashlib.sha256(f"{model}:{self.llm_active}".encode()).hexdigest()[:12]
        self._cache_version = f"{PIPELINE_VERSION}:{config_hash}"

    def health(self) -> dict[str, str]:
        """Return which optional layers (LLM, semantic matcher, Redis
        cache) are active vs. degraded — see :mod:`guard.health`."""
        return dict(self._layer_status)

    # ── Public API ───────────────────────────────────────────────────────

    def check(self, prompt: str, execute: bool = False) -> GuardResult:
        """Screen *prompt* synchronously.

        Lookup order:
          1. **Redis cache** (cross-process, TTL-backed) — returns the full
             :class:`~guard.schemas.GuardResult` on a hit, with a
             ``"cache=redis_hit"`` entry appended to ``audit_log``.
          2. **In-memory LRU cache** (per-process, unbounded by time) — fast
             path for repeated calls within the same process lifetime.
          3. **Live pipeline** — Ollama → heuristics as before.

        Parameters
        ----------
        prompt:
            The user prompt to evaluate.
        execute:
            When ``True``, run the validated prompt through the safe execution
            sandbox and include the response in the returned :class:`GuardResult`.

        Returns
        -------
        :class:`~guard.schemas.GuardResult`
            Full decision record including category, allowed/blocked verdict,
            rewrite (if any), and an append-only ``audit_log``.
        """
        version = self._cache_version

        # ── Layer 1: Redis distributed cache ─────────────────────────────
        _redis = get_cache()
        if _redis is not None:
            redis_hit = _redis.get(prompt, execute, version)
            if redis_hit is not None:
                return redis_hit

        # ── Layer 2: In-process LRU cache ────────────────────────────────
        key = make_key(prompt, execute, version)
        if self._cache is not None:
            cached = self._cache.get(key)
            if cached is not None:
                return cached

        # ── Layer 3: Full pipeline ────────────────────────────────────────
        result = self._check_impl(prompt, execute)

        # Store in Redis (full GuardResult JSON, TTL-backed).
        if _redis is not None:
            _redis.set(prompt, result, execute, version)

        # Store in local LRU.
        if self._cache is not None:
            self._cache.put(key, result)

        return result

    async def check_async(self, prompt: str, execute: bool = False) -> GuardResult:
        """Asyncio-compatible screen — runs in the default thread-pool executor.

        Safe to ``await`` from FastAPI, aiohttp, or any ``asyncio`` service
        without blocking the event loop.  Results are served from / stored to
        the same LRU cache as :meth:`check`.

        Usage example::

            guard = PromptGuard()
            result = await guard.check_async("Write a compliant report...")
        """
        loop = asyncio.get_running_loop()
        return await loop.run_in_executor(None, self.check, prompt, execute)

    # ── Internal pipeline implementation ─────────────────────────────────

    def _check_impl(self, prompt: str, execute: bool) -> GuardResult:
        log: list[str] = []
        backend = "ollama" if self.llm_active else "heuristic-fallback"
        log.append(f"backend={backend}")
        log.append(format_layer_status(self._layer_status))

        # Step 1: ingestion.
        ing = ingest(prompt)
        log.append(
            f"ingest: signatures={len(ing.signature_hits)} "
            f"decoded={len(ing.decoded_payloads)} "
            f"similarity={ing.similarity:.3f} "
            f"homoglyph={ing.homoglyph_detected} "
            f"leetspeak={ing.leetspeak_detected} "
            f"whitespace_injection={ing.whitespace_injection_detected} "
            f"-> flagged={ing.flagged}"
        )

        # Step 2: detection.
        verdict = self.detector.detect(prompt, ing)
        log.append(
            f"detect: is_safe={verdict.is_safe} "
            f"category={verdict.category.value} "
            f"threats={[t.value for t in verdict.threat_types]} "
            f"confidence={verdict.confidence:.3f}"
        )

        # Fast path: safe prompts skip steps 3 & 4 entirely.
        if verdict.is_safe:
            log.append("route=fast_path (skip rewrite & validation)")
            result = GuardResult(
                prompt=prompt,
                allowed=True,
                category=verdict.category,
                path="fast_path",
                detector=verdict,
                effective_prompt=ing.normalized,
                audit_log=log,
            )
            return self._maybe_execute(result, execute)

        # Hard-block threats: blocked unconditionally — no rewrite can rescue them.
        # We still run the rewriter to produce a safe-alternative suggestion so the
        # UI can show "what you should have asked instead", but allowed stays False.
        original_hard_block = _HARD_BLOCK_THREATS.intersection(
            set(verdict.threat_types)
        )
        if original_hard_block:
            blocked_names = ", ".join(t.value for t in original_hard_block)
            log.append(
                f"blocked: hard-block threat(s) detected — {blocked_names}"
            )
            # Generate a safe-alternative rewrite for user guidance only.
            log.append("route=remediation (guidance rewrite only — request blocked)")
            guidance_rewrite = self.rewriter.rewrite(ing.normalized, verdict)
            log.append(f"rewrite: status={guidance_rewrite.status.value}")
            return GuardResult(
                prompt=prompt,
                allowed=False,
                category=Category.RISKY,
                path="blocked",
                detector=verdict,
                rewrite=guidance_rewrite,
                audit_log=log,
            )

        # Remediation loop — step 3: rewrite.
        log.append("route=remediation")
        rewrite = self.rewriter.rewrite(ing.normalized, verdict)
        log.append(f"rewrite: status={rewrite.status.value}")

        if rewrite.status in (RewriteStatus.INVALID, RewriteStatus.NEEDS_CLARIFICATION):
            log.append("blocked: no executable rewrite")
            return GuardResult(
                prompt=prompt,
                allowed=False,
                category=Category.RISKY,
                path="blocked",
                detector=verdict,
                rewrite=rewrite,
                audit_log=log,
            )

        # Step 4: deterministic validation.
        validation = validate(rewrite,verdict)
        log.append(f"validate: passed={validation.passed} reasons={validation.reasons}")
        if not validation.passed:
            log.append("blocked: validation failed")
            return GuardResult(
                prompt=prompt,
                allowed=False,
                category=Category.RISKY,
                path="blocked",
                detector=verdict,
                rewrite=rewrite,
                validation=validation,
                audit_log=log,
            )

        # Verification step: re-run the detector on the rewrite.
        # A rewrite that still carries risk signals is blocked even if it
        # passed the deterministic validator.
        verification = self.detector.detect(
            rewrite.rewritten_prompt, ingest(rewrite.rewritten_prompt)
        )
        log.append(
            f"verify: is_safe={verification.is_safe} "
            f"threats={[t.value for t in verification.threat_types]}"
        )
        if not verification.is_safe:
            log.append("blocked: rewrite still carries risk signals")
            return GuardResult(
                prompt=prompt,
                allowed=False,
                category=Category.RISKY,
                path="blocked",
                detector=verdict,
                rewrite=rewrite,
                validation=validation,
                verification=verification,
                audit_log=log,
            )

        log.append("allowed: rewrite passed validation and verification")
        result = GuardResult(
            prompt=prompt,
            allowed=True,
            category=Category.RESPONSIBLE,
            path="remediation",
            detector=verdict,
            rewrite=rewrite,
            validation=validation,
            verification=verification,
            effective_prompt=rewrite.rewritten_prompt,
            audit_log=log,
        )
        return self._maybe_execute(result, execute)

    def _maybe_execute(self, result: GuardResult, execute: bool) -> GuardResult:
        if execute and result.allowed and result.effective_prompt:
            result.sandbox = self.sandbox.execute(result.effective_prompt)
            result.audit_log.append(
                f"sandbox: output_filtered={result.sandbox.output_filtered} "
                f"items={result.sandbox.filtered_items}"
            )
        return result
