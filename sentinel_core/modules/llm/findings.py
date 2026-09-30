from __future__ import annotations

import json
import re
from hashlib import sha256
from typing import Any

from sqlalchemy.ext.asyncio import AsyncSession

from sentinel_core.modules.test_executor.evidence import evidence_digest
from sentinel_core.modules.utils.redactor import Redactor
from sentinel_core.modules.vulnerability_detector.store import create_or_merge_vulnerability

_LLM_PATH_HINTS = (
    "/chat",
    "/completions",
    "/responses",
    "/generate",
    "/prompt",
    "/llm",
    "/ai/",
    "/agent",
    "/assistant",
    "/model",
)
_LLM_BODY_KEYS = {"prompt", "messages", "input", "model", "tools", "instructions", "system", "assistant"}
_PROMPT_INJECTION_PATTERNS = (
    re.compile(r"ignore\s+(all\s+)?previous\s+instructions", re.I),
    re.compile(
        r"\b(reveal|print|show|dump)\b.{0,80}\b(system\s+prompt|developer\s+message|hidden\s+instructions|"
        r"credentials?|secrets?|tokens?|api[_ -]?keys?|passwords?)\b",
        re.I,
    ),
    re.compile(
        r"\b(system\s+prompt|developer\s+message|hidden\s+instructions|credentials?|secrets?|tokens?|"
        r"api[_ -]?keys?|passwords?)\b.{0,80}\b(reveal|print|show|dump)\b",
        re.I,
    ),
    re.compile(r"system\s+prompt|developer\s+message|hidden\s+instructions", re.I),
    re.compile(r"jailbreak|DAN\s+mode|bypass\s+safety|disregard\s+your\s+instructions", re.I),
    re.compile(r"exfiltrate|send\s+.*credentials|steal\s+.*token|leak\s+.*api[_ -]?key", re.I),
)
_SYSTEM_LEAK_PATTERNS = (
    re.compile(r"BEGIN\s+SYSTEM\s+PROMPT|END\s+SYSTEM\s+PROMPT", re.I),
    re.compile(r"\bsystem:\s*(you are|do not|never|always)", re.I),
    re.compile(r"\bdeveloper:\s*(you are|do not|never|always)", re.I),
    re.compile(r"hidden\s+instructions\s+are|internal\s+instructions\s+are", re.I),
    re.compile(r"confidential\s+(system|developer)\s+(prompt|instructions)", re.I),
)
_SECRET_PATTERNS = (
    re.compile(r"\b(Bearer|Basic)\s+[A-Za-z0-9._~+/=-]{12,}", re.I),
    re.compile(r"\bsk-[A-Za-z0-9]{20,}\b"),
    re.compile(r"\b[A-Za-z0-9_-]{10,}\.[A-Za-z0-9_-]{10,}\.[A-Za-z0-9_-]{10,}\b"),
    re.compile(r"(?i)\b(api[_-]?key|secret|token|password)\b\s*[:=]\s*['\"]?[^'\"\s,&;]{8,}"),
)
_DANGEROUS_TOOL_PATTERNS = (
    (
        "shell_or_process_execution",
        re.compile(
            r"\b(shell|bash|powershell|cmd|terminal|process|spawn|exec(?:ute)?|subprocess|system)"
            r"([._ -]?(run|exec|command|call))?\b",
            re.I,
        ),
    ),
    (
        "secret_file_read",
        re.compile(
            r"(\.aws[\\/]+credentials|\.ssh[\\/]+id_rsa|\.env\b|/etc/(shadow|passwd)|"
            r"serviceaccount[\\/]+token|secrets?[\\/]+[^,\s\"']+|credentials?\b)",
            re.I,
        ),
    ),
    (
        "metadata_or_private_http_fetch",
        re.compile(
            r"https?://("
            r"169\.254\.169\.254|metadata\.google\.internal|metadata\.azure\.com|"
            r"localhost|127(?:\.\d{1,3}){3}|0\.0\.0\.0|10(?:\.\d{1,3}){3}|"
            r"192\.168(?:\.\d{1,3}){2}|172\.(1[6-9]|2\d|3[01])(?:\.\d{1,3}){2}"
            r")\b",
            re.I,
        ),
    ),
    (
        "credential_exfiltration_language",
        re.compile(
            r"\b(exfiltrate|send|post|upload|leak|steal|forward)\b.{0,80}"
            r"\b(credentials?|secrets?|tokens?|api[_ -]?keys?|passwords?|bearer)\b",
            re.I,
        ),
    ),
)
_PRIVILEGE_ESCALATION_TOOL_PATTERNS = (
    (
        "privileged_role_assignment",
        re.compile(
            r"("
            r"\b(grant|assign|set|update|elevate|escalate)[._ -]?"
            r"(role|permission|scope|privilege|admin|owner|superuser)\b"
            r"|"
            r"\b(iam|rbac|role|roles|permission|permissions|scope|scopes|privilege|privileges)\b.{0,120}"
            r"\b(admin|owner|root|superuser|all[_ -]?access)\b"
            r")",
            re.I,
        ),
    ),
    (
        "privileged_scope_minting",
        re.compile(
            r"\b(oauth|oidc|jwt|session|token|scope|scopes|permission|permissions)\b.{0,120}"
            r"\b(admin|owner|root|superuser)\s*[:*]",
            re.I,
        ),
    ),
    (
        "identity_or_tenant_impersonation",
        re.compile(
            r"\b(impersonate|act[_ -]?as|sudo|assume[_ -]?role|switch[_ -]?tenant|"
            r"tenant[_ -]?override|cross[_ -]?tenant)\b",
            re.I,
        ),
    ),
    (
        "sensitive_action_approval",
        re.compile(
            r"\b(approve|override|bypass|force)[._ -]?"
            r"(refund|payment|transfer|withdrawal|payout|coupon|credit|approval)\b"
            r"|"
            r"\b(refund|payment|transfer|withdrawal|payout|coupon|credit)\b.{0,80}"
            r"\b(approve|override|bypass|force)\b",
            re.I,
        ),
    ),
)
_RAG_SURFACE_KEYS = {
    "retrieved_context",
    "retrieved_documents",
    "source_documents",
    "source_docs",
    "citations",
    "references",
    "chunks",
    "page_content",
}
_UNTRUSTED_CONTEXT_SURFACE_KEYS = _RAG_SURFACE_KEYS | {
    "context_documents",
    "tool_output",
    "tool_outputs",
    "tool_result",
    "tool_results",
    "tool_observation",
    "observations",
}
_TOOL_OUTPUT_SURFACE_KEYS = {
    "tool_output",
    "tool_outputs",
    "tool_result",
    "tool_results",
    "tool_observation",
    "tool_observations",
    "tool_response",
    "tool_responses",
    "function_result",
    "function_results",
    "observations",
}
_TOOL_INVOCATION_SURFACE_KEYS = _TOOL_OUTPUT_SURFACE_KEYS | {
    "arguments",
    "function",
    "function_call",
    "function_calls",
    "name",
    "tool_call",
    "tool_calls",
}
_RAG_EXFILTRATION_PATTERNS = (
    re.compile(
        r"\b(dump|reveal|print|show|quote|return|export)\b.{0,100}"
        r"\b(retrieved|source|internal|private|confidential|document|documents|knowledge\s*base|rag|vector)\b",
        re.I,
    ),
    re.compile(
        r"\b(retrieved|source|internal|private|confidential|document|documents|knowledge\s*base|rag|vector)\b"
        r".{0,100}\b(dump|reveal|print|show|quote|return|export)\b",
        re.I,
    ),
)
_RAG_SENSITIVE_PATTERNS = (
    re.compile(r"\b\d{3}-\d{2}-\d{4}\b"),
    re.compile(r"\b(?:\d[ -]*?){13,19}\b"),
    re.compile(r"\b(confidential|internal|private)\s+(customer|document|record|knowledge|context)\b", re.I),
)
_REFUSAL_PATTERNS = (
    re.compile(r"\b(can't|cannot|won't|unable to)\b.*\b(system prompt|instructions|credentials|secrets)\b", re.I),
    re.compile(r"\bI (can'?t|cannot|won'?t) comply\b", re.I),
)
_PERSISTED_SIGNAL_REQUIRED_EVIDENCE = {
    "LLM_RAG_EXFILTRATION": [
        "retrieval_context_sha256",
        "retrieval_context_surface_keys",
    ],
    "LLM_INDIRECT_PROMPT_INJECTION": [
        "untrusted_context_sha256",
        "untrusted_context_surface_keys",
    ],
    "LLM_TOOL_OUTPUT_SECRET_EXPOSURE": [
        "tool_context_sha256",
        "tool_context_surface_keys",
    ],
    "LLM_DANGEROUS_TOOL_INVOCATION": [
        "tool_invocation_sha256",
        "tool_invocation_surface_keys",
    ],
    "LLM_PRIVILEGE_ESCALATING_TOOL_INVOCATION": [
        "tool_invocation_sha256",
        "tool_invocation_surface_keys",
    ],
    "LLM_TOOL_CHAIN_PROMPT_INJECTION": [
        "untrusted_context_sha256",
        "untrusted_context_surface_keys",
        "tool_context_sha256",
        "tool_context_surface_keys",
        "tool_invocation_sha256",
        "tool_invocation_surface_keys",
    ],
}
_PERSISTED_RETRIEVAL_CONTEXT_SIGNALS = {"LLM_RAG_EXFILTRATION"}
_PERSISTED_UNTRUSTED_CONTEXT_SIGNALS = {
    "LLM_INDIRECT_PROMPT_INJECTION",
    "LLM_TOOL_CHAIN_PROMPT_INJECTION",
}
_PERSISTED_TOOL_CONTEXT_SIGNALS = {
    "LLM_TOOL_OUTPUT_SECRET_EXPOSURE",
    "LLM_TOOL_CHAIN_PROMPT_INJECTION",
}
_PERSISTED_TOOL_INVOCATION_SIGNALS = {
    "LLM_DANGEROUS_TOOL_INVOCATION",
    "LLM_PRIVILEGE_ESCALATING_TOOL_INVOCATION",
    "LLM_TOOL_CHAIN_PROMPT_INJECTION",
}


def _text(value: Any, *, default: str = "") -> str:
    text = str(value or default).strip()
    return text or default


def _truncate(value: Any, limit: int) -> str:
    return _text(value)[:limit]


def _slug(value: Any) -> str:
    return re.sub(r"[^a-z0-9]+", "-", _text(value, default="unknown").lower()).strip("-")[:80] or "unknown"


def _flatten_text(value: Any, *, limit: int = 20000) -> str:
    parts: list[str] = []

    def walk(item: Any) -> None:
        if sum(len(part) for part in parts) > limit:
            return
        if item is None:
            return
        if isinstance(item, dict):
            for key, val in item.items():
                parts.append(str(key))
                walk(val)
            return
        if isinstance(item, list):
            for val in item:
                walk(val)
            return
        parts.append(str(item))

    walk(value)
    return " ".join(parts)[:limit]


def _safe_body_fingerprint(value: Any) -> str | None:
    text = Redactor.redact_text(_flatten_text(value))
    if not text:
        return None
    return sha256(text.encode("utf-8")).hexdigest()


def _safe_body_length(value: Any) -> int:
    return len(_flatten_text(value))


def summarize_agentic_violation_details(details: dict[str, Any] | None) -> dict[str, Any]:
    """Keep agentic violation evidence useful without persisting prompt/tool content."""
    raw_details = details or {}
    redacted_details = Redactor.redact_json(raw_details)
    detail_keys = sorted(str(key) for key in raw_details.keys()) if isinstance(raw_details, dict) else []
    summary: dict[str, Any] = {
        "detail_keys": detail_keys[:20],
        "details_sha256": _safe_body_fingerprint(redacted_details),
        "details_content_persisted": False,
    }

    excess_scope = raw_details.get("excess_scope") if isinstance(raw_details, dict) else None
    if isinstance(excess_scope, list):
        summary["excess_scope_count"] = len(excess_scope)
        summary["excess_scope"] = [
            Redactor.redact_text(_truncate(item, 120))
            for item in excess_scope[:20]
        ]

    match = raw_details.get("match") if isinstance(raw_details, dict) else None
    if match:
        summary["matched_text_sha256"] = _safe_body_fingerprint(match)
        summary["matched_text_length"] = _safe_body_length(match)
        summary["matched_text_persisted"] = False

    return summary


def _finalize_evidence(evidence: dict[str, Any]) -> dict[str, Any]:
    payload = dict(evidence)
    payload["hash_algorithm"] = "sha256"
    payload["evidence_hash"] = evidence_digest(payload)
    return payload


def _content_minimization_policy(*, surface: str) -> dict[str, Any]:
    if surface == "agentic_mcp":
        return {
            "raw_tool_details_persisted": False,
            "matched_text_persisted": False,
            "secret_values_persisted": False,
            "persisted_material": ["metadata", "redacted_scope", "sha256_digests", "lengths"],
        }
    return {
        "raw_request_body_persisted": False,
        "raw_response_body_persisted": False,
        "matched_text_persisted": False,
        "secret_values_persisted": False,
        "persisted_material": ["metadata", "sha256_digests", "lengths"],
    }


def _evidence_field_missing(value: Any) -> bool:
    return value is None or value == "" or value == [] or value == {}


def _deterministic_judge_validation(
    *,
    validator: str,
    surface: str,
    evidence: dict[str, Any],
    required_evidence: list[str],
) -> dict[str, Any]:
    missing_evidence = [
        field
        for field in required_evidence
        if field not in evidence or _evidence_field_missing(evidence.get(field))
    ]
    deterministic = not missing_evidence
    return {
        "validator": validator,
        "surface": surface,
        "deterministic_evidence": deterministic,
        "confirmed": False,
        "finding_status": "UNCONFIRMED",
        "promotion_decision": (
            "promote_unconfirmed_finding" if deterministic else "hold_for_review"
        ),
        "required_evidence": required_evidence,
        "missing_evidence": missing_evidence,
        "confirmation_required": True,
    }


def _required_evidence_for_persisted_signal(signal_type: str) -> list[str]:
    required = [
        "body_content_persisted",
        "content_minimization",
        "matched_text_sha256",
        "request_body_sha256",
        "response_body_sha256",
        "signal_type",
    ]
    required.extend(_PERSISTED_SIGNAL_REQUIRED_EVIDENCE.get(signal_type, []))
    return _dedupe(required)


def _dedupe(values: list[str]) -> list[str]:
    seen: set[str] = set()
    deduped: list[str] = []
    for value in values:
        if value in seen:
            continue
        seen.add(value)
        deduped.append(value)
    return deduped


def _matched_text_summary(matches: Any) -> dict[str, Any]:
    match_list = matches if isinstance(matches, list) else ([matches] if matches else [])
    return {
        "matched_text_sha256": _safe_body_fingerprint(match_list),
        "matched_text_count": len(match_list),
        "matched_text_length": _safe_body_length(match_list),
        "matched_text_persisted": False,
    }


def _public_signal_summary(signal: dict[str, Any]) -> dict[str, Any]:
    summary = {
        "signal_type": _text(signal.get("signal_type"), default="LLM_SECURITY"),
        "severity": _text(signal.get("severity"), default="HIGH").upper(),
        "confidence": _text(signal.get("confidence"), default="MEDIUM").upper(),
        "description": _text(signal.get("description"), default="LLM security signal detected."),
        **_matched_text_summary(signal.get("matched_text")),
    }
    if "response_refused" in signal:
        summary["response_refused"] = bool(signal.get("response_refused"))
    if "retrieval_context_present" in signal:
        summary["retrieval_context_present"] = bool(signal.get("retrieval_context_present"))
    if "untrusted_context_present" in signal:
        summary["untrusted_context_present"] = bool(signal.get("untrusted_context_present"))
    if "tool_context_present" in signal:
        summary["tool_context_present"] = bool(signal.get("tool_context_present"))
    if "context_surface_keys" in signal:
        summary["context_surface_keys"] = [
            Redactor.redact_text(_truncate(item, 80))
            for item in (signal.get("context_surface_keys") or [])[:20]
        ]
    exploit_chain = _safe_exploit_chain(signal.get("exploit_chain"))
    if exploit_chain:
        summary["exploit_chain"] = exploit_chain
    return summary


def _has_llm_body_key(value: Any) -> bool:
    if isinstance(value, dict):
        if any(str(key).lower() in _LLM_BODY_KEYS for key in value):
            return True
        return any(_has_llm_body_key(item) for item in value.values())
    if isinstance(value, list):
        return any(_has_llm_body_key(item) for item in value[:10])
    if isinstance(value, str):
        try:
            return _has_llm_body_key(json.loads(value))
        except Exception:
            return False
    return False


def _has_tool_invocation_evidence(value: Any) -> bool:
    if isinstance(value, dict):
        lowered_keys = {str(key).lower() for key in value}
        if lowered_keys & {"tool_calls", "function_call"}:
            return True
        if {"name", "arguments"}.issubset(lowered_keys):
            return True
        if str(value.get("type", "")).lower() in {"function", "function_call", "tool_call"}:
            return True
        return any(_has_tool_invocation_evidence(item) for item in value.values())
    if isinstance(value, list):
        return any(_has_tool_invocation_evidence(item) for item in value[:20])
    if isinstance(value, str):
        lowered = value.lower()
        return "tool_calls" in lowered or "function_call" in lowered
    return False


def _rag_surface_hits(value: Any) -> list[str]:
    hits: set[str] = set()

    def walk(item: Any) -> None:
        if isinstance(item, dict):
            for key, val in item.items():
                key_text = str(key).lower()
                if key_text in _RAG_SURFACE_KEYS:
                    hits.add(key_text)
                walk(val)
            return
        if isinstance(item, list):
            for val in item[:20]:
                walk(val)
            return
        if isinstance(item, str):
            lowered = item.lower()
            for marker in ("retrieved context", "source document", "citation", "knowledge base"):
                if marker in lowered:
                    hits.add(marker.replace(" ", "_"))

    walk(value)
    return sorted(hits)


def _untrusted_context_surface(value: Any) -> tuple[list[str], str]:
    hits: set[str] = set()
    parts: list[str] = []

    def walk(item: Any, *, in_untrusted_context: bool = False) -> None:
        if sum(len(part) for part in parts) > 20000:
            return
        if isinstance(item, dict):
            for key, val in item.items():
                key_text = str(key).lower()
                nested_untrusted = in_untrusted_context or key_text in _UNTRUSTED_CONTEXT_SURFACE_KEYS
                if key_text in _UNTRUSTED_CONTEXT_SURFACE_KEYS:
                    hits.add(key_text)
                walk(val, in_untrusted_context=nested_untrusted)
            return
        if isinstance(item, list):
            for val in item[:20]:
                walk(val, in_untrusted_context=in_untrusted_context)
            return
        if in_untrusted_context and item is not None:
            parts.append(str(item))

    walk(value)
    return sorted(hits), " ".join(parts)[:20000]


def _tool_output_surface(value: Any) -> tuple[list[str], str]:
    hits: set[str] = set()
    parts: list[str] = []

    def walk(item: Any, *, in_tool_context: bool = False) -> None:
        if sum(len(part) for part in parts) > 20000:
            return
        if isinstance(item, dict):
            for key, val in item.items():
                key_text = str(key).lower()
                nested_tool_context = in_tool_context or key_text in _TOOL_OUTPUT_SURFACE_KEYS
                if key_text in _TOOL_OUTPUT_SURFACE_KEYS:
                    hits.add(key_text)
                walk(val, in_tool_context=nested_tool_context)
            return
        if isinstance(item, list):
            for val in item[:20]:
                walk(val, in_tool_context=in_tool_context)
            return
        if in_tool_context and item is not None:
            parts.append(str(item))

    walk(value)
    return sorted(hits), " ".join(parts)[:20000]


def _tool_invocation_surface(value: Any) -> tuple[list[str], str]:
    hits: set[str] = set()
    parts: list[str] = []

    def walk(item: Any, *, in_tool_context: bool = False) -> None:
        if sum(len(part) for part in parts) > 20000:
            return
        if isinstance(item, dict):
            for key, val in item.items():
                key_text = str(key).lower()
                nested_tool_context = in_tool_context or key_text in _TOOL_INVOCATION_SURFACE_KEYS
                if key_text in _TOOL_INVOCATION_SURFACE_KEYS:
                    hits.add(key_text)
                walk(val, in_tool_context=nested_tool_context)
            return
        if isinstance(item, list):
            for val in item[:20]:
                walk(val, in_tool_context=in_tool_context)
            return
        if in_tool_context and item is not None:
            parts.append(str(item))

    walk(value)
    return sorted(hits), " ".join(parts)[:20000]


def _surface_text(value: Any, surface_keys: set[str], *, limit: int = 20000) -> tuple[list[str], str]:
    hits: set[str] = set()
    parts: list[str] = []

    def walk(item: Any, *, in_surface: bool = False) -> None:
        if sum(len(part) for part in parts) > limit:
            return
        if isinstance(item, dict):
            for key, val in item.items():
                key_text = str(key).lower()
                nested_surface = in_surface or key_text in surface_keys
                if key_text in surface_keys:
                    hits.add(key_text)
                walk(val, in_surface=nested_surface)
            return
        if isinstance(item, list):
            for val in item[:20]:
                walk(val, in_surface=in_surface)
            return
        if in_surface and item is not None:
            parts.append(str(item))

    walk(value)
    return sorted(hits), " ".join(parts)[:limit]


def _persisted_signal_context_evidence(signal_type: str, response_body: Any) -> dict[str, Any]:
    evidence: dict[str, Any] = {}
    if signal_type in _PERSISTED_RETRIEVAL_CONTEXT_SIGNALS:
        retrieval_keys, retrieval_text = _surface_text(response_body, _RAG_SURFACE_KEYS)
        evidence.update(
            {
                "retrieval_context_sha256": _safe_body_fingerprint(retrieval_text),
                "retrieval_context_surface_keys": retrieval_keys,
            }
        )
    if signal_type in _PERSISTED_UNTRUSTED_CONTEXT_SIGNALS:
        untrusted_keys, untrusted_text = _untrusted_context_surface(response_body)
        evidence.update(
            {
                "untrusted_context_sha256": _safe_body_fingerprint(untrusted_text),
                "untrusted_context_surface_keys": untrusted_keys,
            }
        )
    if signal_type in _PERSISTED_TOOL_CONTEXT_SIGNALS:
        tool_context_keys, tool_context_text = _tool_output_surface(response_body)
        evidence.update(
            {
                "tool_context_sha256": _safe_body_fingerprint(tool_context_text),
                "tool_context_surface_keys": tool_context_keys,
            }
        )
    if signal_type in _PERSISTED_TOOL_INVOCATION_SIGNALS:
        tool_invocation_keys, tool_invocation_text = _tool_invocation_surface(response_body)
        evidence.update(
            {
                "tool_invocation_sha256": _safe_body_fingerprint(tool_invocation_text),
                "tool_invocation_surface_keys": tool_invocation_keys,
            }
        )
    return evidence


def is_likely_llm_interaction(
    *,
    path: str | None = None,
    request_body: Any = None,
    response_body: Any = None,
) -> bool:
    lowered_path = _text(path).lower()
    if any(hint in lowered_path for hint in _LLM_PATH_HINTS):
        return True
    return _has_llm_body_key(request_body) or _has_llm_body_key(response_body)


def _matches(patterns: tuple[re.Pattern, ...], text: str) -> list[str]:
    hits: list[str] = []
    for pattern in patterns:
        match = pattern.search(text)
        if match:
            hits.append(match.group(0)[:200])
    return hits


def _dangerous_tool_hits(text: str) -> list[str]:
    hits: list[str] = []
    for label, pattern in _DANGEROUS_TOOL_PATTERNS:
        if pattern.search(text):
            hits.append(label)
    return hits


def _privilege_escalating_tool_hits(text: str) -> list[str]:
    hits: list[str] = []
    for label, pattern in _PRIVILEGE_ESCALATION_TOOL_PATTERNS:
        if pattern.search(text):
            hits.append(label)
    return hits


def _safe_exploit_chain(value: Any) -> dict[str, bool]:
    if not isinstance(value, dict):
        return {}
    allowed_keys = (
        "untrusted_tool_output_prompt_injection",
        "dangerous_tool_invocation",
        "privilege_escalating_tool_invocation",
    )
    return {key: bool(value.get(key)) for key in allowed_keys if key in value}


def _is_refusal(text: str) -> bool:
    return bool(_matches(_REFUSAL_PATTERNS, text))


def detect_llm_api_signals(
    *,
    path: str | None = None,
    request_body: Any = None,
    response_body: Any = None,
) -> list[dict[str, Any]]:
    if not is_likely_llm_interaction(path=path, request_body=request_body, response_body=response_body):
        return []

    request_text = _flatten_text(request_body)
    response_text = _flatten_text(response_body)
    request_hits = _matches(_PROMPT_INJECTION_PATTERNS, request_text)
    system_leak_hits = _matches(_SYSTEM_LEAK_PATTERNS, response_text)
    secret_hits = _matches(_SECRET_PATTERNS, response_text)
    rag_exfil_hits = _matches(_RAG_EXFILTRATION_PATTERNS, request_text)
    rag_sensitive_hits = [*_matches(_RAG_SENSITIVE_PATTERNS, response_text), *secret_hits]
    rag_surface_hits = _rag_surface_hits(response_body)
    untrusted_context_keys, untrusted_context_text = _untrusted_context_surface(response_body)
    indirect_prompt_hits = _matches(_PROMPT_INJECTION_PATTERNS, untrusted_context_text)
    tool_context_keys, tool_context_text = _tool_output_surface(response_body)
    tool_invocation_keys, tool_invocation_text = _tool_invocation_surface(response_body)
    tool_secret_hits = _matches(_SECRET_PATTERNS, tool_context_text)
    dangerous_tool_hits = _dangerous_tool_hits(response_text) if _has_tool_invocation_evidence(response_body) else []
    privilege_tool_hits = (
        _privilege_escalating_tool_hits(tool_invocation_text)
        if _has_tool_invocation_evidence(response_body)
        else []
    )
    response_refused = _is_refusal(response_text)
    signals: list[dict[str, Any]] = []

    if rag_surface_hits and rag_exfil_hits and rag_sensitive_hits and not response_refused:
        signals.append(
            {
                "signal_type": "LLM_RAG_EXFILTRATION",
                "severity": "HIGH",
                "confidence": "HIGH",
                "matched_text": [*rag_exfil_hits[:2], *rag_sensitive_hits[:3], *rag_surface_hits[:4]],
                "retrieval_context_present": True,
                "description": (
                    "LLM response appears to disclose sensitive retrieval-augmented context."
                ),
            }
        )

    if untrusted_context_keys and indirect_prompt_hits:
        signals.append(
            {
                "signal_type": "LLM_INDIRECT_PROMPT_INJECTION",
                "severity": "HIGH",
                "confidence": "MEDIUM",
                "matched_text": [*indirect_prompt_hits[:3], *untrusted_context_keys[:4]],
                "retrieval_context_present": bool(rag_surface_hits),
                "untrusted_context_present": True,
                "context_surface_keys": untrusted_context_keys[:20],
                "description": (
                    "LLM retrieval or tool context contains prompt-injection instructions before model output."
                ),
            }
        )

    if tool_context_keys and tool_secret_hits:
        signals.append(
            {
                "signal_type": "LLM_TOOL_OUTPUT_SECRET_EXPOSURE",
                "severity": "CRITICAL",
                "confidence": "HIGH",
                "matched_text": [*tool_secret_hits[:3], *tool_context_keys[:4]],
                "tool_context_present": True,
                "untrusted_context_present": True,
                "context_surface_keys": tool_context_keys[:20],
                "description": (
                    "LLM tool output appears to contain credentials, tokens, or other secret material."
                ),
            }
        )

    if tool_context_keys and indirect_prompt_hits and (dangerous_tool_hits or privilege_tool_hits):
        context_surface_keys = sorted({*tool_context_keys, *tool_invocation_keys})
        signals.append(
            {
                "signal_type": "LLM_TOOL_CHAIN_PROMPT_INJECTION",
                "severity": "CRITICAL",
                "confidence": "HIGH",
                "matched_text": [
                    "untrusted_tool_output_prompt_injection",
                    *dangerous_tool_hits[:3],
                    *privilege_tool_hits[:3],
                    *context_surface_keys[:4],
                ],
                "tool_context_present": True,
                "untrusted_context_present": True,
                "context_surface_keys": context_surface_keys[:20],
                "exploit_chain": {
                    "untrusted_tool_output_prompt_injection": True,
                    "dangerous_tool_invocation": bool(dangerous_tool_hits),
                    "privilege_escalating_tool_invocation": bool(privilege_tool_hits),
                },
                "description": (
                    "Untrusted LLM tool output appears to inject instructions that lead to a dangerous "
                    "or privilege-escalating tool invocation."
                ),
            }
        )

    if dangerous_tool_hits:
        signals.append(
            {
                "signal_type": "LLM_DANGEROUS_TOOL_INVOCATION",
                "severity": "HIGH",
                "confidence": "HIGH",
                "matched_text": dangerous_tool_hits[:4],
                "description": (
                    "LLM response appears to attempt dangerous tool or function invocation."
                ),
            }
        )

    if privilege_tool_hits:
        signals.append(
            {
                "signal_type": "LLM_PRIVILEGE_ESCALATING_TOOL_INVOCATION",
                "severity": "CRITICAL",
                "confidence": "HIGH",
                "matched_text": privilege_tool_hits[:4],
                "tool_context_present": True,
                "untrusted_context_present": True,
                "context_surface_keys": tool_invocation_keys[:20],
                "description": (
                    "LLM response appears to invoke tools that grant privileges, impersonate identities, "
                    "or approve sensitive business actions."
                ),
            }
        )

    if system_leak_hits:
        signals.append(
            {
                "signal_type": "SYSTEM_PROMPT_LEAKAGE",
                "severity": "CRITICAL",
                "confidence": "HIGH",
                "matched_text": system_leak_hits[:3],
                "description": "LLM response appears to disclose hidden system or developer instructions.",
            }
        )

    if secret_hits:
        signals.append(
            {
                "signal_type": "LLM_SECRET_EXPOSURE",
                "severity": "CRITICAL",
                "confidence": "HIGH",
                "matched_text": secret_hits[:3],
                "description": "LLM response appears to disclose credentials, tokens, or API keys.",
            }
        )

    if request_hits and not response_refused and (system_leak_hits or secret_hits):
        signals.append(
            {
                "signal_type": "PROMPT_INJECTION_SUCCESS",
                "severity": "HIGH",
                "confidence": "HIGH",
                "matched_text": request_hits[:3],
                "description": "Prompt-injection payload appears to have induced sensitive output.",
            }
        )
    elif request_hits:
        signals.append(
            {
                "signal_type": "PROMPT_INJECTION_ATTEMPT",
                "severity": "MEDIUM",
                "confidence": "MEDIUM",
                "matched_text": request_hits[:3],
                "response_refused": response_refused,
                "description": (
                    "Prompt-injection payload reached an LLM API endpoint, but no sensitive output was observed."
                ),
            }
        )

    return signals


def _signal_vulnerability_data(
    *,
    account_id: int,
    signal: dict[str, Any],
    endpoint_id: str | None,
    path: str | None,
    method: str | None,
    request_body: Any,
    response_body: Any,
) -> dict[str, Any]:
    signal_type = _text(signal.get("signal_type"), default="LLM_SECURITY")
    safe_path = Redactor.redact_url(_text(path, default="/"))
    evidence = {
        "engine": "llm_api",
        "signal_type": signal_type,
        "path": safe_path,
        "method": _truncate(_text(method, default="POST").upper(), 10),
        **_matched_text_summary(signal.get("matched_text")),
        "response_refused": bool(signal.get("response_refused", False)),
        "retrieval_context_present": bool(signal.get("retrieval_context_present", False)),
        "untrusted_context_present": bool(signal.get("untrusted_context_present", False)),
        "tool_context_present": bool(signal.get("tool_context_present", False)),
        "context_surface_keys": [
            Redactor.redact_text(_truncate(item, 80))
            for item in (signal.get("context_surface_keys") or [])[:20]
        ],
        "request_body_sha256": _safe_body_fingerprint(request_body),
        "response_body_sha256": _safe_body_fingerprint(response_body),
        "request_body_length": _safe_body_length(request_body),
        "response_body_length": _safe_body_length(response_body),
        "body_content_persisted": False,
        "content_minimization": _content_minimization_policy(surface="llm_api"),
        "finding_status": "UNCONFIRMED",
    }
    evidence.update(_persisted_signal_context_evidence(signal_type, response_body))
    exploit_chain = _safe_exploit_chain(signal.get("exploit_chain"))
    if exploit_chain:
        evidence["exploit_chain"] = exploit_chain
    evidence["judge_validation"] = _deterministic_judge_validation(
        validator="deterministic_llm_signal_judge",
        surface="llm_api",
        evidence=evidence,
        required_evidence=_required_evidence_for_persisted_signal(signal_type),
    )
    return {
        "account_id": account_id,
        "template_id": _truncate(f"llm-{_slug(signal_type)}", 100),
        "endpoint_id": endpoint_id,
        "url": safe_path,
        "method": _truncate(_text(method, default="POST").upper(), 10),
        "severity": _text(signal.get("severity"), default="HIGH").upper(),
        "type": _truncate(f"LLM:{signal_type}", 100),
        "description": _text(signal.get("description"), default=f"LLM security signal: {signal_type}"),
        "status": "OPEN",
        "confidence": _text(signal.get("confidence"), default="MEDIUM").upper(),
        "remediation": (
            "Add LLM input/output guardrails, isolate system prompts from user-controlled context, "
            "filter secrets from model-visible data, and require tool/output allowlists for agentic workflows."
        ),
        "evidence": _finalize_evidence(evidence),
    }


async def persist_llm_api_findings(
    db: AsyncSession,
    *,
    account_id: int,
    endpoint_id: str | None,
    path: str | None,
    method: str | None,
    request_body: Any,
    response_body: Any,
) -> dict[str, Any]:
    created_count = 0
    merged_count = 0
    vulnerabilities: list[dict[str, Any]] = []
    signals = detect_llm_api_signals(path=path, request_body=request_body, response_body=response_body)

    for signal in signals:
        vulnerability_data = _signal_vulnerability_data(
            account_id=account_id,
            signal=signal,
            endpoint_id=endpoint_id,
            path=path,
            method=method,
            request_body=request_body,
            response_body=response_body,
        )
        vulnerability, created, fingerprint = await create_or_merge_vulnerability(db, vulnerability_data)
        if created:
            created_count += 1
        else:
            merged_count += 1
        vulnerabilities.append(
            {
                "id": vulnerability.id,
                "created": created,
                "fingerprint": fingerprint,
                "template_id": vulnerability.template_id,
                "severity": vulnerability.severity,
                "type": vulnerability.type,
                "occurrence_count": int(vulnerability.occurrence_count or 1),
            }
        )

    return {
        "signals": [_public_signal_summary(signal) for signal in signals],
        "created_count": created_count,
        "merged_count": merged_count,
        "vulnerabilities": vulnerabilities,
    }


async def persist_agentic_violation_finding(
    db: AsyncSession,
    *,
    account_id: int,
    agent_id: str,
    tool_name: str,
    violation_type: str,
    severity: str,
    details: dict[str, Any] | None = None,
) -> dict[str, Any]:
    v_type = _text(violation_type, default="AGENTIC_SECURITY_VIOLATION").upper()
    safe_tool = _truncate(tool_name, 100)
    evidence = {
        "engine": "agentic_mcp",
        "agent_id": _truncate(agent_id, 120),
        "tool_name": safe_tool,
        "violation_type": v_type,
        "details_summary": summarize_agentic_violation_details(details),
        "content_minimization": _content_minimization_policy(surface="agentic_mcp"),
        "finding_status": "UNCONFIRMED",
    }
    evidence["judge_validation"] = _deterministic_judge_validation(
        validator="deterministic_agentic_policy_judge",
        surface="agentic_mcp",
        evidence=evidence,
        required_evidence=[
            "agent_id",
            "content_minimization",
            "details_summary",
            "tool_name",
            "violation_type",
        ],
    )
    vulnerability_data = {
        "account_id": account_id,
        "template_id": _truncate(f"agentic-{_slug(v_type)}", 100),
        "endpoint_id": None,
        "url": f"mcp:{safe_tool}",
        "method": "MCP",
        "severity": _text(severity, default="HIGH").upper(),
        "type": _truncate(f"AGENTIC:{v_type}", 100),
        "description": f"Agentic/MCP security violation detected: {v_type}.",
        "status": "OPEN",
        "confidence": "HIGH",
        "remediation": (
            "Constrain agent scopes to least privilege, enforce MCP tool allowlists, validate tool outputs, "
            "and block prompt-injection patterns before they enter model or tool context."
        ),
        "evidence": _finalize_evidence(evidence),
    }
    vulnerability, created, fingerprint = await create_or_merge_vulnerability(db, vulnerability_data)
    return {
        "id": vulnerability.id,
        "created": created,
        "fingerprint": fingerprint,
        "template_id": vulnerability.template_id,
        "severity": vulnerability.severity,
        "type": vulnerability.type,
        "occurrence_count": int(vulnerability.occurrence_count or 1),
    }
