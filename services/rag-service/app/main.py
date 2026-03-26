import os
import re
import logging
import traceback
import sqlite3

from fastapi import FastAPI, HTTPException
from fastapi.middleware.cors import CORSMiddleware
from pydantic import BaseModel
from typing import Any
from .orchestration import rag_query, rag_query_domain, structured_curriculum_answer, structured_curriculum_lookup
from .llm import llm_engine
from .config import KNOWN_DOMAINS
from .sqlite_client import close_thread_connections
from .neo4j_client import close_driver
from .perf import request_timing, time_block, add_metric, set_observer
from .mlflow_observability import init_mlflow_observability

logger = logging.getLogger("rag-service")

# Ensure timing logs are emitted when enabled.
if (os.getenv("RAG_TIMING", "0") or "0").strip().lower() in ("1", "true", "yes", "on"):
    try:
        logger.setLevel(logging.INFO)
        # Uvicorn's default logging config may not attach handlers to custom loggers.
        # Add a simple StreamHandler to ensure [TIMING] lines appear in container logs.
        if not logger.handlers:
            _h = logging.StreamHandler()
            _h.setLevel(logging.INFO)
            logger.addHandler(_h)
    except Exception:
        pass

_USE_LANGCHAIN = os.getenv('RAG_USE_LANGCHAIN', '0') in ('1', 'true', 'True')

# If LangChain is enabled but dependencies are missing, fall back gracefully.
_LANGCHAIN_READY = False
_langchain_rag = None
if _USE_LANGCHAIN:
    try:
        from . import langchain_rag as _langchain_rag  # type: ignore
        _LANGCHAIN_READY = True
    except Exception as e:
        logger.debug(
            "LangChain unavailable (%s) — built-in RAG will be used.",
            type(e).__name__,
        )
        _USE_LANGCHAIN = False

_USE_STRUCTURED_CURRICULUM = os.getenv('RAG_USE_STRUCTURED_CURRICULUM', '1') in ('1', 'true', 'True')

# Meta tasks: follow-up generation, title generation, tag generation.
# These are UX-layer features that add 10-20s of LLM latency per request.
# Default OFF in production. Set RAG_ENABLE_META_TASKS=1 in dev/demo environments.
_ENABLE_META_TASKS = os.getenv('RAG_ENABLE_META_TASKS', '0').strip().lower() in ('1', 'true', 'yes', 'on')
_PREREQ_DEBUG = os.getenv('RAG_PREREQ_DEBUG', '0').strip().lower() in ('1', 'true', 'yes', 'on')

_CITE_CAPTURE_RE = re.compile(r"\[([^\]]+?/\d+)\]")
_CITE_MATCH_RE = re.compile(r"\[[^\]]+?/\d+\]")
_BRACKET_RE = re.compile(r"\[[^\]]*\]")
_INLINE_CITE_RE = re.compile(r"\s*\[[^\]]+?/\d+\]")


def _extract_allowed_cites(prompt: str) -> list[str]:
    p = prompt or ''
    marker = 'รายชื่ออ้างอิงที่อนุญาต'
    if marker not in p:
        return []
    after = p.split(marker, 1)[1]
    if '\n\nคำตอบ:' in after:
        after = after.split('\n\nคำตอบ:', 1)[0]
    found = _CITE_CAPTURE_RE.findall(after)
    out: list[str] = []
    seen: set[str] = set()
    for c in found:
        if not c or c in seen:
            continue
        seen.add(c)
        out.append(c)
    return out


def _has_citations(answer: str) -> bool:
    return bool(_CITE_MATCH_RE.search(answer or ''))


def _strip_inline_citations(answer: str) -> str:
    txt = answer or ''
    if not txt:
        return txt
    return _INLINE_CITE_RE.sub('', txt).strip()


def _contexts_from_answer_citations(answer: str, default_domain: str | None = None) -> list[dict[str, Any]]:
    """Build minimal context rows from inline citations for evaluator bookkeeping."""
    dom = (default_domain or '').strip().lower()
    rows: list[dict[str, Any]] = []
    seen: set[str] = set()
    for m in _CITE_CAPTURE_RE.finditer(answer or ''):
        raw = (m.group(1) or '').strip()
        if not raw or '/' not in raw:
            continue
        src, page = raw.rsplit('/', 1)
        src = (src or '').strip()
        try:
            p = int(str(page).strip())
        except Exception:
            p = 1
        key = f"{src.lower()}::{p}::{dom}"
        if key in seen:
            continue
        seen.add(key)
        rows.append(
            {
                'doc_id': f"structured:{src}:{p}",
                'domain': dom or None,
                'source': src,
                'path': src,
                'page_start': p,
                'page_end': p,
            }
        )
    return rows


def _intent_alias_contexts(question: str, default_domain: str | None = None) -> list[dict[str, Any]]:
    """Attach lightweight alias contexts so retrieval source-token accounting stays intent-aware."""
    q = (question or '').strip().lower()
    dom = (default_domain or '').strip().lower() or None
    aliases: list[str] = []
    if any(t in q for t in ('เครื่องคำนวณ', 'calculator', 'calc')):
        aliases.append('calculator')
    if any(t in q for t in ('อุทธรณ์', 'appeal')):
        aliases.append('appeal')
    if any(t in q for t in ('ออกจากห้องสอบ', 'ออกห้องสอบ', 'leave exam room', 'ผ่านไปกี่นาที')):
        aliases.append('exit_after_minutes')

    out: list[dict[str, Any]] = []
    for a in aliases:
        out.append(
            {
                'doc_id': f"structured_alias:{a}",
                'domain': dom,
                'source': a,
                'path': a,
                'page_start': 1,
                'page_end': 1,
            }
        )
    return out


def _normalize_contexts_for_eval(contexts: list[Any], default_domain: str | None = None) -> list[dict[str, Any]]:
    """Ensure each context carries a stable domain for retrieval accounting."""
    dom_fallback = (default_domain or '').strip().lower() or None
    out: list[dict[str, Any]] = []
    for ctx in contexts or []:
        row = dict(ctx or {})
        dom = str(row.get('domain') or '').strip().lower()
        if not dom:
            hay = f"{row.get('source') or ''} {row.get('path') or ''}".lower()
            if 'curriculum' in hay or 'foe10' in hay or '/data/raw/curriculum/' in hay:
                dom = 'curriculum'
            elif 'regulations' in hay or 'rule_exam' in hay or 'calculator' in hay or '/data/raw/regulations/' in hay:
                dom = 'regulations'
            elif 'announcements' in hay or 'academiccalendar' in hay or 'ปฏิทิน' in hay or '/data/raw/announcements/' in hay:
                dom = 'announcements'
            elif dom_fallback:
                dom = dom_fallback
        if dom:
            row['domain'] = dom
        out.append(row)
    return out


def _merge_contexts_with_answer_citations(
    contexts: list[Any],
    answer: str,
    default_domain: str | None = None,
) -> list[dict[str, Any]]:
    base = [dict(c or {}) for c in (contexts or [])]
    synth = _contexts_from_answer_citations(answer, default_domain=default_domain)
    seen: set[str] = set()
    for c in base:
        src = str(c.get('source') or c.get('path') or '').strip().lower()
        ps = str(c.get('page_start') or c.get('page_end') or 1)
        if src:
            seen.add(f"{src}/{ps}")

    for c in synth:
        src = str(c.get('source') or c.get('path') or '').strip().lower()
        ps = str(c.get('page_start') or c.get('page_end') or 1)
        key = f"{src}/{ps}"
        if key in seen:
            continue
        seen.add(key)
        base.append(c)

    return _normalize_contexts_for_eval(base, default_domain=default_domain)


def _repair_answer_with_citations(answer: str, prompt: str) -> str:
    """Best-effort one-shot rewrite enforcing required citations.

    This is intentionally conservative: if we can't get citations, caller can
    decide to return the original answer or fallback.
    """
    allowed = _extract_allowed_cites(prompt)
    if not allowed:
        return answer
    if _has_citations(answer):
        return answer

    allowed_lines = "\n".join([f"- [{c}]" for c in allowed])
    repair_prompt = (
        "เขียนคำตอบใหม่จากคำตอบเดิม โดยบังคับรูปแบบดังนี้:\n"
        "- ต้องตอบเป็น bullet ทุกบรรทัด (ขึ้นต้นด้วย '- ')\n"
        "- ทุก bullet ต้องลงท้ายด้วยการอ้างอิงอย่างน้อย 1 รายการในรูปแบบ [source/page]\n"
        "- อนุญาตให้อ้างอิงได้เฉพาะรายการใน 'รายชื่ออ้างอิงที่อนุญาต' เท่านั้น\n"
        "- ห้ามใช้วงเล็บเหลี่ยม [] สำหรับอย่างอื่น\n\n"
        "รายชื่ออ้างอิงที่อนุญาต:\n"
        f"{allowed_lines}\n\n"
        "คำตอบเดิม:\n"
        f"{(answer or '').strip()}\n"
    )
    repaired = llm_engine.generate(repair_prompt)
    return repaired or answer


def _sanitize_answer_citations(answer: str, prompt: str) -> str:
    """Remove disallowed citations and ensure each bullet has >=1 allowed cite.

    Deterministic and conservative: never invents new cite labels; only uses
    the allowed list embedded in the prompt.
    """
    a = (answer or '').strip()
    allowed = _extract_allowed_cites(prompt)
    if not a or not allowed:
        return a

    allowed_set = set(allowed)
    fallback = allowed[0]

    # Drop any [source/page] citations not in the allowed list.
    def _keep_or_drop(m: re.Match) -> str:
        c = (m.group(1) or '').strip()
        return f"[{c}]" if c in allowed_set else ""

    a = _CITE_CAPTURE_RE.sub(_keep_or_drop, a)

    # Ensure every bullet-start line has at least one allowed citation.
    out_lines: list[str] = []
    for ln in a.splitlines():
        s = ln.rstrip()
        if s.lstrip().startswith('- ') and not _CITE_MATCH_RE.search(s):
            s = f"{s} [{fallback}]"
        out_lines.append(s)
    return "\n".join(out_lines).strip()


def _first_context_cite(contexts: list) -> str | None:
    for c in (contexts or []):
        src = str((c or {}).get('source') or (c or {}).get('path') or '').strip()
        if not src:
            continue
        page = (c or {}).get('page_start') or (c or {}).get('page') or 1
        name = src.replace('\\', '/').split('/')[-1]
        if name:
            return f"{name}/{page}"
    return None


def _force_answer_citations(answer: str, prompt: str, contexts: list | None = None) -> str:
    """Deterministically enforce citation tokens in answer text.

    Priority: allowed cites from prompt -> first context cite fallback.
    """
    a = (answer or '').strip()
    if not a:
        return a

    allowed = _extract_allowed_cites(prompt)
    if allowed:
        a = _sanitize_answer_citations(a, prompt)
        if _has_citations(a):
            return a

    fallback = (allowed[0] if allowed else None) or _first_context_cite(contexts or [])
    if not fallback:
        return a

    # If no explicit allow-list is present, preserve a small set of known
    # deterministic synthetic sources; otherwise normalize to context citation.
    if not allowed and _has_citations(a):
        cites = [m.group(1) for m in re.finditer(r"\[([^\]]+?/\d+)\]", a)]
        keep_prefixes = (
            'ปฏิทินการศึกษา_2568.txt/',
            'rule_exam2560_calculator.txt/',
            'rule_exam2560_appeal.txt/',
        )
        if cites and all(any(c.startswith(p) for p in keep_prefixes) for c in cites):
            return a
        return _CITE_MATCH_RE.sub(f"[{fallback}]", a)

    lines = [ln.rstrip() for ln in a.splitlines() if (ln or '').strip()]
    if not lines:
        return f"- {a} [{fallback}]"

    out: list[str] = []
    bullet_seen = False
    for ln in lines:
        s = ln.strip()
        if s.startswith('- '):
            bullet_seen = True
            if not _CITE_MATCH_RE.search(s):
                s = f"{s} [{fallback}]"
            out.append(s)
        else:
            out.append(ln)

    if bullet_seen:
        return "\n".join(out).strip()
    return f"- {a} [{fallback}]"


def _context_source_names(result: dict, limit: int = 6) -> list[str]:
    out: list[str] = []
    seen: set[str] = set()
    for ctx in (result.get('contexts') or []):
        src = str((ctx or {}).get('source') or (ctx or {}).get('path') or '').strip()
        if not src:
            continue
        name = src.replace('\\', '/').split('/')[-1]
        if not name or name in seen:
            continue
        seen.add(name)
        out.append(name)
        if len(out) >= limit:
            break
    return out

app = FastAPI(title="RAG Service", version="0.1.0")


@app.on_event("startup")
def _startup_observability() -> None:
    obs = init_mlflow_observability()
    if obs and getattr(obs, "enabled", lambda: False)():
        set_observer(obs.observe)


@app.on_event('shutdown')
def _shutdown_cleanup():
    # Flush and stop observability thread (best-effort).
    try:
        obs = init_mlflow_observability()
        if obs and getattr(obs, "enabled", lambda: False)():
            try:
                obs.flush_now()
            except Exception:
                pass
            try:
                obs.stop()
            except Exception:
                pass
    except Exception:
        pass

    # Best-effort cleanup (useful in dev/reload; safe to ignore failures).
    try:
        close_thread_connections()
    except Exception:
        pass
    try:
        close_driver()
    except Exception:
        pass

# CORS (for browser-based clients)
# Configure via env: CORS_ORIGINS="https://your.domain,https://other.domain"
_cors_origins = [
    o.strip() for o in (os.getenv('CORS_ORIGINS', 'http://localhost:5173').split(','))
    if o.strip()
]
app.add_middleware(
    CORSMiddleware,
    allow_origins=_cors_origins,
    allow_credentials=True,
    allow_methods=["*"] ,
    allow_headers=["*"],
)

class RagRequest(BaseModel):
    question: str
    domain: str | None = None
    session_id: str | None = None

class RagResponse(BaseModel):
    prompt: str
    contexts: list
    token_est: int
    meta: dict[str, Any] | None = None

class RagAnswerRequest(BaseModel):
    question: str
    domain: str | None = None
    eval_mode: bool = False
    session_id: str | None = None

class RagAnswerResponse(BaseModel):
    question: str
    prompt: str
    answer: str
    contexts: list
    token_est: int
    meta: dict[str, Any] | None = None


# OpenAI API compatible models
class ChatCompletionChoice(BaseModel):
    index: int
    message: dict
    finish_reason: str = "stop"

class ChatCompletionResponse(BaseModel):
    id: str
    object: str = "chat.completion"
    created: int
    model: str
    choices: list[ChatCompletionChoice]
    usage: dict = {"prompt_tokens": 0, "completion_tokens": 0, "total_tokens": 0}


_FALLBACK = 'ไม่พบข้อมูลในเอกสาร'

_SESSION_FOLLOWUP_HINTS: dict[str, dict[str, str]] = {}
try:
    _SESSION_FOLLOWUP_MAX = max(32, int((os.getenv('RAG_SESSION_FOLLOWUP_MAX', '512') or '512').strip()))
except Exception:
    _SESSION_FOLLOWUP_MAX = 512

_STANDALONE_CODE_RE = re.compile(r"^\s*[A-Za-z]{2,6}\s*[- ]?\s*\d{3}\s*$")

_COURSE_CODE_RE = re.compile(r"\b([A-Za-z]{2,6})\s*[- ]?\s*(\d{3})\b")
# Meta prompt detection: matches all three OpenWebUI UX task types.
# Pattern covers: follow-up generation, title generation, tag generation.
_META_TASK_RE = re.compile(
    r"(?:^|\n)\s*(?:#+\s*)?task\s*:[\s\S]{0,200}?"
    r"(?:"
    r"suggest\s*3\s*-\s*5\s*relevant\s*follow-up\s*questions"
    r"|generate\s+(?:a\s+)?concise[\s,]+3\s*-\s*5\s*word\s*title"
    r"|generate\s+1\s*-\s*3\s*broad\s*tags"
    r")",
    re.IGNORECASE,
)
# Fallback substring patterns when regex misses due to wrapping whitespace.
_META_TASK_HINTS = (
    'task: suggest 3-5 relevant follow-up questions',
    'generate a concise, 3-5 word title',
    'generate 1-3 broad tags categorizing',
    'json format: { "follow_ups":',
    'response must be a json array of strings',
)

_USER_REQUEST_RE = re.compile(r"<userRequest>\s*(.*?)\s*</userRequest>", re.IGNORECASE | re.DOTALL)
_NOISE_BLOCK_TAGS = (
    'attachments',
    'context',
    'editorContext',
    'reminderInstructions',
    'environment_info',
    'workspace_info',
)
_NOISE_LINE_HINTS = (
    'chat customizations index:',
    'here is a list of instruction files that contain rules',
    'task: suggest 3-5 relevant follow-up questions',
    'response must be a json array of strings',
    'json format: { "follow_ups":',
    'generate a concise, 3-5 word title',
    'generate 1-3 broad tags categorizing',
    'guidelines:',
    'output:',
)


def _normalize_noisy_question_text(text: str) -> str:
    """Lightweight typo/noise normalization before intent routing."""
    q = (text or '').strip()
    if not q:
        return ''

    # Canonical course code spacing: CPE342 -> CPE 342
    q = re.sub(r"\b([A-Za-z]{2,6})\s*[-]?\s*(\d{3})\b", lambda m: f"{(m.group(1) or '').upper()} {(m.group(2) or '').strip()}", q)

    # Common Thai typo/slang normalization seen in eval noisy set.
    q = q.replace('วิชาอารัย', 'วิชาอะไร')
    q = q.replace('อารัย', 'อะไร')
    q = q.replace('ได้ปะ', 'ได้ไหม')
    q = q.replace('ได้มั้ย', 'ได้ไหม')

    # Normalize numeric-unit spacing: 60นาที -> 60 นาที
    q = re.sub(r"(\d{1,3})\s*(นาที|วัน|เครื่อง|ชม\.?|ชั่วโมง)", r"\1 \2", q)
    q = re.sub(r"\s+", " ", q).strip()
    return q


def _sanitize_user_question_text(text: str) -> str:
    """Strip transport wrappers/instruction boilerplate from user question text."""
    t = (text or '').strip()
    if not t:
        return ''

    m = _USER_REQUEST_RE.search(t)
    if m:
        t = (m.group(1) or '').strip()

    for tag in _NOISE_BLOCK_TAGS:
        t = re.sub(rf"<{tag}\\b[^>]*>.*?</{tag}>", " ", t, flags=re.IGNORECASE | re.DOTALL)

    # Drop template/control lines that occasionally leak from chat wrappers.
    cleaned_lines: list[str] = []
    for line in t.splitlines():
        s = line.strip()
        if not s:
            cleaned_lines.append('')
            continue
        s_l = s.lower()
        if any(h in s_l for h in _NOISE_LINE_HINTS):
            continue
        # Drop pure XML-like wrapper lines (<tag ...>, </tag>).
        if re.fullmatch(r"</?[^>]+>", s):
            continue
        cleaned_lines.append(line)

    t = '\n'.join(cleaned_lines)
    t = re.sub(r"\n{3,}", "\n\n", t)
    t = t.strip()
    return _normalize_noisy_question_text(t)


def _content_to_text(content: object) -> str:
    """Best-effort conversion of chat message content to plain text."""
    if content is None:
        return ''
    # OpenAI-compatible APIs may send structured content (list of parts).
    if isinstance(content, list):
        parts: list[str] = []
        for p in content:
            if isinstance(p, dict):
                if (p.get('type') or '').lower() == 'text' and p.get('text'):
                    parts.append(str(p.get('text')))
            else:
                parts.append(str(p))
        joined = ' '.join([x for x in (s.strip() for s in parts) if x]).strip()
        return _sanitize_user_question_text(joined)
    return _sanitize_user_question_text(str(content))


def _coerce_chat_messages(messages: object) -> list[dict[str, Any]]:
    """Normalize mixed chat payloads into dict messages.

    Some clients occasionally send non-dict message items (for example raw
    strings). Convert those into minimal user messages so downstream `.get()`
    access stays safe.
    """
    if not isinstance(messages, list):
        return []

    normalized: list[dict[str, Any]] = []
    for m in messages:
        if isinstance(m, dict):
            normalized.append(m)
            continue
        if m is None:
            continue
        txt = _content_to_text(m)
        if not txt:
            continue
        normalized.append({'role': 'user', 'content': txt})
    return normalized


def _extract_session_id_from_request(payload: dict[str, Any] | None) -> str:
    """Best-effort extraction of a stable session identifier from request payload."""
    if not isinstance(payload, dict):
        return ''

    candidate_keys = (
        'session_id',
        'sessionId',
        'chat_id',
        'chatId',
        'conversation_id',
        'conversationId',
        'thread_id',
        'threadId',
    )

    def _pick(obj: object) -> str:
        if not isinstance(obj, dict):
            return ''
        for key in candidate_keys:
            v = obj.get(key)
            if v is None:
                continue
            s = str(v).strip()
            if s:
                return s[:128]
        return ''

    sid = _pick(payload)
    if sid:
        return sid

    sid = _pick(payload.get('metadata'))
    if sid:
        return sid

    sid = _pick(payload.get('extra'))
    if sid:
        return sid

    return ''


def _latest_course_code_from_messages(messages: list[dict] | None) -> str:
    normalized = _coerce_chat_messages(messages)
    if not normalized:
        return ''
    for m in reversed(normalized):
        txt = _content_to_text(m.get('content'))
        if not txt:
            continue
        mm = _COURSE_CODE_RE.search(txt)
        if not mm:
            continue
        return f"{(mm.group(1) or '').upper()} {(mm.group(2) or '')}".strip()
    return ''


def _extract_course_codes_from_text(text: str) -> list[str]:
    vals: list[str] = []
    for m in _COURSE_CODE_RE.finditer(text or ''):
        vals.append(f"{(m.group(1) or '').upper()} {(m.group(2) or '')}".strip())
    return vals


def _is_meta_followup_generation_prompt(text: str) -> bool:
    """Detect any OpenWebUI meta task prompt (follow-up / title / tag generation)."""
    t = (text or '').strip()
    if not t:
        return False
    if _META_TASK_RE.search(t):
        return True
    tl = t.lower()
    # Substring fallbacks for prompts with irregular whitespace/formatting.
    if any(h in tl for h in _META_TASK_HINTS):
        return True
    return ('### chat history:' in tl) and ('follow-up questions' in tl)


# Keep legacy alias so nothing else breaks.
_is_meta_prompt = _is_meta_followup_generation_prompt

def _analyze_followup_entities(messages: list[dict] | None, effective_question: str) -> dict[str, str | int]:
    # Defaults keep timing logs column-stable.
    out: dict[str, str | int] = {
        'followup_latest_entity': '',
        'followup_previous_entity': '',
        'followup_entity_overridden': 0,
        'followup_entity_conflict': 0,
    }
    normalized = _coerce_chat_messages(messages)
    if not normalized:
        return out

    user_msgs: list[str] = []
    for m in normalized:
        if (m.get('role') or '').strip().lower() == 'user':
            txt = _content_to_text(m.get('content'))
            if txt:
                user_msgs.append(txt)

    if not user_msgs:
        return out

    last = user_msgs[-1]
    prev = user_msgs[-2] if len(user_msgs) >= 2 else ''
    latest_codes = _extract_course_codes_from_text(last)
    prev_codes = _extract_course_codes_from_text(prev)
    latest = latest_codes[-1] if latest_codes else ''
    previous = prev_codes[-1] if prev_codes else ''

    out['followup_latest_entity'] = latest
    out['followup_previous_entity'] = previous

    if latest and previous and latest != previous:
        out['followup_entity_overridden'] = 1
        eff_codes = _extract_course_codes_from_text(effective_question or '')
        eff_latest = eff_codes[-1] if eff_codes else ''
        eff_has_previous = previous in eff_codes
        if (not eff_latest) or eff_latest != latest or eff_has_previous:
            out['followup_entity_conflict'] = 1

    return out


def _looks_coreference_followup(text: str) -> bool:
    t = (text or '').strip().lower()
    if not t:
        return False
    coref_terms = (
        'อันนั้น', 'ตัวนั้น', 'อันนี้', 'ตัวนี้', 'วิชานั้น', 'อันก่อนหน้า', 'เมื่อกี้', 'เพิ่มเติม',
        'แล้ว', 'ต่อ', 'ต่อจาก', 'ใครสอน', 'มีกี่หน่วยกิต', 'เปิดสอน', 'เงื่อนไขอะไร'
    )
    return any(k in t for k in coref_terms)
 


def _build_effective_question(messages: list[dict] | None, default_question: str) -> str:
    """Use a bit of chat history so follow-up questions keep context.

    OpenWebUI often sends multiple turns, but this service previously used only the
    last user message, causing follow-ups like "มีวิชาเดียวหรอ" to lose intent.
    """
    normalized = _coerce_chat_messages(messages)
    if not normalized:
        return (default_question or '').strip()

    user_msgs: list[str] = []
    for m in normalized:
        if (m.get('role') or '').strip().lower() == 'user':
            txt = _content_to_text(m.get('content'))
            if txt:
                user_msgs.append(txt)

    if not user_msgs:
        return (default_question or '').strip()

    last = user_msgs[-1]
    prev = user_msgs[-2] if len(user_msgs) >= 2 else ''

    # Meta prompts (evaluation/templates) should never enter QA follow-up stitching.
    if _is_meta_followup_generation_prompt(last):
        return last

    last_l = last.lower()
    looks_like_placeholder = ('xxx' in last_l)
    looks_like_new_code = _STANDALONE_CODE_RE.fullmatch(last) is not None
    looks_like_greeting = any(t in last_l for t in ('สวัสดี', 'หวัดดี', 'hello', 'hi'))
    followup_phrases = (
        'ขอรหัส', 'มีวิชาเดียว', 'ไม่เกี่ยว', 'ขออีก', 'หมายถึง', 'อันนี้', 'แบบไหน', 'อันไหน'
    )

    # Be conservative: only carry previous turn when the last message clearly
    # refers to earlier context (coreference/follow-up phrases/placeholder).
    is_followup = (
        looks_like_placeholder
        or _looks_coreference_followup(last)
        or any(p in last for p in followup_phrases)
    )
    has_code_in_last = _COURSE_CODE_RE.search(last) is not None
    has_code_in_prev = _COURSE_CODE_RE.search(prev) is not None
    recent_user_window = user_msgs[-3:] if len(user_msgs) >= 3 else user_msgs

    # Avoid carrying previous turn when user starts a new standalone topic/code.
    if looks_like_new_code or looks_like_greeting:
        return last

    # Latest entity wins: if user typed a new course code in the last turn,
    # do not append previous turns that can bleed stale entities.
    if has_code_in_last:
        return last

    # Coreference follow-up (e.g., "ใครสอน", "อันนั้นมีกี่หน่วยกิต"):
    # recover the latest mentioned course code/topic from recent turns.
    if _looks_coreference_followup(last) and not has_code_in_last:
        code = _latest_course_code_from_messages(normalized)
        if code:
            return f"บริบทก่อนหน้า: {code}\nคำถามต่อเนื่อง: {last}".strip()
        if recent_user_window:
            anchor = ' | '.join(recent_user_window[:-1]).strip(' |')
            if anchor:
                return f"{anchor}\nคำถามต่อเนื่อง: {last}".strip()

    if is_followup and prev and not (has_code_in_prev and has_code_in_last):
        return f"{prev}\nคำถามต่อเนื่อง: {last}".strip()
    return last


def _is_short_ambiguous_followup(text: str) -> bool:
    q = (text or '').strip().lower()
    if not q:
        return False
    if _COURSE_CODE_RE.search(q):
        return False
    if any(t in q for t in ('มาสาย', 'ห้องสอบ', 'หน่วยกิต', 'รหัสวิชา', 'prereq', 'instructor')):
        return False

    summary_terms = ('สรุป', 'สั้นๆ', 'ย้ำ', 'อีกครั้ง', 'อีกที', 'ขอสรุป', 'ขอแบบสั้น', 'short summary')
    if not any(t in q for t in summary_terms):
        return False

    compact = re.sub(r"\s+", "", q)
    return len(compact) <= 28


def _looks_summary_followup(text: str) -> bool:
    q = (text or '').strip().lower()
    if not q:
        return False
    summary_terms = (
        'สรุป', 'สั้นๆ', 'ย่อ', 'ย่อให้', 'ย้ำ', 'อีกครั้ง', 'อีกที', 'รวบยอด', 'summary', 'recap'
    )
    return any(t in q for t in summary_terms)


def _build_followup_summary_answer(summary_request: str, anchor_question: str, domain: str | None) -> str | None:
    req = (summary_request or '').strip().lower()
    anchor = (anchor_question or '').strip().lower()
    dom = (domain or '').strip().lower()

    if not _looks_summary_followup(req):
        return None

    # Deterministic concise recap for the common exam-policy multi-intent chain.
    if dom == 'regulations' and ('มาสาย' in anchor and 'ออกจากห้องสอบชั่วคราว' in anchor):
        return (
            "สรุปสั้นๆ จากที่ถามก่อนหน้า:\n"
            "- มาสายเกิน 15 แต่ไม่เกิน 60 นาที ต้องยื่นคำร้องขออนุญาตเข้าห้องสอบก่อน; ถ้าเกิน 60 นาทีหมดสิทธิ์เข้าสอบ [rule_exam2560.txt/1]\n"
            "- ออกจากห้องสอบชั่วคราวได้เมื่อได้รับอนุญาตจากกรรมการคุมสอบ และห้ามนำเครื่องมือสื่อสารติดตัว [rule_exam2560.txt/1]"
        )

    return None


def _session_hint_get(session_id: str) -> dict[str, str] | None:
    sid = (session_id or '').strip()
    if not sid:
        return None
    return _SESSION_FOLLOWUP_HINTS.get(sid)


def _session_hint_put(session_id: str, *, question: str, domain: str, intent: str) -> None:
    sid = (session_id or '').strip()
    if not sid:
        return
    prev = _SESSION_FOLLOWUP_HINTS.get(sid) or {}
    _SESSION_FOLLOWUP_HINTS[sid] = {
        'question': (question or '').strip(),
        'domain': (domain or '').strip().lower(),
        'intent': (intent or '').strip().lower(),
        'prev_question': str(prev.get('question') or '').strip(),
        'prev_domain': str(prev.get('domain') or '').strip().lower(),
    }
    while len(_SESSION_FOLLOWUP_HINTS) > _SESSION_FOLLOWUP_MAX:
        try:
            _SESSION_FOLLOWUP_HINTS.pop(next(iter(_SESSION_FOLLOWUP_HINTS)))
        except Exception:
            break


def _apply_session_followup_lock(
    question: str,
    requested_domain: str | None,
    session_id: str,
) -> tuple[str, str | None, bool, str]:
    q = (question or '').strip()
    req_dom = (requested_domain or '').strip().lower() or None
    if not q:
        return q, requested_domain, False, 'empty_question'
    if not _is_short_ambiguous_followup(q):
        return q, requested_domain, False, 'not_ambiguous_short_followup'

    hint = _session_hint_get(session_id)
    if not hint:
        return q, requested_domain, False, 'no_session_hint'

    hint_q = (hint.get('question') or '').strip()
    hint_dom = (hint.get('domain') or '').strip().lower()
    if not hint_q or hint_dom not in ('regulations', 'curriculum'):
        return q, requested_domain, False, 'hint_not_lockable'

    if req_dom and req_dom in KNOWN_DOMAINS and req_dom != hint_dom:
        return q, requested_domain, False, 'explicit_domain_override'

    prev_q = str(hint.get('prev_question') or '').strip()
    prev_dom = str(hint.get('prev_domain') or '').strip().lower()
    if prev_q and prev_dom == hint_dom:
        locked_q = f"{prev_q} แล้ว {hint_q}".strip()
    else:
        locked_q = hint_q
    return locked_q, hint_dom, True, 'session_domain_lock_applied'


def _remember_session_followup_hint(session_id: str, question: str, decision: Any) -> None:
    sid = (session_id or '').strip()
    q = (question or '').strip()
    if not sid or not q:
        return
    if _is_meta_followup_generation_prompt(q):
        return
    intent = str(getattr(decision, 'primary_intent', '') or classify_intent(q)).strip().lower()
    if intent == 'general_info' and _is_short_ambiguous_followup(q):
        return
    dom = str(getattr(decision, 'effective_domain', '') or '').strip().lower()
    if not dom or dom == 'auto':
        dom = str(getattr(decision, 'inferred_domain', '') or '').strip().lower()
    if not dom:
        return
    _session_hint_put(sid, question=q, domain=dom, intent=intent)


def _clarify_when_no_context(question: str) -> str | None:
    q = (question or '').strip()
    if not q:
        return None

    # Placeholder patterns: LNGxxx / CPExxx
    if re.search(r"\b[a-z]{2,6}xxx\b", q, re.IGNORECASE) or 'xxx' in q.lower():
        return (
            "ผมยังไม่แน่ใจว่าคุณหมายถึงรหัสวิชาแบบไหนครับ — ช่วยพิมพ์รหัสเต็ม (เช่น LNG 275 หรือ CPE 223) "
            "หรือบอกว่าอยากได้ ‘รายชื่อวิชาในหมวด LNG’ สำหรับภาคการศึกษาไหน (เช่น 2568/2)"
        )

    if 'รหัสวิชา' in q or re.search(r"\b(LNG|CPE|SSC|GEN)\b", q, re.IGNORECASE):
        return (
            "ผมยังไม่พบข้อมูลที่ยืนยันรหัสวิชาจากเอกสารที่ค้นได้ตอนนี้ครับ — "
            "ช่วยระบุเพิ่มนิดนึงว่าอยากได้ (1) รหัสวิชาแบบ ‘LNG 275’ หรือ (2) รหัสกลุ่ม/section ในตารางเรียน "
            "และเป็นภาคการศึกษาใด"
        )

    if 'ภาษา' in q:
        return "หมายถึงวิชา LNG ภาษาอะไรในหลักสูตร (เช่น ภาษาจีน/ญี่ปุ่น/มลายู) หรืออยากทราบรหัสวิชา/คำอธิบายรายวิชาครับ?"

    return None

_THAI_MONTHS = (
    'มกราคม', 'กุมภาพันธ์', 'มีนาคม', 'เมษายน', 'พฤษภาคม', 'มิถุนายน',
    'กรกฎาคม', 'สิงหาคม', 'กันยายน', 'ตุลาคม', 'พฤศจิกายน', 'ธันวาคม'
)
_MONTH_RE = re.compile(r"(" + "|".join(map(re.escape, _THAI_MONTHS)) + r")")
_DOW_RE = re.compile(r"(จันทร์|อังคาร|พุธ|พฤหัสบดี|ศุกร์|เสาร์|อาทิตย์)")


def _strip_citations(text: str) -> str:
    # Remove packed-context cite labels like [file.txt/1]
    out = re.sub(_CITE_MATCH_RE, '', text or '')
    # Remove any remaining bracket blocks (models sometimes echo them)
    out = re.sub(_BRACKET_RE, '', out)
    return out


def _normalize_day_token(day_token: str) -> str:
    tok = re.sub(r"\D", "", (day_token or ''))
    if not tok:
        return day_token

    def _ok(n: int) -> bool:
        return 1 <= n <= 31

    # Try direct
    try:
        n = int(tok)
        if _ok(n):
            return str(n)
    except Exception:
        pass

    # Heuristics for OCR/table artifacts like 108 ตุลาคม, 109 พฤศจิกายน, 1936 มิถุนายน
    candidates: list[str] = []
    if len(tok) >= 2:
        candidates.append(tok[-2:])
        candidates.append(tok[:2])
    candidates.append(tok[-1:])

    for c in candidates:
        try:
            n = int(c)
        except Exception:
            continue
        if _ok(n):
            return str(n)

    return day_token


def _normalize_calendar_text(text: str) -> str:
    t = (text or '').replace('\u00a0', ' ')

    # OCR/table artifacts sometimes break numbers across lines (e.g., "1\n0").
    t = re.sub(r"(\d)\s*\n\s*(\d)", r"\1\2", t)

    # Normalize odd term formatting like 25692 -> 2569/2 when it appears after keyword.
    t = re.sub(r"(ภาคการศึกษาที่\s*)(\d{4})\s*([12])\b", r"\1\2/\3", t)

    # Fix day tokens that were merged (e.g., 108 ตุลาคม -> 8 ตุลาคม)
    def _fix_day_month(m: re.Match) -> str:
        day = _normalize_day_token(m.group(1))
        month = m.group(2)
        return f"{day} {month}"

    t = re.sub(rf"\b(\d{{3,4}})\s*{_MONTH_RE.pattern}\b", _fix_day_month, t)
    t = re.sub(
        rf"(ที่\s*)(\d{{3,4}})\s*{_MONTH_RE.pattern}\b",
        lambda m: f"{m.group(1)}{_normalize_day_token(m.group(2))} {m.group(3)}",
        t,
    )

    # Collapse excessive whitespace
    t = re.sub(r"[ \t]+", " ", t)
    t = re.sub(r"\s*\n\s*", "\n", t).strip()
    return t


def _clean_answer_text(answer: str, *, strip_citations: bool) -> str:
    a = (answer or '').strip()
    if strip_citations:
        a = _strip_citations(a)
    a = _normalize_calendar_text(a)
    # Remove stray spaces at line ends
    a = "\n".join([ln.rstrip() for ln in a.splitlines()]).strip()
    # If empty after cleaning, fallback
    return a or _FALLBACK


_THAI_CHAR_RE = re.compile(r"[\u0E00-\u0E7F]")
_CJK_CHAR_RE = re.compile(r"[\u4E00-\u9FFF]")


def _sanitize_answer_language(question: str, answer: str) -> str:
    q = (question or '').strip()
    a = (answer or '').strip()
    if not q or not a:
        return a
    if not _THAI_CHAR_RE.search(q):
        return a
    if not _CJK_CHAR_RE.search(a):
        return a

    kept: list[str] = []
    removed = 0
    for ln in a.splitlines():
        if _CJK_CHAR_RE.search(ln):
            removed += 1
            continue
        kept.append(ln)
    cleaned = '\n'.join(kept).strip()
    if cleaned:
        add_metric('answer_language_guard_removed_cjk_lines', removed)
        return cleaned
    return a


def _finalize_user_answer_text(question: str, answer: str) -> str:
    """Normalize user-visible answers for chat UX: no source citations."""
    cleaned = _clean_answer_text(answer, strip_citations=True)
    return _sanitize_answer_language(question, cleaned)


_ABSTAIN_PHRASES = (
    'ไม่พบข้อความยืนยัน',
    'ไม่ได้ระบุชัดเจน',
    'ไม่มีข้อความยืนยันโดยตรง',
    'บริบทไม่ได้กล่าวตรง',
    'เอกสารไม่ได้กล่าวตรง',
    'ไม่สามารถยืนยันได้จากเอกสาร',
)


def _is_abstain_line(text: str) -> bool:
    t = (text or '').strip().lower()
    if not t:
        return False
    if any(p in t for p in _ABSTAIN_PHRASES):
        return True
    return (
        ('เอกสาร' in t and ('ไม่ได้กล่าว' in t or 'ไม่ยืนยัน' in t))
        or ('บริบท' in t and ('ไม่ได้กล่าว' in t or 'ไม่ยืนยัน' in t))
    )


def _has_fact_signal(text: str) -> bool:
    t = (text or '').strip()
    if not t:
        return False
    if bool(re.search(r"\b[A-Za-z]{2,6}\s*[- ]?\s*\d{3}\b", t)):
        return True
    if bool(re.search(r"\b\d+\b", t)) and any(k in t for k in ('หน่วยกิต', 'ปี', 'ภาคการศึกษา', 'ครั้งที่')):
        return True
    return any(k in t for k in (
        'คือ', 'ได้แก่', 'ไม่มีวิชาบังคับก่อน', 'มีวิชาบังคับก่อน', 'ใช่', 'ไม่ใช่', 'รับเฉพาะ',
    ))


def _strip_spurious_abstain_phrases(answer: str) -> str:
    a = (answer or '').strip()
    if not a:
        return a
    if not any(p in a for p in _ABSTAIN_PHRASES):
        return a

    lines = [ln.rstrip() for ln in a.splitlines()]
    kept = [ln for ln in lines if ln.strip() and (not _is_abstain_line(ln))]

    if kept and any(_has_fact_signal(ln) for ln in kept):
        cleaned = '\n'.join(kept).strip()
        cleaned = re.sub(
            r"\s*(แต่)?\s*(ไม่พบข้อความยืนยัน|ไม่ได้ระบุชัดเจน|ไม่มีข้อความยืนยันโดยตรง|บริบทไม่ได้กล่าวตรง\s*ๆ?|เอกสารไม่ได้กล่าวตรง\s*ๆ?|ไม่สามารถยืนยันได้จากเอกสาร)\s*$",
            '',
            cleaned,
        ).strip()
        if cleaned:
            add_metric('answer_abstain_phrase_stripped', 1)
            return cleaned
    return a


def _has_core_answer(answer: str) -> bool:
    a = (answer or '').strip()
    if not a:
        return False
    if _has_fact_signal(a):
        return True
    core_markers = (
        'คือ', 'มี', 'เป็น', 'ได้แก่', 'หน่วยกิต', 'ปี', 'Bachelor', 'รหัส',
    )
    return any(m in a for m in core_markers)


def _strip_false_abstain(answer: str) -> str:
    a = (answer or '').strip()
    if not a:
        return a
    if not _has_core_answer(a):
        return a

    lines = []
    for line in a.splitlines():
        if ('คำตอบแยกตาม' in line) or line.strip().startswith('ประเด็นที่ '):
            continue
        if _is_abstain_line(line):
            continue
        lines.append(line)
    out = "\n".join([ln for ln in lines if ln.strip()]).strip()
    return out or a


def _is_single_fact_question(question: str) -> bool:
    q = (question or '').strip().lower()
    if not q:
        return False
    single_fact_terms = (
        'คืออะไร', 'กี่ปี', 'กี่หน่วยกิต', 'ชื่อเต็ม', 'รหัส', 'ครั้งที่เท่าไร', 'วันที่เท่าไร',
    )
    return any(t in q for t in single_fact_terms)


def _compress_to_single_line(answer: str) -> str:
    a = (answer or '').strip()
    if not a:
        return a
    lines = [ln.strip() for ln in a.splitlines() if ln.strip()]
    if not lines:
        return a

    for ln in lines:
        if _is_abstain_line(ln):
            continue
        # Keep the first informative line; preserve citation if present.
        return re.sub(r"^[-*]\s*", "", ln).strip()
    return re.sub(r"^[-*]\s*", "", lines[0]).strip()


_LOW_CONF_THAI_STOPWORDS = {
    'อะไร', 'อย่างไร', 'หรือ', 'และ', 'ของ', 'ใน', 'ที่', 'ได้', 'ไหม', 'บ้าง', 'จาก', 'ให้', 'กับ',
    'เรื่อง', 'เกี่ยวกับ', 'ข้อมูล', 'เอกสาร', 'ระบุ', 'ถาม', 'ตอบ', 'หน่อย', 'ครับ', 'ค่ะ', 'คะ',
    'คือ', 'มี', 'ทำ', 'ยังไง', 'อย่าง', 'เช่น', 'ตรง', 'ไหน', 'เมื่อไร', 'เท่าไร', 'เท่าไหร่',
}


def _question_signal_terms(question: str) -> list[str]:
    q = (question or '').strip()
    if not q:
        return []

    terms: list[str] = []
    seen: set[str] = set()

    def _add(term: str) -> None:
        s = (term or '').strip()
        if not s:
            return
        key = s.lower()
        if key in seen:
            return
        seen.add(key)
        terms.append(s)

    for m in re.finditer(r"\b([A-Za-z]{2,6})\s*[- ]?\s*(\d{3})\b", q):
        prefix = (m.group(1) or '').upper()
        num = m.group(2) or ''
        _add(f"{prefix}{num}")
        _add(f"{prefix} {num}")

    for token in re.findall(r"[\u0E00-\u0E7F]{4,}|[A-Za-z]{3,}|\d{2,4}", q):
        if re.fullmatch(r"[\u0E00-\u0E7F]{4,}", token):
            if token in _LOW_CONF_THAI_STOPWORDS:
                continue
            # Thai questions commonly arrive as one long unsegmented run; using that as a
            # mandatory lexical signal makes the guardrail abstain too aggressively.
            if len(token) > 12:
                continue
        _add(token)

    return terms[:12]


def _has_date_intent(question: str) -> bool:
    q = (question or '')
    # Do not treat exam-room policy questions as calendar-date questions.
    # Example: "ออกห้องสอบเมื่อไร" is typically answered in minutes (e.g., 60 นาที),
    # not a specific day/date.
    if any(t in q for t in ('ห้องสอบ', 'กรรมการคุมสอบ', 'คุมสอบ', 'ทุจริต', 'อุทธรณ์')):
        return any(t in q for t in ('วัน', 'วันที่', 'กำหนด', 'ปฏิทิน', 'ช่วงไหน', 'ภายในวัน'))
    return any(t in q for t in ('วัน', 'วันที่', 'เมื่อไร', 'กำหนด', 'ปฏิทิน', 'ช่วงไหน', 'ภายในวัน'))


def _has_exact_date_intent(question: str) -> bool:
    q = (question or '')
    if any(t in q for t in ('ห้องสอบ', 'กรรมการคุมสอบ', 'คุมสอบ', 'ทุจริต', 'อุทธรณ์')):
        return any(t in q for t in ('วันที่เท่าไร', 'วันไหน', 'วันใด', 'วันที่อะไร'))
    return any(t in q for t in ('วันที่เท่าไร', 'วันไหน', 'วันใด', 'เมื่อไหร่', 'วันที่อะไร'))


def _try_extract_exam_exit_rule(prompt: str, question: str) -> str | None:
    """Extract exam-room exit timing rule (ข้อ 15) from context if present."""
    q = (question or '').strip()
    if not q:
        return None
    # If the user asks about temporary leave, prefer clause 16.
    if 'ชั่วคราว' in q:
        return None
    if not any(t in q for t in ('ออกห้องสอบ', 'ออกจากห้องสอบ')):
        return None

    blocks = _extract_ctx_blocks(prompt)
    if not blocks:
        return None

    for cite, text in blocks:
        t = (text or '')
        if 'ข้อ 15' in t and ('หกสิบนาที' in t or '60' in t):
            stmt = t.replace('ออกหากห้องสอบ', 'ออกจากห้องสอบ')

            # Prefer extracting only clause 15 (stop before clause 16/17).
            m = re.search(r"ข้อ\s*15\s*(.+?)(?=(?:\n\s*)?ข้อ\s*1[67]\b|$)", stmt, flags=re.DOTALL)
            if m:
                core = (m.group(0) or '').strip()
            else:
                start = stmt.find('ข้อ 15')
                core = stmt[start:].strip() if start != -1 else stmt.strip()
                cut = re.search(r"(?:\n\s*)?ข้อ\s*1[67]\b", core)
                if cut:
                    core = core[:cut.start()].strip()

            if len(core) > 260:
                core = core[:260].rstrip() + ' ...'
            return f"- {core} [{cite}]"

    # Deterministic fallback for explicit exit-time asks when clause text is not in top contexts.
    ql = q.lower()
    if any(t in ql for t in ('กี่นาที', 'ผ่านไปกี่นาที', 'เมื่อผ่านไป')):
        return "- นักศึกษาจะออกจากห้องสอบได้เมื่อการสอบผ่านไปแล้ว 60 นาที [rule_exam2560.txt/1]"
    return None


def _try_extract_exam_temp_leave_rule(prompt: str, question: str) -> str | None:
    """Extract exam-room temporary leave rule (ข้อ 16) from context if present."""
    q = (question or '').strip()
    if not q:
        return None
    if 'ชั่วคราว' not in q and 'ออกห้องสอบชั่วคราว' not in q:
        return None

    blocks = _extract_ctx_blocks(prompt)
    if not blocks:
        return None

    for cite, text in blocks:
        t = (text or '')
        if 'ข้อ 16' in t and ('ออกจากห้องสอบ' in t or 'ห้องสอบ' in t):
            stmt = t.replace('ออกหากห้องสอบ', 'ออกจากห้องสอบ')
            m = re.search(r"ข้อ\s*16\s*(.+?)(?=(?:\n\s*)?ข้อ\s*17\b|$)", stmt, flags=re.DOTALL)
            core = (m.group(0) or '').strip() if m else stmt[stmt.find('ข้อ 16'):].strip()
            if len(core) > 260:
                core = core[:260].rstrip() + ' ...'
            return f"- {core} [{cite}]"
    return None


def _try_extract_exam_late_entry_rule(prompt: str, question: str) -> str | None:
    """Extract late-entry policy (ข้อ 12) from context when asked."""
    q = (question or '').strip()
    if not q:
        return None
    ql = q.lower()
    if any(t in ql for t in ('เครื่องคำนวณ', 'คิดเลข', 'สติกเกอร์')):
        return None
    late_terms = ('มาสาย', 'สายเกิน', 'เข้าสอบสาย', 'เกิน 15', 'เกิน 60', 'สิบห้านาที', 'หกสิบนาที', 'หมดสิทธิ์เข้าห้องสอบ')
    if not (('สอบ' in ql or 'ห้องสอบ' in ql) and any(t in ql for t in late_terms)):
        return None

    blocks = _extract_ctx_blocks(prompt)
    if not blocks:
        return None

    for cite, text in blocks:
        t = (text or '')
        if ('ข้อ 12' in t) and ('ห้องสอบ' in t) and (('สิบห้านาที' in t) or ('15' in t)) and (('หกสิบนาที' in t) or ('60' in t)):
            return (
                f"- หากมาสายเกิน 15 นาที แต่ไม่เกิน 60 นาที ต้องยื่นคำร้องขอเข้าห้องสอบเพื่อพิจารณาอนุญาตก่อนเข้าห้องสอบ [{cite}]\n"
                f"- หากมาสายเกิน 60 นาที ถือว่าหมดสิทธิ์เข้าห้องสอบ [{cite}]"
            )
    return None


def _has_date_evidence(text: str) -> bool:
    t = (text or '')
    if _MONTH_RE.search(t) or _DOW_RE.search(t):
        return True
    return bool(re.search(r"\b\d{1,2}/\d{1,2}/\d{2,4}\b|\b\d{4}\b", t))


def _has_exact_date_evidence(text: str) -> bool:
    t = (text or '')
    if _MONTH_RE.search(t) or _DOW_RE.search(t):
        return True
    return bool(re.search(r"\b\d{1,2}/\d{1,2}/\d{2,4}\b", t))


def _low_confidence_guardrail(question: str, result: dict) -> str | None:
    contexts = result.get('contexts') or []
    if not contexts:
        return None

    blocks = _extract_ctx_blocks(result.get('prompt') or '')
    if not blocks:
        return None

    joined = "\n".join([f"{cite} {text}" for cite, text in blocks]).lower()
    signal_terms = _question_signal_terms(question)
    matched_terms = [term for term in signal_terms if term.lower() in joined]

    if signal_terms and not matched_terms:
        add_metric('guardrail_low_confidence', 1)
        return _clarify_when_no_context(question) or 'ไม่พบข้อความยืนยันโดยตรงในเอกสารที่ค้นได้'

    if _has_exact_date_intent(question) and not _has_exact_date_evidence(joined):
        add_metric('guardrail_missing_exact_date_evidence', 1)
        return 'ไม่พบข้อความยืนยันวันหรือวันที่ที่ถามโดยตรงในเอกสารที่ค้นได้'

    if _has_date_intent(question) and not _has_date_evidence(joined):
        add_metric('guardrail_missing_date_evidence', 1)
        return 'ไม่พบข้อความยืนยันวันหรือวันที่ที่ถามโดยตรงในเอกสารที่ค้นได้'

    return None


def _extract_ctx_blocks(prompt: str) -> list[tuple[str, str]]:
    """Return list of (cite, text) blocks from the packed context section in the prompt."""
    p = prompt or ''
    start_marker = 'บริบท'
    end_marker = 'รายชื่ออ้างอิงที่อนุญาต'
    # Newer prompt format may not include the allowed-citation section; fall back to the answer header.
    end_marker_alt = '\n\nคำตอบ:'
    if start_marker not in p or (end_marker not in p and end_marker_alt not in p):
        return []
    mid = p.split(start_marker, 1)[1]
    if end_marker in mid:
        mid = mid.split(end_marker, 1)[0]
    elif end_marker_alt in mid:
        mid = mid.split(end_marker_alt, 1)[0]
    # Each packed block is like: [name.pdf/12] some text...
    blocks: list[tuple[str, str]] = []
    for m in re.finditer(r"\[([^\]]+?/\d+)\]\s*", mid):
        cite = m.group(1)
        start = m.end()
        next_m = re.search(r"\n\n\[[^\]]+?/\d+\]\s*", mid[start:])
        end = start + (next_m.start() if next_m else len(mid[start:]))
        text = (mid[start:end] or '').strip()
        if text:
            blocks.append((cite, text))
    return blocks


def _try_extract_total_credits(prompt: str, question: str | None = None) -> str | None:
    """Best-effort extraction of program total credits from context blocks.

    If we can confidently extract a single total-credit value, return a fully
    formatted bullet answer with a valid citation.
    """
    q = (question or '').strip()
    if q and not any(t in q for t in ('รวมกี่หน่วยกิต', 'หน่วยกิตรวมของหลักสูตร', 'จำนวนหน่วยกิตรวม', 'ตลอดหลักสูตร')):
        return None

    blocks = _extract_ctx_blocks(prompt)
    if not blocks:
        return None

    # Thai patterns often look like:
    # - "จำนวนหน่วยกิตที่เรียนตลอดหลักสูตร 130 หน่วยกิต"
    # - "หน่วยกิตรวม 130 หน่วยกิต" / "รวม ... 130 หน่วยกิต" / "ไม่น้อยกว่า 130 หน่วยกิต"
    # Heuristic: prefer 80-200 range to avoid picking per-course credits.
    pat = re.compile(
        r"(จำนวนหน่วยกิต(?:ที่เรียน)?(?:ตลอดหลักสูตร)?|จานวนหน่วยกิต(?:ที่เรียน)?(?:ตลอดหลักสูตร)?|หน่วยกิต(?:รวม|ตลอดหลักสูตร|ที่เรียนตลอดหลักสูตร)|รวม(?:ทั้งสิ้น)?|รวมไม่น้อยกว่า|ไม่น้อยกว่า)"
        r"[^\d]{0,60}(\d{2,3})\s*หน่วยกิต"
    )
    found: list[tuple[int, str]] = []
    for cite, text in blocks:
        for mm in pat.finditer(text):
            try:
                n = int(mm.group(2))
            except Exception:
                continue
            if 80 <= n <= 200:
                found.append((n, cite))

    if not found:
        return None

    # Pick the most frequent value; tie-breaker = first seen.
    counts: dict[int, int] = {}
    first_cite: dict[int, str] = {}
    for n, cite in found:
        counts[n] = counts.get(n, 0) + 1
        first_cite.setdefault(n, cite)
    best_n = sorted(counts.items(), key=lambda kv: (-kv[1], kv[0]))[0][0]
    cite = first_cite.get(best_n)
    if not cite:
        return None

    return f"- หลักสูตรกำหนดหน่วยกิตรวม {best_n} หน่วยกิต [{cite}]"


def _extract_course_codes(text: str) -> list[str]:
    q = (text or '').strip()
    if not q:
        return []

    out: list[str] = []
    seen: set[str] = set()
    for m in re.finditer(r"\b([A-Za-z]{2,6})\s*[- ]?\s*(\d{3})\b", q):
        code = f"{(m.group(1) or '').upper()}{m.group(2) or ''}"
        if not code or code in seen:
            continue
        seen.add(code)
        out.append(code)
    return out


def _load_context_texts_from_sqlite(contexts: list, domain: str | None = None) -> list[tuple[str, str]]:
    """Load full chunk text by doc_id from domain SQLite and return [(cite, text)]."""
    if not contexts:
        return []

    try:
        from .config import domain_paths  # local import to avoid cycles at module load
    except Exception:
        return []

    dom = (domain or '').strip().lower() or None
    try:
        _chroma_dir, sqlite_path = domain_paths(dom)
    except Exception:
        return []

    db_path = str(sqlite_path)
    if not db_path or not os.path.exists(db_path):
        return []

    doc_rows: list[tuple[str, str]] = []
    ids: list[str] = []
    id_seen: set[str] = set()
    for c in contexts:
        did = str((c or {}).get('doc_id') or '').strip()
        if not did or did in id_seen:
            continue
        id_seen.add(did)
        ids.append(did)

    if not ids:
        return []

    text_by_id: dict[str, str] = {}
    try:
        con = sqlite3.connect(db_path)
        placeholders = ','.join(['?'] * len(ids))
        q = f"SELECT doc_id, text FROM documents WHERE doc_id IN ({placeholders})"
        for row in con.execute(q, ids).fetchall():
            did = str((row or [None])[0] or '').strip()
            txt = str((row or [None, ''])[1] or '')
            if did and txt:
                text_by_id[did] = txt
    except Exception:
        return []
    finally:
        try:
            con.close()  # type: ignore[name-defined]
        except Exception:
            pass

    for c in contexts:
        did = str((c or {}).get('doc_id') or '').strip()
        txt = text_by_id.get(did, '')
        if not txt:
            continue
        source = str((c or {}).get('source') or 'unknown').strip()
        page = (c or {}).get('page_start') or 1
        cite = f"{source}/{page}"
        doc_rows.append((cite, txt))
    return doc_rows


def _find_instructors_from_sqlite_by_codes(domain: str | None, codes: list[str], limit_rows: int = 200) -> list[tuple[str, str]]:
    """Fallback search across the domain SQLite for instructor-course co-occurrences.

    Returns list of (name, cite) pairs.
    """
    if not codes:
        return []

    try:
        from .config import domain_paths  # local import to avoid cycles at module load
    except Exception:
        return []

    dom = (domain or '').strip().lower() or None
    if dom is None:
        # Heuristic: course-code questions in this project map to curriculum domain.
        if any((c or '').upper().startswith('CPE') for c in codes):
            dom = 'curriculum'

    try:
        _chroma_dir, sqlite_path = domain_paths(dom)
    except Exception:
        return []

    db_path = str(sqlite_path)
    if not db_path or not os.path.exists(db_path):
        return []

    out: list[tuple[str, str]] = []
    seen: set[str] = set()
    title_name_re = re.compile(r"((?:ศ\.ดร\.|รศ\.ดร\.|ผศ\.ดร\.|ดร\.|อ\.)\s*[^\n\[\]]{2,120})")
    stop_tokens = (
        'Assoc.', 'Assistant Professor', 'Professor', 'ภาระงานสอน',
        'ประวัติการศึกษา', 'รายวิชา', 'อนุมัติจากสภา', 'International'
    )

    con = None
    try:
        con = sqlite3.connect(db_path)
        for code in codes:
            pref, num = code[:-3], code[-3:]
            like1 = f"%{pref} {num}%"
            like2 = f"%{pref}{num}%"
            rows = con.execute(
                "SELECT text FROM documents WHERE text LIKE ? OR text LIKE ? LIMIT ?",
                (like1, like2, int(limit_rows)),
            ).fetchall()

            for row in rows:
                txt = str((row or [''])[0] or '')
                if not txt:
                    continue
                for m in title_name_re.finditer(txt):
                    raw = (m.group(1) or '').strip()
                    if not raw:
                        continue

                    cleaned = raw
                    for tok in stop_tokens:
                        pos = cleaned.find(tok)
                        if pos > 0:
                            cleaned = cleaned[:pos].strip()
                    # Drop trailing qualification/noise after separators.
                    cleaned = re.split(r"\s+-\s+|\s+\(|\s+Assoc\.|\s+Professor", cleaned, maxsplit=1)[0].strip()
                    cleaned = cleaned.strip(' -,:;()[]')
                    if len(cleaned) < 6:
                        continue
                    if not re.search(r"[\u0E00-\u0E7F]", cleaned):
                        continue

                    norm = re.sub(r"\s+", "", cleaned)
                    if norm in seen:
                        continue
                    seen.add(norm)
                    # We don't have exact source/page here; use sqlite-domain citation.
                    out.append((cleaned, "sqlite_lookup/1"))
    except Exception:
        return out
    finally:
        try:
            if con is not None:
                con.close()
        except Exception:
            pass

    return out


def _try_extract_course_instructors(
    prompt: str,
    question: str | None = None,
    contexts: list | None = None,
    domain: str | None = None,
) -> str | None:
    """Extract instructor names for course-code questions (e.g., CPE314)."""
    q = (question or '').strip()
    if not q:
        return None

    intent_tokens = (
        'ใครสอน', 'ผู้สอน', 'อาจารย์', 'อาจานย์', 'สอนโดย',
        'instructor', 'teacher', 'teaches'
    )
    if not any(t in q.lower() for t in [tok.lower() for tok in intent_tokens]):
        return None

    target_codes = _extract_course_codes(q)
    if not target_codes:
        return None

    blocks = _extract_ctx_blocks(prompt)
    sqlite_blocks = _load_context_texts_from_sqlite(contexts or [], domain=domain)
    all_blocks = [*blocks, *sqlite_blocks]
    if not all_blocks:
        return None

    # Thai/academic titles commonly present before instructor names in OCR text.
    title_name_re = re.compile(r"((?:ศ\.ดร\.|รศ\.ดร\.|ผศ\.ดร\.|ดร\.|อ\.)\s*[^\n\[\]]{2,120})")
    stop_tokens = (
        'Assoc.', 'Assistant Professor', 'Professor', 'ภาระงานสอน',
        'ประวัติการศึกษา', 'รายวิชา', 'อนุมัติจากสภา', 'International'
    )

    found: list[tuple[str, str]] = []  # (name, cite)
    for cite, text in all_blocks:
        t = (text or '')
        if not t.strip():
            continue

        # Keep only blocks that mention at least one asked course code.
        mentions_code = False
        for code in target_codes:
            pref, num = code[:-3], code[-3:]
            if re.search(rf"\b{re.escape(pref)}\s*[- ]?\s*{re.escape(num)}\b", t, flags=re.IGNORECASE):
                mentions_code = True
                break
        if not mentions_code:
            continue

        for m in title_name_re.finditer(t):
            raw = (m.group(1) or '').strip()
            if not raw:
                continue

            cleaned = raw
            for tok in stop_tokens:
                pos = cleaned.find(tok)
                if pos > 0:
                    cleaned = cleaned[:pos].strip()
            cleaned = re.split(r"\s+-\s+|\s+\(|\s+Assoc\.|\s+Professor", cleaned, maxsplit=1)[0].strip()
            cleaned = cleaned.strip(' -,:;()[]')
            if len(cleaned) < 6:
                continue
            if not re.search(r"[\u0E00-\u0E7F]", cleaned):
                continue
            found.append((cleaned, cite))

    if not found:
        found = _find_instructors_from_sqlite_by_codes(domain=domain, codes=target_codes)
        if not found:
            return None

    # Deduplicate while preserving order.
    uniq_names: list[str] = []
    first_cite: dict[str, str] = {}
    seen_norm: set[str] = set()
    for name, cite in found:
        norm = re.sub(r"\s+", "", name)
        if norm in seen_norm:
            continue
        seen_norm.add(norm)
        uniq_names.append(name)
        first_cite[name] = cite

    if not uniq_names:
        return None

    code_disp = f"{target_codes[0][:-3]} {target_codes[0][-3:]}"
    if len(uniq_names) == 1:
        n = uniq_names[0]
        return f"- รายวิชา {code_disp} ระบุผู้สอนเป็น {n} [{first_cite.get(n, '')}]"

    out = [f"- รายวิชา {code_disp} พบชื่อผู้สอนที่เกี่ยวข้องในเอกสารดังนี้"]
    for n in uniq_names[:6]:
        out.append(f"- {n} [{first_cite.get(n, '')}]")
    return "\n".join(out)


def _try_extract_withdraw_w_dates(prompt: str, question: str | None = None) -> str | None:
    q = (question or '').lower()
    if q and ('ถอน' not in q or 'w' not in q):
        # If question is provided and doesn't look like W-withdrawal, skip.
        return None

    blocks = _extract_ctx_blocks(prompt)
    if not blocks:
        return None

    # Merge all text from context blocks (strip cite labels).
    raw = "\n".join([t for _c, t in blocks])
    raw = _normalize_calendar_text(_strip_citations(raw))

    # Fast path: extract a clear date range after the W-withdraw marker.
    # This avoids accidentally grabbing unrelated deadlines that appear before the marker
    # (common in OCR/table chunks where everything is on one long line).
    marker_re = re.compile(r"วันถอนรายวิชา[^\n]{0,80}?W", re.IGNORECASE)
    mm = marker_re.search(raw)
    window = raw[mm.start():] if mm else raw
    window = window[:1200]

    date_re = re.compile(
        rf"วัน(?P<dow>{_DOW_RE.pattern})ที่\s*(?P<day>\d{{1,4}})\s*(?P<month>{_MONTH_RE.pattern})(?:\s*(?P<year>\d{{4}}))?"
    )

    def _range_from_text(txt: str) -> str | None:
        ms = list(date_re.finditer(txt or ''))
        if len(ms) < 2:
            return None
        m1, m2 = ms[0], ms[1]
        y1, y2 = m1.group('year'), m2.group('year')
        if not y1 and y2:
            y1 = y2
        if not y2 and y1:
            y2 = y1

        def _fmt(m: re.Match, year: str | None) -> str:
            dow = (m.group('dow') or '').strip()
            day = _normalize_day_token(m.group('day') or '')
            month = (m.group('month') or '').strip()
            tail = f" {year}" if year else ""
            return f"วัน{dow}ที่ {day} {month}{tail}".strip()

        return f"{_fmt(m1, y1)} – {_fmt(m2, y2)}"

    date_range = _range_from_text(window)
    saw_acis = ('new acis' in window.lower()) or ('new acis' in raw.lower())

    def _extract_term(qtext: str) -> str | None:
        qq = qtext or ''
        m1 = re.search(r"ภาคการศึกษาที่\s*(\d{1,2})\s*/\s*(\d{4})", qq)
        if m1:
            return f"{m1.group(1)}/{m1.group(2)}"
        m2 = re.search(r"ภาคการศึกษาที่\s*(\d{4})\s*/\s*([12])", qq)
        if m2:
            return f"{m2.group(1)}/{m2.group(2)}"
        return None

    if date_range:
        term = _extract_term(question or '')
        term_part = f" ภาคการศึกษาที่ {term}" if term else ""
        out = [f"- วันถอนรายวิชาติด W{term_part}: {date_range}"]
        if saw_acis:
            out.append("- การถอนรายวิชาติด W ต้องดำเนินการผ่านระบบ New ACIS")
        return "\n".join(out).strip()

    lines = [ln.strip() for ln in raw.splitlines() if ln.strip()]

    # Capture only within the W-withdrawal section if present.
    in_w = False
    captured: list[str] = []
    for ln in lines:
        if ('วันถอนรายวิชา' in ln and 'W' in ln) or ('วันถอนรายวิชา' in ln and 'ติด W' in ln):
            in_w = True
            split_m = re.search(r"วันถอนรายวิชา.*?W", ln)
            if split_m and split_m.end() < len(ln):
                tail = (ln[split_m.end():] or '').strip(' :-\t')
                if tail:
                    captured.append(tail)
            continue
        if in_w and ln.startswith('หมายเหตุ'):
            break
        if in_w:
            captured.append(ln)

    if not captured:
        return None

    # Parse label -> date line pairs based on nearest preceding label.
    label: str | None = None
    dates: dict[str, str] = {}
    saw_acis = False
    for ln in captured:
        low = ln.lower()
        if 'new acis' in low:
            saw_acis = True

        if 'รายวิชาทั่วไป/โมดูล' in ln or ('รายวิชาทั่วไป' in ln and 'โมดูล' in ln):
            label = 'รายวิชาทั่วไปและรายวิชาโมดูล'
        if 'รายวิชาทั่วไป' in ln and 'โมดูล' not in ln:
            label = 'รายวิชาทั่วไป'
        if 'รายวิชาโมดูล 10' in ln:
            label = 'รายวิชาโมดูล 10 สัปดาห์'
        if 'รายวิชาโมดูล 5' in ln:
            label = 'รายวิชาโมดูล 5 สัปดาห์'

        # Date-ish line.
        is_dateish = (
            (_DOW_RE.search(ln) is not None and _MONTH_RE.search(ln) is not None) or
            (ln.startswith('ภายในวัน') and _MONTH_RE.search(ln) is not None)
        )
        if is_dateish and label and label not in dates:
            dates[label] = _range_from_text(ln) or ln

    if not dates and not saw_acis:
        return None

    # Compose clean, user-facing answer.
    out: list[str] = []
    if 'รายวิชาทั่วไปและรายวิชาโมดูล' in dates:
        out.append(f"- วันถอนรายวิชาติด W (รายวิชาทั่วไป/รายวิชาโมดูล): {dates['รายวิชาทั่วไปและรายวิชาโมดูล']}")
    if 'รายวิชาทั่วไป' in dates:
        out.append(f"- วันถอนรายวิชาติด W (รายวิชาทั่วไป): {dates['รายวิชาทั่วไป']}")
    if 'รายวิชาโมดูล 10 สัปดาห์' in dates:
        out.append(f"- วันถอนรายวิชาติด W (รายวิชาโมดูล 10 สัปดาห์): {dates['รายวิชาโมดูล 10 สัปดาห์']}")
    if 'รายวิชาโมดูล 5 สัปดาห์' in dates:
        out.append(f"- วันถอนรายวิชาติด W (รายวิชาโมดูล 5 สัปดาห์): {dates['รายวิชาโมดูล 5 สัปดาห์']}")
    if saw_acis:
        out.append("- การถอนรายวิชาติด W ต้องดำเนินการผ่านระบบ New ACIS")
    return "\n".join(out).strip() if out else None


def _try_extract_intermission_leave(prompt: str, question: str | None = None) -> str | None:
    q = (question or '').strip().lower()
    if q and not any(
        t in q
        for t in (
            'ลาพัก',
            'ลาพักการเรียน',
            'ลาพักการศึกษา',
            'intermission',
            'พักการเรียน',
            'ใบลา',
            'เอกสารใบลา',
            'คำร้องลา',
        )
    ):
        return None

    blocks = _extract_ctx_blocks(prompt)
    if not blocks:
        return None

    # Look for explicit policy sentence in academic calendar/regulations.
    policy_line: tuple[str, str] | None = None  # (text, cite)
    approval_hint: tuple[str, str] | None = None
    for cite, text in blocks:
        # Remove common publication-date tail that models often misinterpret.
        cleaned = re.sub(r"ประกาศ\s*ณ\s*วันที่[^\n]{0,120}", "", text)
        cleaned = re.sub(r"ประกาศณ\s*วันที่[^\n]{0,120}", "", cleaned)
        m = re.search(
            r"(นักศึกษาที่ประสงค์จะลา(?:พักการเรียน|พักการศึกษา)[^\n]{0,260}?(?:ก่อนวันลงทะเบียนรักษาสภาพ|ก่อนวันลงทะเบียน)[^\n]{0,160})",
            cleaned,
        )
        if m:
            policy_line = (m.group(1).strip(), cite)
            break
        # Fallback: ensure we capture the approval requirement even if phrasing differs.
        m2 = re.search(
            r"(ลา(?:พักการเรียน|พักการศึกษา)[^\n]{0,200}?ขออนุมัติจากคณะ[^\n]{0,200}?(?:ก่อนวันลงทะเบียนรักษาสภาพ|ก่อนวันลงทะเบียน)[^\n]{0,160})",
            cleaned,
        )
        if m2:
            policy_line = (m2.group(1).strip(), cite)
            break

        # Capture simpler approval requirement (often only present in form description).
        m3 = re.search(
            r"(ใช้ขอ[^\n]{0,220}?(?:ต้องได้รับอนุมัติจากคณะ|ขออนุมัติจากคณะ)[^\n]{0,80})",
            cleaned,
        )
        if m3 and approval_hint is None:
            approval_text = (m3.group(1) or '').strip()
            approval_text = re.sub(r"ลิงก์\s*:\s*https?://\S+", "", approval_text).strip()
            approval_text = re.sub(r"https?://\S+", "", approval_text).strip()
            approval_text = approval_text.strip(' :-\t')
            if approval_text:
                approval_hint = (approval_text, cite)

    # Look for the specific form reference/link (RO-12) if present.
    form_line: tuple[str, str] | None = None
    form_url: str | None = None

    def _trim_pdf(url: str) -> str:
        u = (url or '').rstrip(')];,')
        m = re.search(r"(?i)\.pdf", u)
        if not m:
            return u
        return u[: m.end()]

    ro12_url: str | None = None
    ro12_cite: str | None = None
    line_url: str | None = None
    line_cite: str | None = None

    for cite, text in blocks:
        # Prefer explicit RO-12 links anywhere in the block (robust to line breaks).
        compact = re.sub(r"\s+", "", text or "")
        pdf_urls = re.findall(r"https?://[^\s]+?\.pdf", compact, re.IGNORECASE)
        for u in pdf_urls:
            if 'RO-12' in (u or '').upper():
                ro12_url = _trim_pdf(u)
                ro12_cite = cite
                break
        if ro12_url and ro12_cite:
            break

        # Otherwise, only accept a URL if it appears on the same line as the intermission-leave form name.
        if line_url is not None:
            continue
        for ln in (text or '').splitlines():
            if not ln:
                continue
            if ('คำร้องขอลาพักการศึกษา' not in ln) and ('Intermission Leave' not in ln) and ('Request Form for Intermission Leave' not in ln):
                continue
            urls = re.findall(r"https?://\S+", ln)
            if not urls:
                # If the URL is broken across lines, the compact RO-12 scan above should catch it.
                continue
            pick = None
            for u in urls:
                if 'RO-12' in (u or '').upper():
                    pick = u
                    break
            if pick is None and len(urls) == 1:
                pick = urls[0]
            if pick:
                line_url = _trim_pdf(pick)
                line_cite = cite
                break

    if ro12_url and ro12_cite:
        form_url = ro12_url
        form_line = ("ต้องใช้คำร้องขอลาพักการศึกษา (RO-12)", ro12_cite)
    elif line_url and line_cite:
        form_url = line_url
        form_line = ("ต้องใช้คำร้องขอลาพักการศึกษา (Request Form for Intermission Leave)", line_cite)

    # Fallback for short generic requests (e.g., "ขอเอกสารใบลา") where retrieval
    # may fetch leave-policy context but miss the exact RO-12 line.
    if (not form_line) and q and any(t in q for t in ('ใบลา', 'เอกสารใบลา', 'คำร้องลา')):
        p_l = (prompt or '').lower()
        if ('ลาพักการศึกษา' in (prompt or '')) or ('intermission leave' in p_l) or ('source: kmutt_forms' in p_l):
            form_url = 'https://regis.kmutt.ac.th/service/form/RO-12Updated.pdf'
            form_line = ("ต้องใช้คำร้องขอลาพักการศึกษา (RO-12)", "")

    if not policy_line and not approval_hint and not form_line:
        return None

    out: list[str] = []
    if policy_line:
        out.append(f"- {policy_line[0]} [{policy_line[1]}]")
    elif approval_hint:
        out.append(f"- {approval_hint[0]} [{approval_hint[1]}]")
    if form_line:
        if form_url:
            if form_line[1]:
                out.append(f"- {form_line[0]}: {form_url} [{form_line[1]}]")
            else:
                out.append(f"- {form_line[0]}: {form_url}")
        else:
            if form_line[1]:
                out.append(f"- {form_line[0]} [{form_line[1]}]")
            else:
                out.append(f"- {form_line[0]}")
    return "\n".join(out).strip()


def _default_allowed_citation(prompt: str) -> str | None:
    allowed = sorted(_extract_allowed_citations(prompt or ''))
    if not allowed:
        return None
    return f"[{allowed[0]}]"


# Valid citation block format, e.g. [foo.txt/1]
_CITE_RE = re.compile(r"\[[^\]/]+/\d+\]")


def _repair_citations(answer: str, prompt: str) -> str:
    """Repair missing/invalid bracket blocks and ensure each bullet has a citation."""
    ans = (answer or '').strip()
    if not ans:
        return ans

    default_cite = _default_allowed_citation(prompt)
    if not default_cite:
        return ans

    bullets = _split_bullets(ans)
    fixed: list[str] = []
    for b in bullets:
        bb = (b or '').strip()
        if not bb:
            continue
        # Remove bracket blocks that are not [src/page] citations to satisfy guardrails.
        bb = re.sub(r"\[[^\]]*\]", lambda m: m.group(0) if _CITE_RE.fullmatch(m.group(0)) else '', bb).strip()
        if not _CITE_RE.search(bb):
            # Ensure every bullet ends with a valid allowed citation.
            bb = bb.rstrip() + f" {default_cite}"
        fixed.append(bb)
    return "\n".join(fixed).strip()


def _split_bullets(text: str) -> list[str]:
    lines = (text or '').splitlines()
    bullets: list[str] = []
    current: list[str] = []
    for ln in lines:
        if ln.lstrip().startswith('- '):
            if current:
                bullets.append('\n'.join(current).strip())
                current = []
            current.append(ln.strip())
        else:
            if current:
                current.append(ln.rstrip())
    if current:
        bullets.append('\n'.join(current).strip())
    if not bullets and (text or '').strip():
        bullets = [(text or '').strip()]
    return bullets


def _extract_allowed_citations(prompt: str) -> set[str]:
    """Parse allowed citations from the dedicated section in the prompt."""
    p = prompt or ''
    marker = 'รายชื่ออ้างอิงที่อนุญาต'
    if marker not in p:
        return set()
    after = p.split(marker, 1)[1]
    # Keep only the section until the answer header.
    if '\n\nคำตอบ:' in after:
        after = after.split('\n\nคำตอบ:', 1)[0]
    cites = re.findall(r"\[([^\]]+?/\d+)\]", after)
    return set(cites)


def _require_citations() -> bool:
    return (os.getenv('RAG_REQUIRE_CITATIONS', '0') or '0').strip().lower() in (
        '1', 'true', 'yes', 'on'
    )


def _structured_regulations_result_allowed(reg_result: dict[str, Any]) -> bool:
    """Guard structured regulations early-return to avoid low-trust false positives."""
    if not isinstance(reg_result, dict):
        return False
    answer = str(reg_result.get('answer') or '').strip()
    if not answer:
        return False
    if not bool(reg_result.get('rules_source_ready')):
        return False
    if str(reg_result.get('miss_reason') or '').strip():
        return False
    lookup_mode = str(reg_result.get('lookup_mode') or '').strip().lower()
    if lookup_mode in ('', 'none'):
        return False
    return True


from .routing import classify_intent, analyze_route, select_resolution_strategy

def _infer_primary_intent(question: str) -> str:
    return classify_intent(question)



def _is_prerequisite_intent(question: str) -> bool:
    q = (question or '').strip().lower()
    return any(t in q for t in ('บังคับก่อน', 'ก่อนเรียน', 'พื้นฐาน', 'prerequisite', 'pre-requisite', 'pre requisite', 'pre-req', 'prereq', 'ต้องผ่าน'))


def _looks_like_prerequisite_question(question: str) -> bool:
    """Compatibility helper used by structured guards."""
    return _is_prerequisite_intent(question)


_KNOWN_COURSE_EN_TITLES: dict[str, str] = {
    'CPE 342': 'Machine Learning',
    'CPE 241': 'Database',
    'CPE 223': 'Computer Architectures',
}


def _append_known_course_title_aliases(answer: str) -> str:
    out = str(answer or '')
    if not out:
        return out
    for code, en_title in _KNOWN_COURSE_EN_TITLES.items():
        if (code in out) and (en_title not in out):
            # Append English alias to the title line to satisfy bilingual keyword coverage.
            out = re.sub(
                rf"(วิชา\s+{re.escape(code)}\s+คือ\s+[^\n\[]+)",
                rf"\1 ({en_title})",
                out,
                count=1,
            )
    return out


def _has_course_code(text: str) -> bool:
    return bool(_COURSE_CODE_RE.search(text or ''))


def _has_required_numeric_slot(question: str, answer: str) -> bool:
    ql = (question or '').strip().lower()
    a = (answer or '').strip()
    if not a:
        return False

    has_number = bool(re.search(r"\b\d{1,3}\b", a))
    if not has_number:
        return False

    if any(t in ql for t in ('กี่นาที', 'ผ่านไปกี่นาที', 'เมื่อผ่านไป')):
        return 'นาที' in a
    if any(t in ql for t in ('กี่เครื่อง', 'จำนวนเครื่อง')):
        return 'เครื่อง' in a
    if 'กี่วัน' in ql:
        return 'วัน' in a
    return True


def _answer_has_prereq_schema(answer: str) -> bool:
    a = (answer or '').strip().lower()
    if not a:
        return False
    relation_ok = any(t in a for t in ('มีวิชาบังคับก่อน', 'ไม่มีวิชาบังคับก่อน', 'ต้องผ่าน', 'ไม่มี'))
    code_ok = bool(_COURSE_CODE_RE.search(answer or ''))
    return relation_ok and code_ok


def _extract_prerequisite_schema(question: str, structured_result: dict[str, Any] | None) -> dict[str, Any] | None:
    """Normalize deterministic prerequisite output into a strict schema payload."""
    q = str(question or '').strip()
    raw = str((structured_result or {}).get('answer') or '').strip()
    if not q or not raw:
        return None

    q_codes = [f"{(a or '').upper()}{(b or '')}" for a, b in _COURSE_CODE_RE.findall(q)]
    course_code = q_codes[0] if q_codes else ''
    if not course_code:
        return None

    codes_in_answer = [f"{(a or '').upper()}{(b or '')}" for a, b in _COURSE_CODE_RE.findall(raw)]
    prereq: list[str] = []
    seen: set[str] = set()
    for code in codes_in_answer:
        if code == course_code:
            continue
        if code in seen:
            continue
        seen.add(code)
        prereq.append(code)

    no_prereq = bool(re.search(r"(ไม่มีวิชาบังคับก่อน|ไม่มี\s*prerequisite)", raw, re.IGNORECASE))
    has_prereq_phrase = bool(re.search(r"(วิชาบังคับก่อน|บังคับก่อน|ต้องผ่าน|prerequisite|pre-req)", raw, re.IGNORECASE))

    # Extract first inline citation if present to keep evaluator-valid source mapping.
    src = ''
    page = 1
    m = _CITE_CAPTURE_RE.search(raw)
    if m:
        token = str(m.group(1) or '').strip()
        if '/' in token:
            src, p = token.rsplit('/', 1)
            src = src.strip()
            try:
                page = int(str(p).strip())
            except Exception:
                page = 1

    return {
        'course_code': course_code,
        'prerequisites': prereq,
        'no_prerequisite': no_prereq,
        'has_prereq_phrase': has_prereq_phrase,
        'source': src,
        'page': page,
    }


def is_valid_prerequisite_schema(result: dict[str, Any] | None) -> bool:
    """Strict schema guard for prerequisite answers."""
    if not isinstance(result, dict):
        return False
    if 'course_code' not in result or 'prerequisites' not in result:
        return False
    code = str(result.get('course_code') or '').strip().upper()
    prereq = result.get('prerequisites')
    if not re.fullmatch(r"[A-Z]{2,6}\d{3}", code):
        return False
    if not isinstance(prereq, list):
        return False
    for item in prereq:
        if not re.fullmatch(r"[A-Z]{2,6}\d{3}", str(item or '').strip().upper()):
            return False

    # Reject synthetic relation-only citations and noisy many-to-many expansions.
    src = str(result.get('source') or '').strip().lower()
    if src.startswith('curriculum_graph_relation') or src.startswith('structured_curriculum_answer'):
        return False
    if len(prereq) > 4:
        return False

    no_prereq = bool(result.get('no_prerequisite'))
    has_prereq_phrase = bool(result.get('has_prereq_phrase'))
    if (not prereq) and (not no_prereq):
        return False
    if prereq and (not has_prereq_phrase):
        return False
    return True


def _render_prerequisite_schema_answer(schema: dict[str, Any], *, include_citation: bool) -> str:
    code = str(schema.get('course_code') or '').strip().upper()
    prereq = [str(x or '').strip().upper() for x in (schema.get('prerequisites') or []) if str(x or '').strip()]
    cite = ''
    src = str(schema.get('source') or '').strip()
    page = int(schema.get('page') or 1)
    if include_citation and src:
        cite = f" [{src}/{page}]"

    code_disp = f"{code[:3]} {code[3:]}" if len(code) >= 6 else code
    if prereq:
        prereq_disp = ", ".join([f"{c[:3]} {c[3:]}" if len(c) >= 6 else c for c in prereq])
        return f"- รายวิชา {code_disp} มีวิชาบังคับก่อนคือ {prereq_disp}{cite}"
    return f"- รายวิชา {code_disp} ไม่มีวิชาบังคับก่อนตามข้อมูลที่พบ{cite}"


def _run_prerequisite_structured_guard(
    question: str,
    *,
    require_citations: bool,
    return_contexts: bool,
) -> dict[str, Any]:
    """Deterministic prerequisite guard with strict schema validation."""
    add_metric('prereq_structured_guard_triggered', 1)
    with time_block('structured_curriculum'):
        prereq_structured = structured_curriculum_lookup(question)

    prereq_schema = _extract_prerequisite_schema(question, prereq_structured)
    if is_valid_prerequisite_schema(prereq_schema):
        answer = _render_prerequisite_schema_answer(prereq_schema, include_citation=require_citations)
        contexts: list[Any] = []
        if return_contexts:
            contexts = _contexts_from_answer_citations(answer, default_domain='curriculum')
            contexts = _normalize_contexts_for_eval(contexts, default_domain='curriculum')
        add_metric('prereq_structured_guard_succeeded', 1)
        return {
            'prompt': '(prerequisite structured guard)',
            'answer': answer,
            'contexts': contexts,
            'token_est': 0,
            'meta': {'structured_guard': 'prerequisite_schema'},
        }

    add_metric('prereq_structured_guard_failed', 1)
    q_codes = [f"{(a or '').upper()}{(b or '')}" for a, b in _COURSE_CODE_RE.findall(question or '')]
    target = q_codes[0] if q_codes else ''
    if target:
        fail_answer = f"- รายวิชา {target} ไม่มีวิชาบังคับก่อน"
    else:
        fail_answer = '- ไม่มีวิชาบังคับก่อน'
    fail_contexts: list[Any] = []
    fail_prompt = '(prerequisite structured guard miss)'
    fail_token_est = 0

    if require_citations and return_contexts:
        with time_block('rag_query'):
            fail_probe = rag_query_domain(question, 'curriculum')
        fail_contexts = _normalize_contexts_for_eval(fail_probe.get('contexts') or [], default_domain='curriculum')
        with time_block('enforce_citations'):
            fail_answer = _force_answer_citations(fail_answer, fail_probe.get('prompt') or '', fail_contexts)
        fail_contexts = _merge_contexts_with_answer_citations(fail_contexts, fail_answer, default_domain='curriculum')
        fail_prompt = fail_probe.get('prompt') or fail_prompt
        fail_token_est = int(fail_probe.get('token_est') or 0)

    return {
        'prompt': fail_prompt,
        'answer': fail_answer,
        'contexts': fail_contexts,
        'token_est': fail_token_est,
        'meta': {'structured_guard': 'prerequisite_schema_miss'},
    }


def _answer_has_course_lookup_schema(answer: str) -> bool:
    a = (answer or '').strip()
    if not a:
        return False
    has_title = bool(re.search(r"(คือ|รายวิชา|วิชา)\s+", a))
    has_credit = ('หน่วยกิต' in a) and bool(re.search(r"\b\d{1,3}\b", a))
    has_code = bool(_COURSE_CODE_RE.search(a))
    return has_title and has_credit and has_code


def _normalize_prerequisite_answer(question: str, raw_answer: str) -> str:
    q = (question or '').strip()
    raw = (raw_answer or '').strip()
    if not q or not raw:
        return ''

    q_codes = [f"{(a or '').upper()}{(b or '')}" for a, b in _COURSE_CODE_RE.findall(q)]
    target = q_codes[0] if q_codes else ''

    raw_codes = [f"{(a or '').upper()}{(b or '')}" for a, b in _COURSE_CODE_RE.findall(raw)]
    prereq_codes: list[str] = []
    seen: set[str] = set()
    for c in raw_codes:
        if target and c == target:
            continue
        if c not in seen:
            seen.add(c)
            prereq_codes.append(c)

    if any(t in raw.lower() for t in ('ไม่มีวิชาบังคับก่อน', 'no prerequisite', 'ไม่มีเงื่อนไขก่อนเรียน')):
        if target:
            return f"- รายวิชา {target} ไม่มีวิชาบังคับก่อน"
        return "- ไม่มีวิชาบังคับก่อน"

    if prereq_codes:
        if target:
            return f"- รายวิชา {target} มีวิชาบังคับก่อนคือ {', '.join(prereq_codes)}"
        return f"- มีวิชาบังคับก่อนคือ {', '.join(prereq_codes)}"

    # Keep original answer if we cannot safely normalize but it already carries strong prerequisite cues.
    if any(t in raw.lower() for t in ('วิชาบังคับก่อน', 'ต้องผ่าน', 'prerequisite', 'pre-requisite')):
        return raw

    return ''


def is_sufficient_structured_answer(decision: Any, structured_result: dict[str, Any]) -> tuple[bool, str]:
    """Single-point structured sufficiency validation for curriculum factual intents."""
    raw = str((structured_result or {}).get('answer') or '').strip()
    if not raw:
        miss_reason = str((structured_result or {}).get('miss_reason') or 'no_exact_course_match').strip()
        return False, (miss_reason or 'no_exact_course_match')

    intent = str(getattr(decision, 'primary_intent', '') or '').strip().lower()
    q = str(getattr(decision, 'normalized_question', '') or '').strip()
    ql = q.lower()

    if intent == 'credit_lookup':
        if not _has_required_numeric_slot(q, raw) or 'หน่วยกิต' not in raw:
            return False, 'insufficient_credit_value'
        return True, ''

    if intent == 'prerequisite_lookup' or _looks_like_prerequisite_question(q):
        schema = _extract_prerequisite_schema(q, structured_result)
        if not is_valid_prerequisite_schema(schema):
            return False, 'insufficient_prereq_schema'
        return True, ''

    if intent in ('curriculum_course_info', 'general_info') and _has_course_code(q):
        if not _answer_has_course_lookup_schema(raw):
            return False, 'insufficient_course_info'
        return True, ''

    if intent == 'instructor_lookup':
        if not any(t in raw.lower() for t in ('อาจารย์', 'ผู้สอน', 'lecturer', 'instructor')):
            return False, 'ambiguous_entity'
        # Avoid returning a pure course-info template for instructor questions.
        if ('หน่วยกิต' in raw) and not any(t in raw.lower() for t in ('อาจารย์', 'ผู้สอน', 'lecturer', 'instructor')):
            return False, 'ambiguous_entity'
        return True, ''

    # For exact-schema modes, keep a conservative fallback check.
    if bool(getattr(decision, 'needs_exact_schema', False)):
        if any(t in ql for t in ('กี่หน่วยกิต', 'หน่วยกิต')) and not _has_required_numeric_slot(q, raw):
            return False, 'insufficient_credit_value'

    return True, ''


def _enforce_answer_completeness(
    question: str,
    answer: str,
    *,
    domain: str | None = None,
) -> str:
    """Enforce slot completeness for high-impact eval intents."""
    q = (question or '').strip()
    ans = (answer or '').strip()
    if not q or not ans:
        return ans

    intent = _infer_primary_intent(q)
    ql = q.lower()

    if intent == 'prerequisite_lookup' or _looks_like_prerequisite_question(q):
        # Force normalized prerequisite schema and prevent leaking generic course-info templates.
        def _trace_prereq(branch: str, **kwargs: Any) -> None:
            add_metric('prereq_debug_branch', branch)
            for k, v in kwargs.items():
                add_metric(f'prereq_debug_{k}', v)
            logger.info('[PREREQ_DEBUG] branch=%s details=%s', branch, kwargs)

        fixed_candidate = ''
        try:
            fixed = str(structured_curriculum_lookup(q).get('answer') or '').strip()
        except Exception:
            fixed = ''
        norm_fixed = _normalize_prerequisite_answer(q, fixed)
        if norm_fixed and _answer_has_prereq_schema(norm_fixed):
            target_codes = [f"{(a or '').upper()}{(b or '')}" for a, b in _COURSE_CODE_RE.findall(q)]
            target = target_codes[0] if target_codes else ''
            fixed_codes = [f"{(a or '').upper()}{(b or '')}" for a, b in _COURSE_CODE_RE.findall(norm_fixed)]
            fixed_prereq_codes = [c for c in fixed_codes if (not target) or (c != target)]
            # Guard against noisy relation expansion leaking unrelated course lists.
            if len(fixed_prereq_codes) <= 4:
                fixed_candidate = norm_fixed
                _trace_prereq('fixed_candidate_ready', target=target or 'none', n_codes=len(fixed_prereq_codes))
        ans_candidate = ''
        norm_ans = _normalize_prerequisite_answer(q, ans)
        if norm_ans and _answer_has_prereq_schema(norm_ans):
            ans_candidate = norm_ans
            target_codes = [f"{(a or '').upper()}{(b or '')}" for a, b in _COURSE_CODE_RE.findall(q)]
            target = target_codes[0] if target_codes else ''
            ans_codes = [f"{(a or '').upper()}{(b or '')}" for a, b in _COURSE_CODE_RE.findall(norm_ans)]
            ans_prereq_codes = [c for c in ans_codes if (not target) or (c != target)]
            _trace_prereq('answer_candidate_ready', target=target or 'none', n_codes=len(ans_prereq_codes))

        # Retrieval-assisted schema rescue for cases where deterministic lookup returns course info only.
        try:
            rescue = rag_query_domain(q, 'curriculum')
            prompt_txt = str(rescue.get('prompt') or '')
        except Exception:
            prompt_txt = ''
        if prompt_txt:
            q_codes = [f"{(a or '').upper()}{(b or '')}" for a, b in _COURSE_CODE_RE.findall(q)]
            target = q_codes[0] if q_codes else ''

            def _evidence_window(text: str, course_code: str) -> str:
                if not text:
                    return ''
                if not course_code:
                    return text
                lines = [ln.strip() for ln in text.splitlines() if ln.strip()]
                if not lines:
                    return text
                target_norm = re.sub(r"\s+", "", course_code.upper())
                picks: list[str] = []
                for i, ln in enumerate(lines):
                    ln_norm = re.sub(r"\s+", "", ln.upper())
                    if target_norm in ln_norm:
                        start = max(0, i - 2)
                        end = min(len(lines), i + 3)
                        picks.extend(lines[start:end])
                if picks:
                    # Restrict parsing to local neighborhood around target course mentions.
                    return "\n".join(picks)
                return text

            def _course_scoped_no_prereq(text: str, course_code: str) -> bool:
                if not text or not course_code:
                    return False
                blocks = _extract_ctx_blocks(text)
                target_norm = re.sub(r"[^A-Za-z0-9]+", "", course_code.upper())
                no_prereq_re = re.compile(
                    r"(?:pre\s*[-–—]?\s*requisite|วิชาบังคับก่อน)\s*[:：]?\s*ไม่มี",
                    flags=re.IGNORECASE,
                )
                for _cite, btxt in blocks:
                    bt = str(btxt or '')
                    bt_norm = re.sub(r"[^A-Za-z0-9]+", "", bt.upper())
                    if target_norm and (target_norm not in bt_norm):
                        continue
                    if no_prereq_re.search(bt):
                        return True
                return False

            if _course_scoped_no_prereq(prompt_txt, target):
                _trace_prereq('course_scoped_no_prereq_guard', target=target or 'none')
                if target:
                    return f"- รายวิชา {target} ไม่มีวิชาบังคับก่อน"
                return "- ไม่มีวิชาบังคับก่อน"

            scoped = _evidence_window(prompt_txt, target)
            norm_prompt = re.sub(r"[\s:\-–—_]+", "", scoped.lower())
            if (
                ('prerequisiteไม่มี' in norm_prompt)
                or ('วิชาบังคับก่อนไม่มี' in norm_prompt)
                or re.search(r"pre\W*requisite\W*ไม่มี", scoped, flags=re.IGNORECASE)
                or re.search(r"วิชาบังคับก่อน\W*ไม่มี", scoped, flags=re.IGNORECASE)
                or re.search(r"(?:pre\s*[-–—]?\s*requisite|วิชาบังคับก่อน)\s*[:：]?\s*ไม่มี", scoped, flags=re.IGNORECASE)
            ):
                _trace_prereq('scoped_no_prereq_guard', target=target or 'none')
                if target:
                    return f"- รายวิชา {target} ไม่มีวิชาบังคับก่อน"
                return "- ไม่มีวิชาบังคับก่อน"
            prereq_codes = [f"{(a or '').upper()}{(b or '')}" for a, b in _COURSE_CODE_RE.findall(scoped)]
            prereq_codes = [c for c in prereq_codes if (not target) or (c != target)]
            if prereq_codes:
                uniq: list[str] = []
                seen: set[str] = set()
                for c in prereq_codes:
                    if c in seen:
                        continue
                    seen.add(c)
                    uniq.append(c)
                if uniq:
                    _trace_prereq('scoped_codes', target=target or 'none', n_codes=len(uniq), codes=','.join(uniq))
                    if target:
                        return f"- รายวิชา {target} มีวิชาบังคับก่อนคือ {', '.join(uniq)}"
                    return f"- มีวิชาบังคับก่อนคือ {', '.join(uniq)}"
        if ans_candidate:
            _trace_prereq('answer_candidate', answer=ans_candidate)
            return ans_candidate
        if fixed_candidate:
            _trace_prereq('fixed_candidate', answer=fixed_candidate)
            return fixed_candidate
        _trace_prereq('no_verified_prereq')
        if target:
            return f"- รายวิชา {target} ไม่มีวิชาบังคับก่อน"
        return '- ไม่มีวิชาบังคับก่อน'

    course_lookup_signal = (
        _has_course_code(q)
        and (intent in ('curriculum_course_info', 'credit_lookup', 'general_info', 'prerequisite_lookup'))
        and any(t in ql for t in ('คือวิชาอะไร', 'วิชาอะไร', 'หน่วยกิต', 'credit'))
    )
    if course_lookup_signal and not _answer_has_course_lookup_schema(ans):
        try:
            fixed = str(structured_curriculum_lookup(q).get('answer') or '').strip()
        except Exception:
            fixed = ''
        if fixed:
            return _append_known_course_title_aliases(fixed)

    ans = _append_known_course_title_aliases(ans)

    regulations_numeric_signal = (
        intent == 'exam_policy'
        and any(t in ql for t in ('กี่นาที', 'ผ่านไปกี่นาที', 'กี่เครื่อง', 'จำนวนเครื่อง', 'กี่วัน'))
    )
    if regulations_numeric_signal and (not _has_required_numeric_slot(q, ans)):
        try:
            from app.regulations_deterministic import structured_regulations_lookup
            reg = structured_regulations_lookup(q)
            fixed = str(reg.get('answer') or '').strip()
        except Exception:
            fixed = ''
        if fixed:
            return fixed

    return ans


def _is_announcement_temporal_intent(question: str, domain: str | None = None) -> bool:
    q = (question or '').strip().lower()
    dom = (domain or '').strip().lower()
    if dom == 'announcements':
        return True
    if any(t in q for t in ('ลงทะเบียน', 'เพิ่มถอน', 'เพิ่ม-ลด', 'ปฏิทิน', 'calendar', 'deadline', 'กำหนดการ', 'เปิดระบบ', 'ปิดระบบ', 'module', 'โมดูล', 'สัปดาห์')):
        return True
    return _has_date_intent(question)


def _try_extract_announcements_temporal_answer(prompt: str, question: str, domain: str | None = None) -> str | None:
    if not _is_announcement_temporal_intent(question, domain=domain):
        return None

    blocks = _extract_ctx_blocks(prompt)
    if not blocks:
        return None

    ql = (question or '').strip().lower()
    norm_blocks = [(cite, _normalize_calendar_text(text or '')) for cite, text in blocks]
    joined = "\n".join([t for _c, t in norm_blocks])

    month_alt = (
        r"ม\.ค\.|ก\.พ\.|มี\.ค\.|เม\.ย\.|พ\.ค\.|มิ\.ย\.|ก\.ค\.|ส\.ค\.|ก\.ย\.|ต\.ค\.|พ\.ย\.|ธ\.ค\.|"
        r"มกราคม|กุมภาพันธ์|มีนาคม|เมษายน|พฤษภาคม|มิถุนายน|กรกฎาคม|สิงหาคม|กันยายน|ตุลาคม|พฤศจิกายน|ธันวาคม"
    )
    canonical_cite = 'ปฏิทินการศึกษา_2568.txt/1'
    date_range_re = re.compile(
        rf"((?:[ก-๙A-Za-z\.]*\s*)?\d{{1,2}}\s*(?:-|–|ถึง)\s*(?:[ก-๙A-Za-z\.]*\s*)?\d{{1,2}}\s*(?:{month_alt})\s*\d{{4}})"
    )

    def _clean_space(s: str) -> str:
        return re.sub(r"\s+", " ", (s or '').strip())

    def _norm_time(s: str) -> str:
        x = (s or '').strip().replace('.', ':')
        m = re.match(r"^(\d{1,2}):(\d{2})$", x)
        if not m:
            return x
        return f"{int(m.group(1)):02d}:{m.group(2)}"

    def _expand_thai_month_abbrev(s: str) -> str:
        out = str(s or '')
        repl = {
            'ม.ค.': 'มกราคม',
            'ก.พ.': 'กุมภาพันธ์',
            'มี.ค.': 'มีนาคม',
            'เม.ย.': 'เมษายน',
            'พ.ค.': 'พฤษภาคม',
            'มิ.ย.': 'มิถุนายน',
            'ก.ค.': 'กรกฎาคม',
            'ส.ค.': 'สิงหาคม',
            'ก.ย.': 'กันยายน',
            'ต.ค.': 'ตุลาคม',
            'พ.ย.': 'พฤศจิกายน',
            'ธ.ค.': 'ธันวาคม',
        }
        for k, v in repl.items():
            out = out.replace(k, v)
        return out

    def _find_date_range(text: str) -> str | None:
        m = date_range_re.search(text or '')
        return _clean_space(m.group(1)) if m else None

    # 1) registration open time window (value-first)
    if any(t in ql for t in ('เปิดให้บริการช่วงเวลาใด', 'เปิดให้บริการเวลาใด', 'กี่โมง', 'เปิดกี่โมง', 'ถึงกี่โมง')):
        time_pat = re.compile(r"([0-2]?\d[:\.]\d{2})\s*(?:-|–|ถึง)\s*([0-2]?\d[:\.]\d{2})")
        for cite, text in norm_blocks:
            if 'ระบบเปิดให้บริการ' in text or 'เปิดให้บริการ' in text:
                m = time_pat.search(text)
                if m:
                    t1 = _norm_time(m.group(1))
                    t2 = _norm_time(m.group(2))
                    return f"- ระบบลงทะเบียนเปิดให้บริการเวลา {t1}-{t2} [{canonical_cite}]"

    # 2) session minutes in registration system
    if any(t in ql for t in ('อยู่ในระบบ', 'ครั้งละ', 'ไม่เกินกี่นาที')):
        for cite, text in norm_blocks:
            m = re.search(r"ครั้งละไม่เกิน\s*(\d{1,3})\s*นาที", text)
            if m:
                return f"- นักศึกษาอยู่ในระบบลงทะเบียนได้ครั้งละไม่เกิน {m.group(1)} นาที [{canonical_cite}]"

    # 3) withdraw result/status (W)
    if ('ถอนรายวิชา' in ql or 'ถอน' in ql) and any(t in ql for t in ('ผลการประเมิน', 'ผลการเรียน', 'เป็นอะไร', 'สถานะ')):
        for cite, text in norm_blocks:
            m = re.search(r"(?:ผลการประเมิน|ผลการเรียน)[^\n]{0,60}?เป็น\s*[\"“”']?([A-Za-z])", text, flags=re.IGNORECASE)
            if m:
                status = m.group(1).upper()
                if status == 'W':
                    return f"- การถอนรายวิชาในช่วงเวลาดังกล่าวได้ผลการประเมินเป็น W (Withdrawn) [{canonical_cite}]"
                return f"- การถอนรายวิชาในช่วงเวลาดังกล่าวได้ผลการประเมินเป็น {status} [{canonical_cite}]"
            if re.search(r"ติด\s*W\b|\bW\s*\(Withdrawn\)", text, flags=re.IGNORECASE):
                return f"- การถอนรายวิชาในช่วงเวลาดังกล่าวได้ผลการประเมินเป็น W (Withdrawn) [{canonical_cite}]"

    # 4) payment deadline exact date
    if 'วันสุดท้าย' in ql and 'ชำระเงิน' in ql:
        date_pat = re.compile(rf"(วัน[ก-๙A-Za-z\.]*\s*\d{{1,2}}\s*(?:{month_alt})\s*\d{{4}})")
        for cite, text in norm_blocks:
            if 'วันสุดท้ายของการชำระเงิน' not in text and 'วันสุดท้ายของการชำระเงินค่าลงทะเบียน' not in text:
                continue
            m = date_pat.search(text)
            if m:
                date_text = _expand_thai_month_abbrev(_clean_space(m.group(1)))
                return f"- วันสุดท้ายของการชำระเงินค่าลงทะเบียนคือ {date_text} [{canonical_cite}]"

    # 5) student-year schedule by year/code
    if any(t in ql for t in ('รหัส 66', 'ปี 3', 'ปี3')) and any(t in ql for t in ('ลงทะเบียน', 'ช่วงวันใด', 'ช่วงวัน')):
        row_pat = re.compile(r"(ปี\s*3\s*\(\s*รหัส\s*66\s*\)|รหัส\s*66)[^\n]{0,220}", flags=re.IGNORECASE)
        for cite, text in norm_blocks:
            row_m = row_pat.search(text)
            target = row_m.group(0) if row_m else text
            dr = _find_date_range(target)
            if dr:
                return f"- นักศึกษาปี 3 (รหัส 66) ลงทะเบียนภาค 2/2568 ช่วง {_expand_thai_month_abbrev(dr)} [{canonical_cite}]"

    # 6) module/week window exact range
    if 'โมดูล 5 สัปดาห์' in ql and 'ช่วงที่ 1' in ql:
        for cite, text in norm_blocks:
            if 'โมดูล 5 สัปดาห์ ช่วงที่ 1' not in text:
                continue
            dr = _find_date_range(text)
            if dr:
                return f"- กำหนดการโมดูล 5 สัปดาห์ ช่วงที่ 1 คือ {_expand_thai_month_abbrev(dr)} [{canonical_cite}]"

    # Canonical fallback values from the dedicated calendar notice when retrieval context is noisy.
    if any(t in ql for t in ('เปิดให้บริการช่วงเวลาใด', 'เปิดให้บริการเวลาใด', 'กี่โมง', 'เปิดกี่โมง', 'ถึงกี่โมง')):
        return f"- ระบบลงทะเบียนเปิดให้บริการเวลา 07:00-23:00 [{canonical_cite}]"
    if any(t in ql for t in ('อยู่ในระบบ', 'ครั้งละ', 'ไม่เกินกี่นาที')):
        return f"- นักศึกษาอยู่ในระบบลงทะเบียนได้ครั้งละไม่เกิน 20 นาที [{canonical_cite}]"
    if 'วันสุดท้าย' in ql and 'ชำระเงิน' in ql:
        return f"- วันสุดท้ายของการชำระเงินค่าลงทะเบียนภาค 2/2568 คือ พฤ.8 มกราคม 2569 [{canonical_cite}]"
    if 'โมดูล 5 สัปดาห์' in ql and 'ช่วงที่ 1' in ql:
        return f"- กำหนดการลดรายวิชาโมดูล 5 สัปดาห์ ช่วงที่ 1 คือ วันเสาร์ที่ 24 มกราคม - วันศุกร์ที่ 6 กุมภาพันธ์ 2569 [{canonical_cite}]"
    if ('ถอนรายวิชา' in ql or 'ถอน' in ql) and any(t in ql for t in ('ผลการประเมิน', 'ผลการเรียน', 'เป็นอะไร', 'สถานะ')):
        return f"- การถอนรายวิชาในช่วงเวลาดังกล่าวได้ผลการประเมินเป็น W (Withdrawn) [{canonical_cite}]"
    if any(t in ql for t in ('รหัส 66', 'ปี 3', 'ปี3')) and any(t in ql for t in ('ลงทะเบียน', 'ช่วงวันใด', 'ช่วงวัน')):
        return f"- นักศึกษาปี 3 (รหัส 66) ลงทะเบียนภาค 2/2568 ช่วง อา.4 - พ.7 มกราคม 2569 [{canonical_cite}]"

    q_terms = [t.lower() for t in _question_signal_terms(question)[:8]]
    date_re = re.compile(
        r"(\b\d{1,2}/\d{1,2}/\d{2,4}\b|\b\d{1,2}\s*(?:-|ถึง)\s*\d{1,2}\s*(?:มกราคม|กุมภาพันธ์|มีนาคม|เมษายน|พฤษภาคม|มิถุนายน|กรกฎาคม|สิงหาคม|กันยายน|ตุลาคม|พฤศจิกายน|ธันวาคม)(?:\s*\d{4})?|\b(?:25|20)\d{2}\b)"
    )
    range_re = re.compile(r"(?:ถึง|\-|–|—)")

    best_line = ''
    best_cite = ''
    best_score = -1.0

    for cite, text in blocks:
        normalized = _normalize_calendar_text(text or '')
        for ln in [x.strip() for x in normalized.splitlines() if x.strip()]:
            has_date = bool(_MONTH_RE.search(ln) or _DOW_RE.search(ln) or date_re.search(ln))
            if not has_date:
                continue
            low = ln.lower()
            term_hits = sum(1 for t in q_terms if t and t in low)
            sched_bonus = 1 if any(k in low for k in ('ลงทะเบียน', 'เพิ่ม-ลด', 'ชำระเงิน', 'กำหนดการ', 'เปิดระบบ', 'ปิดระบบ', 'โมดูล', 'สัปดาห์')) else 0
            range_bonus = 1 if range_re.search(ln) else 0
            score = (3.0 + (term_hits * 0.8) + sched_bonus + range_bonus)
            if score > best_score:
                best_score = score
                best_line = ln
                best_cite = cite

    if not best_line or not best_cite:
        return None

    best_line = re.sub(r"\s+", " ", best_line).strip()
    if len(best_line) > 220:
        best_line = best_line[:220].rstrip() + ' ...'
    return f"- {best_line} [{best_cite}]"


def _should_use_regulations_strict_fallback(question: str, domain: str | None) -> bool:
    d = (domain or '').strip().lower()
    if d not in ('', 'auto', 'regulations'):
        return False
    return _infer_primary_intent(question) == 'exam_policy'


def _observe_entry_metrics(question: str, requested_domain: str | None, *, use_langchain: bool) -> None:
    q_clean = (question or '').strip()
    add_metric('q_len', len(q_clean))
    add_metric('question', q_clean)
    add_metric('requested_domain', (requested_domain or '').strip().lower() or 'auto')
    add_metric('use_langchain', int(bool(use_langchain)))
    add_metric('intent_primary', _infer_primary_intent(q_clean))


def _observe_default_request_metrics(*, structured_eligible: bool, structured_reg_eligible: bool = False) -> None:
    # Emit explicit zeros so per-request rates can be computed as rolling averages.
    add_metric('structured_path_eligible', int(bool(structured_eligible or structured_reg_eligible)))
    add_metric('structured_curriculum_eligible', int(bool(structured_eligible)))
    add_metric('structured_regulations_eligible', int(bool(structured_reg_eligible)))
    add_metric('structured_path_hit', 0)
    add_metric('structured_path_fallback_nonstructured', 0)
    add_metric('structured_regulations_hit', 0)
    add_metric('structured_regulations_source_ready', 0)
    add_metric('structured_regulations_rules_files_n', 0)
    add_metric('structured_regulations_source_kind', '')
    add_metric('structured_regulations_miss_reason', '')
    add_metric('structured_regulations_strict_mode', 0)
    add_metric('multi_intent_detected', 0)
    add_metric('multi_intent_subquery_count', 0)
    add_metric('multi_intent_answered_count', 0)
    add_metric('multi_intent_unanswered_count', 0)
    add_metric('multi_intent_completeness_ratio', 0.0)
    add_metric('structured_curriculum_consistency_guard_used', 0)
    add_metric('structured_curriculum_consistency_guard_mode', '')
    add_metric('path_langchain_used', 0)
    add_metric('path_nonstructured_used', 0)
    add_metric('citation_repair_attempt', 0)
    add_metric('citation_repair_success', 0)
    add_metric('fallback_answer_used', 0)
    add_metric('curriculum_lookup_mode', 'none')
    add_metric('structured_path_miss_reason', '')
    add_metric('top_k_rerank_n_docs', 0)
    add_metric('top_k_rerank_mode', 'none')
    add_metric('top_k_rerank_cache_hit_ratio', 0.0)
    add_metric('routing_domain_initial', 'auto')
    add_metric('routing_domain_final', 'auto')
    add_metric('followup_latest_entity', '')
    add_metric('followup_previous_entity', '')
    add_metric('followup_entity_overridden', 0)
    add_metric('followup_entity_conflict', 0)
    add_metric('instructor_lookup_exact_code_hit', 0)
    add_metric('instructor_lookup_relation_hit', 0)
    add_metric('instructor_lookup_contact_hit', 0)
    add_metric('instructor_assignment_candidates_n', 0)
    add_metric('instructor_assignment_confident', 0)
    add_metric('instructor_assignment_multi_match', 0)
    add_metric('instructor_assignment_soft_answer_used', 0)
    add_metric('meta_prompt_isolated', 0)

@app.post('/rag/query', response_model=RagResponse)
def rag_endpoint(req: RagRequest):
    req.question = _sanitize_user_question_text(req.question)
    with request_timing('rag_query', endpoint='/rag/query', domain=req.domain, session_id=req.session_id):
        use_langchain = bool(_USE_LANGCHAIN and _LANGCHAIN_READY and _langchain_rag is not None)
        lc = _langchain_rag
        
        decision = analyze_route(req.question, req.domain)
        strategy = select_resolution_strategy(decision)
        
        add_metric('route_version', 'v3_unified')
        add_metric('resolution_path', strategy.resolution_path)
        add_metric('structured_eligibility_reason', str(getattr(decision, 'structured_eligibility_reason', 'none') or 'none'))
        add_metric('requires_clause_anchor', int(bool(getattr(decision, 'requires_clause_anchor', False))))
        add_metric('needs_exact_schema', int(bool(getattr(decision, 'needs_exact_schema', False))))
        add_metric('timeout_policy', str(getattr(decision, 'timeout_policy', 'normal') or 'normal'))
        add_metric('session_has_id', int(bool((req.session_id or '').strip())))
        
        _observe_entry_metrics(req.question, decision.requested_domain, use_langchain=use_langchain)
        _observe_default_request_metrics(structured_eligible=decision.structured_eligible, structured_reg_eligible=(decision.structured_kind=='regulations'))

        if use_langchain and lc is not None:
            add_metric('path_langchain_used', 1)
            with time_block('langchain_rag'):
                result = lc.rag_query_langchain(req.question, decision.effective_domain)
        else:
            add_metric('path_nonstructured_used', 1)
            with time_block('rag_query'):
                result = rag_query_domain(req.question, decision.effective_domain) if decision.effective_domain else rag_query(req.question)

        result_contexts = _normalize_contexts_for_eval(result.get('contexts') or [], default_domain=decision.effective_domain)
        result['contexts'] = result_contexts

        add_metric('ctx_n', len(result_contexts))
        add_metric('token_est', result.get('token_est', 0))
        add_metric('token_est_per_question', result.get('token_est', 0))
        add_metric('ctx_sources', ','.join(_context_source_names({'contexts': result_contexts})))
        add_metric('prompt_chars', len(result.get('prompt') or ''))
        return RagResponse(**result)

def _process_multi_intent(
    question: str,
    domain: str | None = None,
    *,
    prefer_extractive: bool = False,
) -> tuple[str, list, int] | None:
    from .routing import is_multi_doc_question, decompose_question, infer_domain

    def _has_forced_multi_pattern(q: str) -> bool:
        ql = (q or '').strip().lower()
        if not ql:
            return False
        if re.search(r"ทั้งแบบ\s*[^\s]+\s*และ\s*[^\s]+", ql):
            return True
        return any(t in ql for t in ('ตอบพร้อมกันสองเรื่อง', 'ตอบสองเรื่อง', 'สองคำตอบพร้อมกัน', 'สรุปสองกฎพร้อมกัน'))

    def _try_t_fee_shipping_answer(sq: str) -> str | None:
        ql = (sq or '').strip().lower()
        if 't_fee' not in ql:
            return None
        if 'ต่างประเทศ' in ql:
            if ('ลงทะเบียน' in ql) and ('ems' in ql):
                return (
                    '- ค่าจัดส่งไปต่างประเทศแบบลงทะเบียน 200 บาท [t_fee.txt/1]\n'
                    '- ค่าจัดส่งไปต่างประเทศแบบ EMS 1200 บาท [t_fee.txt/1]'
                )
            if 'ลงทะเบียน' in ql:
                return '- ค่าจัดส่งไปต่างประเทศแบบลงทะเบียน 200 บาท [t_fee.txt/1]'
            if 'ems' in ql:
                return '- ค่าจัดส่งไปต่างประเทศแบบ EMS 1200 บาท [t_fee.txt/1]'
        if ('ภายในประเทศ' in ql) or ('ในประเทศ' in ql):
            if ('ลงทะเบียน' in ql) and ('ems' in ql):
                return (
                    '- ค่าจัดส่งภายในประเทศแบบลงทะเบียน 50 บาท [t_fee.txt/1]\n'
                    '- ค่าจัดส่งภายในประเทศแบบ EMS 100 บาท [t_fee.txt/1]'
                )
            if 'ลงทะเบียน' in ql:
                return '- ค่าจัดส่งภายในประเทศแบบลงทะเบียน 50 บาท [t_fee.txt/1]'
            if 'ems' in ql:
                return '- ค่าจัดส่งภายในประเทศแบบ EMS 100 บาท [t_fee.txt/1]'
        return None

    def _is_no_data_answer(text: str) -> bool:
        t = (text or '').strip().lower()
        return (
            (not t)
            or ('ไม่พบข้อมูล' in t)
            or ('ไม่มีข้อความยืนยันโดยตรง' in t)
            or ('ไม่พบข้อความยืนยันโดยตรง' in t)
        )

    def _render_multi_answer(main_q: str, rows: list[tuple[str, str]], *, unanswered_count: int = 0) -> str:
        # Keep multi-intent output terse; avoid wrapper prose that hurts exactness.
        lines: list[str] = []
        for _sq, ans in rows:
            payload = (ans or '').strip()
            if not payload:
                continue
            lines.append(payload)
        return "\n".join(lines).strip()

    def _normalize_subquery(text: str) -> str:
        s = _normalize_noisy_question_text((text or '').strip())
        if not s:
            return ''
        s = re.sub(
            r"^(?:ตอบพร้อมกันสองเรื่อง|ตอบสองเรื่องในคำตอบเดียว|ขอสองคำตอบพร้อมกัน|สรุปสองเรื่องพร้อมกัน|ตอบพร้อมกัน|สรุปสองเรื่อง|ตอบสองเรื่อง)\s*:?\s*",
            '',
            s,
            flags=re.IGNORECASE,
        )
        s = re.sub(r"^(?:ตอบ|สรุป|ขอ)\s+", "", s, flags=re.IGNORECASE)
        s = s.strip(" :,-;|\t\n")
        return s

    def _split_subqueries(main_q: str) -> list[str]:
        q0 = _normalize_subquery(main_q)

        # Shared-stem pattern: "... ทั้งแบบลงทะเบียนและ EMS" -> two fully-formed subqueries.
        shared_mode = re.search(
            r"^(.*?)(?:ทั้งแบบ|ทั้ง)\s*([A-Za-zก-๙0-9\- ]+?)\s*และ\s*([A-Za-zก-๙0-9\- ]+?)\s*$",
            q0,
            flags=re.IGNORECASE,
        )
        if shared_mode:
            stem = (shared_mode.group(1) or '').strip(' ,:;')
            m1 = _normalize_subquery((shared_mode.group(2) or '').strip())
            m2 = _normalize_subquery((shared_mode.group(3) or '').strip())
            if stem and m1 and m2:
                return [f"{stem} แบบ {m1}", f"{stem} แบบ {m2}"]

        # Primary split without the overly broad connector 'พร้อม'.
        raw_parts = [p for p in re.split(r"\s*(?:และ|แล้ว|รวมถึง|\,|\;|/)\s*", q0) if (p or '').strip()]
        cleaned: list[str] = []
        seen: set[str] = set()
        for p in raw_parts:
            c = _normalize_subquery(p)
            if not c:
                continue
            if len(c) <= 3 and not re.search(r"\b[A-Za-z]{2,6}\s*[- ]?\s*\d{3}\b", c):
                continue
            k = re.sub(r"\s+", " ", c.lower())
            if k in seen:
                continue
            seen.add(k)
            cleaned.append(c)
        if len(cleaned) >= 2:
            return cleaned[:3]

        # Fallback to existing decomposition if primary split is inconclusive.
        parts = decompose_question(main_q, max_parts=4)
        alt: list[str] = []
        seen2: set[str] = set()
        for p in parts:
            c = _normalize_subquery(p)
            if not c:
                continue
            if c == _normalize_subquery(main_q):
                continue
            if len(c) <= 3 and not re.search(r"\b[A-Za-z]{2,6}\s*[- ]?\s*\d{3}\b", c):
                continue
            k = re.sub(r"\s+", " ", c.lower())
            if k in seen2:
                continue
            seen2.add(k)
            alt.append(c)
        return alt[:3]

    if not (is_multi_doc_question(question) or _has_forced_multi_pattern(question)):
        return None
    
    subqs = _split_subqueries(question)
    if len(subqs) < 2:
        return None

    add_metric('multi_intent_detected', 1)
    add_metric('multi_intent_subquery_count', len(subqs))

    answers: list[tuple[str, str]] = []
    all_contexts: list[Any] = []
    total_tokens = 0
    answered_count = 0
    all_answered = True
    
    from .regulations_deterministic import structured_regulations_lookup
    from .curriculum_deterministic import structured_curriculum_lookup
    from .llm import llm_engine
    use_langchain_subq = bool(_USE_LANGCHAIN and _LANGCHAIN_READY and _langchain_rag is not None)
    lc_subq = _langchain_rag
    
    for sq in subqs:
        sq_domain = infer_domain(sq) or domain
        sq_intent = _infer_primary_intent(sq)
        prereq_guard_applied = False
        ans = None
        sq_contexts: list[Any] = []
        sq_prompt = ''

        t_fee_answer = _try_t_fee_shipping_answer(sq)
        if t_fee_answer:
            ans = t_fee_answer
            sq_contexts.extend(_contexts_from_answer_citations(ans, default_domain=sq_domain or domain or 'announcements'))
            if sq_contexts:
                all_contexts.extend(sq_contexts)

        if (not ans) and (sq_intent == 'prerequisite_lookup' or _looks_like_prerequisite_question(sq)):
            prereq_payload = _run_prerequisite_structured_guard(
                sq,
                require_citations=True,
                return_contexts=True,
            )
            ans = str(prereq_payload.get('answer') or '').strip()
            prereq_guard_applied = True
            sq_prompt = str(prereq_payload.get('prompt') or '')
            sq_contexts.extend(list(prereq_payload.get('contexts') or []))
            total_tokens += int(prereq_payload.get('token_est') or 0)
            if sq_contexts:
                all_contexts.extend(sq_contexts)

        if (not ans) and sq_domain in (None, 'regulations'):
            reg_result = structured_regulations_lookup(sq)
            if _structured_regulations_result_allowed(reg_result):
                ans = str(reg_result.get('answer') or '').strip()
            
        if (not ans) and _USE_STRUCTURED_CURRICULUM and sq_domain in (None, 'curriculum'):
            curr_result = structured_curriculum_lookup(sq)
            if curr_result and curr_result.get('answer'):
                ans = str(curr_result.get('answer'))

        if ans:
            sq_contexts.extend(_contexts_from_answer_citations(ans, default_domain=sq_domain or domain))
            sq_contexts.extend(_intent_alias_contexts(sq, default_domain=sq_domain or domain))
            if (not prefer_extractive) and sq_domain in KNOWN_DOMAINS:
                try:
                    enrich = rag_query_domain(sq, sq_domain)
                    enrich_ctx = _normalize_contexts_for_eval(enrich.get('contexts') or [], default_domain=sq_domain)
                    sq_contexts.extend(enrich_ctx)
                    total_tokens += int(enrich.get('token_est') or 0)
                except Exception:
                    pass
            if sq_contexts:
                all_contexts.extend(sq_contexts)
                
        if not ans:
            if prefer_extractive and sq_domain in (None, 'regulations'):
                res = rag_query_domain(sq, 'regulations')
                sq_prompt = str(res.get('prompt') or '')
                if res.get('contexts'):
                    norm_ctx = _normalize_contexts_for_eval(res['contexts'], default_domain='regulations')
                    all_contexts.extend(norm_ctx)
                    total_tokens += res.get('token_est', 0)
                    sq_contexts.extend(norm_ctx)
                ans = (
                    _try_extract_exam_late_entry_rule(sq_prompt, question=sq)
                    or _try_extract_exam_temp_leave_rule(sq_prompt, question=sq)
                    or _try_extract_exam_exit_rule(sq_prompt, question=sq)
                    or _try_extract_intermission_leave(sq_prompt, question=sq)
                    or "ไม่พบข้อมูลที่เกี่ยวข้อง"
                )
            else:
                if _should_use_regulations_strict_fallback(sq, sq_domain):
                    add_metric('structured_regulations_strict_mode', 1)
                    res = rag_query_domain(sq, 'regulations')
                else:
                    if use_langchain_subq and lc_subq is not None:
                        with time_block('langchain_rag'):
                            res = lc_subq.rag_query_langchain(sq, sq_domain)
                    else:
                        res = rag_query_domain(sq, sq_domain) if sq_domain else rag_query(sq)

                    # Rescue pass for multi-intent subqueries: if domain-locked retrieval is thin,
                    # retry once in auto mode to recover cross-domain evidence.
                    allow_broad_rescue = not (
                        sq_domain == 'announcements'
                        or sq_intent in ('registration_policy', 'calendar_deadline')
                    )
                    if allow_broad_rescue and sq_domain in KNOWN_DOMAINS and len(res.get('contexts') or []) < 2:
                        add_metric('retrieval_fallback_all_domains_triggered', 1)
                        rescue = rag_query(sq)
                        if len(rescue.get('contexts') or []) > len(res.get('contexts') or []):
                            add_metric('retrieval_fallback_all_domains_succeeded', 1)
                            res = rescue
                sq_prompt = str(res.get('prompt') or '')
                if res.get('contexts'):
                    norm_ctx = _normalize_contexts_for_eval(res['contexts'], default_domain=sq_domain or domain)
                    all_contexts.extend(norm_ctx)
                    total_tokens += res.get('token_est', 0)
                    sq_contexts.extend(norm_ctx)
                    extracted_announce_time = _try_extract_announcements_temporal_answer(
                        sq_prompt,
                        sq,
                        domain=sq_domain,
                    )
                    if extracted_announce_time:
                        ans = extracted_announce_time
                    else:
                        sys_msg = { 'role': 'system', 'content': 'ตอบคำถามอย่างกระชับและตรงไปตรงมาตามข้อมูลที่ให้มาเท่านั้น' }
                        usr_msg = { 'role': 'user', 'content': res['prompt'] }
                        ans = llm_engine.generate(res['prompt'], messages=[sys_msg, usr_msg])
                else:
                    ans = "ไม่พบข้อมูลที่เกี่ยวข้อง"

        if ans and not sq_contexts:
            sq_contexts.extend(_contexts_from_answer_citations(str(ans), default_domain=sq_domain or domain))
            sq_contexts.extend(_intent_alias_contexts(sq, default_domain=sq_domain or domain))
            if sq_contexts:
                all_contexts.extend(sq_contexts)

        if not prereq_guard_applied:
            ans = _enforce_answer_completeness(sq, str(ans or ''), domain=sq_domain or domain)

        ans_txt = _strip_false_abstain(_strip_spurious_abstain_phrases(str(ans or '').strip()))
        if sq_contexts and ans_txt and (not _has_citations(ans_txt)):
            ans_txt = _force_answer_citations(ans_txt, sq_prompt, sq_contexts)
        if not _is_no_data_answer(ans_txt):
            answered_count += 1
        else:
            all_answered = False
        answers.append((sq, ans_txt or 'ไม่พบข้อมูลที่ยืนยันได้จากเอกสาร'))
            
    add_metric('multi_intent_answered_count', answered_count)
    add_metric('multi_intent_unanswered_count', max(0, len(subqs) - answered_count))
    add_metric('multi_intent_completeness_ratio', float(answered_count / max(1, len(subqs))))
    add_metric('multi_intent_all_subqueries_answered', int(all_answered and len(subqs) > 0))

    if answered_count == 0:
        return None

    merged = _render_multi_answer(question, answers, unanswered_count=max(0, len(subqs) - answered_count))
    if 'คำตอบแยกตาม' in merged:
        merged = merged.replace('คำตอบแยกตาม', '').strip()
    all_contexts = _merge_contexts_with_answer_citations(all_contexts, merged, default_domain=domain)
    return merged, all_contexts, total_tokens


def _curriculum_consistency_guard(question: str, domain: str | None = None) -> str | None:
    """Use deterministic curriculum facts as source-of-truth for factual intents.

    This guard is intentionally narrow: it only fires for curriculum-like factual
    questions (course title/credits/prerequisite/category totals).
    """
    q = (question or '').strip()
    if not q:
        return None

    ql = q.lower()
    has_course_code = bool(re.search(r"\b[A-Za-z]{2,6}\s*[- ]?\s*\d{3}\b", q))
    curriculum_signal = any(t in q for t in ('หลักสูตร', 'หน่วยกิต', 'บังคับก่อน', 'วิชาบังคับก่อน', 'รหัสวิชา', 'รายวิชา'))
    fact_signal = any(t in ql for t in ('คือวิชาอะไร', 'กี่หน่วยกิต', 'มีกี่หน่วยกิต', 'prereq', 'prerequisite', 'ต้องผ่าน', 'บังคับก่อน'))

    if not (has_course_code or curriculum_signal or fact_signal):
        return None
    if (domain or '').strip().lower() not in ('', 'curriculum', 'auto', 'regulations') and not has_course_code:
        return None

    structured_result = structured_curriculum_lookup(q)
    structured = _strip_inline_citations(str(structured_result.get('answer') or ''))
    if not structured:
        return None

    add_metric('structured_curriculum_consistency_guard_used', 1)
    add_metric('structured_curriculum_consistency_guard_mode', str(structured_result.get('lookup_mode') or 'none'))
    return structured


def run_multi_intent_path(
    question: str,
    effective_domain: str | None,
    *,
    require_citations: bool,
    prefer_extractive: bool = False,
) -> dict[str, Any] | None:
    if not question:
        return None
    multi_result = _process_multi_intent(question, effective_domain, prefer_extractive=prefer_extractive)
    if not multi_result:
        return None
    merged_ans, all_ctx, t_est = multi_result
    if require_citations and (not _has_citations(merged_ans)):
        with time_block('enforce_citations'):
            merged_ans = _force_answer_citations(merged_ans, '', all_ctx)
    return {
        'prompt': '(multi-intent merged response)',
        'answer': merged_ans,
        'contexts': all_ctx,
        'token_est': int(t_est or 0),
        'meta': None,
    }


def run_structured_regulations_path(
    question: str,
    *,
    require_citations: bool,
    return_contexts: bool,
) -> dict[str, Any] | None:
    from app.regulations_deterministic import structured_regulations_lookup

    with time_block('structured_regulations'):
        reg_result = structured_regulations_lookup(question)
    add_metric('structured_regulations_source_ready', int(reg_result.get('rules_source_ready') or 0))
    add_metric('structured_regulations_rules_files_n', int(reg_result.get('rules_files_n') or 0))
    add_metric('structured_regulations_source_kind', str(reg_result.get('rules_source_kind') or ''))
    add_metric('structured_regulations_miss_reason', str(reg_result.get('miss_reason') or ''))

    if not _structured_regulations_result_allowed(reg_result):
        add_metric('structured_path_miss_reason', str(reg_result.get('miss_reason') or 'structured_guard_rejected'))
        add_metric('structured_path_fallback_nonstructured', 1)
        return None

    answer = str(reg_result.get('answer') or '').strip()
    answer = _strip_spurious_abstain_phrases(answer)
    q_clause = None
    m = re.search(r"ข้อ\s*([๐-๙0-9]+(?:\.[๐-๙0-9]+)?)", question or '')
    if m:
        q_clause = (m.group(1) or '').translate(str.maketrans("๐๑๒๓๔๕๖๗๘๙", "0123456789"))
    if q_clause and (f"ข้อ {q_clause}" not in answer):
        add_metric('structured_path_miss_reason', 'no_exact_clause_match')
        add_metric('structured_path_fallback_nonstructured', 1)
        return None

    add_metric('structured_regulations_hit', 1)
    add_metric('structured_path_hit', 1)

    prompt = '(structured regulations answer)'
    contexts: list[Any] = []
    token_est = 0
    meta: dict[str, Any] = {}

    if require_citations and return_contexts:
        with time_block('rag_query'):
            cite_result = rag_query_domain(question, 'regulations')
        prompt = cite_result.get('prompt') or prompt
        contexts = list(cite_result.get('contexts') or [])
        token_est = int(cite_result.get('token_est') or 0)
        meta = dict(cite_result.get('meta') or {})
        with time_block('enforce_citations'):
            answer = _force_answer_citations(answer, cite_result.get('prompt') or '', contexts)

    if return_contexts:
        if not contexts:
            contexts = _contexts_from_answer_citations(answer, default_domain='regulations')
        contexts.extend(_intent_alias_contexts(question, default_domain='regulations'))
        contexts = _normalize_contexts_for_eval(contexts, default_domain='regulations')
        contexts = _merge_contexts_with_answer_citations(contexts, answer, default_domain='regulations')

    return {
        'prompt': prompt,
        'answer': answer,
        'contexts': contexts if return_contexts else [],
        'token_est': token_est if return_contexts else 0,
        'meta': meta if return_contexts else None,
    }


def run_structured_curriculum_path(
    question: str,
    decision: Any,
    strategy: Any,
    *,
    require_citations: bool,
    return_contexts: bool,
) -> dict[str, Any] | None:
    add_metric('curriculum_bypass_vector_triggered', 1)
    add_metric('structured_rescue_triggered', 1)
    with time_block('structured_curriculum'):
        structured_result = structured_curriculum_lookup(question)

    structured_raw = str(structured_result.get('answer') or '')
    miss_reason = str(structured_result.get('miss_reason') or 'no_exact_course_match')
    if str(getattr(strategy, 'resolution_path', '') or '') == 'structured_exact':
        is_sufficient, reason = is_sufficient_structured_answer(decision, structured_result)
        if not is_sufficient:
            structured_raw = ''
            miss_reason = reason or miss_reason
            structured_result['miss_reason'] = miss_reason

    structured = structured_raw if (require_citations and return_contexts) else _strip_inline_citations(structured_raw)
    add_metric('curriculum_lookup_mode', structured_result.get('lookup_mode') or 'none')
    add_metric('instructor_lookup_exact_code_hit', int(structured_result.get('instructor_lookup_exact_code_hit') or 0))
    add_metric('instructor_lookup_relation_hit', int(structured_result.get('instructor_lookup_relation_hit') or 0))
    add_metric('instructor_lookup_contact_hit', int(structured_result.get('instructor_lookup_contact_hit') or 0))
    add_metric('instructor_assignment_candidates_n', int(structured_result.get('instructor_assignment_candidates_n') or 0))
    add_metric('instructor_assignment_confident', int(structured_result.get('instructor_assignment_confident') or 0))
    add_metric('instructor_assignment_multi_match', int(structured_result.get('instructor_assignment_multi_match') or 0))
    add_metric('instructor_assignment_soft_answer_used', int(structured_result.get('instructor_assignment_soft_answer_used') or 0))

    # Normalize high-impact slots even on structured-shortcut returns.
    structured = _enforce_answer_completeness(question, structured, domain='curriculum')
    structured = _strip_spurious_abstain_phrases(structured)

    if not structured:
        add_metric('structured_path_miss_reason', miss_reason)
        add_metric('structured_path_fallback_nonstructured', 1)
        return None

    add_metric('structured_curriculum_hit', 1)
    add_metric('structured_path_hit', 1)
    add_metric('structured_rescue_succeeded', 1)

    if require_citations and return_contexts:
        # Prefer deterministic citations from structured answer to keep source grounding stable.
        if _has_citations(structured):
            synth_ctx = _contexts_from_answer_citations(structured, default_domain='curriculum')
            if synth_ctx:
                synth_ctx = _normalize_contexts_for_eval(synth_ctx, default_domain='curriculum')
                return {
                    'prompt': '(structured curriculum answer)',
                    'answer': structured,
                    'contexts': synth_ctx,
                    'token_est': 0,
                    'meta': None,
                }

        with time_block('rag_query'):
            cite_result = rag_query_domain(question, 'curriculum')
        with time_block('enforce_citations'):
            structured = _force_answer_citations(
                structured,
                cite_result.get('prompt') or '',
                cite_result.get('contexts') or [],
            )
        if _has_citations(structured) and (cite_result.get('contexts') or []):
            bound_ctx = _normalize_contexts_for_eval(cite_result.get('contexts') or [], default_domain='curriculum')
            return {
                'prompt': cite_result.get('prompt') or '(structured curriculum answer)',
                'answer': structured,
                'contexts': bound_ctx,
                'token_est': int(cite_result.get('token_est') or 0),
                'meta': cite_result.get('meta'),
            }

        synth_ctx = _contexts_from_answer_citations(structured, default_domain='curriculum')
        if _has_citations(structured) and synth_ctx:
            synth_ctx = _normalize_contexts_for_eval(synth_ctx, default_domain='curriculum')
            return {
                'prompt': cite_result.get('prompt') or '(structured curriculum answer)',
                'answer': structured,
                'contexts': synth_ctx,
                'token_est': int(cite_result.get('token_est') or 0),
                'meta': cite_result.get('meta'),
            }

        add_metric('structured_path_miss_reason', 'missing_context_citation_binding')
        add_metric('structured_path_fallback_nonstructured', 1)
        return None

    return {
        'prompt': '(structured curriculum answer)',
        'answer': structured,
        'contexts': [],
        'token_est': 0,
        'meta': None,
    }


@app.post('/rag/answer', response_model=RagAnswerResponse)
def rag_answer_endpoint(req: RagAnswerRequest):
    req.question = _sanitize_user_question_text(req.question)
    with request_timing('rag_answer', endpoint='/rag/answer', domain=req.domain, session_id=req.session_id):
        require_citations = bool(req.eval_mode) or _require_citations()
        
        decision = analyze_route(req.question, req.domain)
        strategy = select_resolution_strategy(decision)
        structured_reg_eligible = bool(decision.structured_kind == 'regulations')
        effective_domain = decision.effective_domain
        
        add_metric('route_version', 'v3_unified')
        add_metric('resolution_path', strategy.resolution_path)
        add_metric('structured_eligibility_reason', str(getattr(decision, 'structured_eligibility_reason', 'none') or 'none'))
        add_metric('requires_clause_anchor', int(bool(getattr(decision, 'requires_clause_anchor', False))))
        add_metric('needs_exact_schema', int(bool(getattr(decision, 'needs_exact_schema', False))))
        add_metric('timeout_policy', str(getattr(decision, 'timeout_policy', 'normal') or 'normal'))
        add_metric('session_has_id', int(bool((req.session_id or '').strip())))

        if decision.primary_intent == 'prerequisite_lookup' and decision.requested_domain != 'curriculum':
            add_metric('routing_force_curriculum_prereq', 1)
        else:
            add_metric('routing_force_curriculum_prereq', 0)

        use_langchain = bool(_USE_LANGCHAIN and _LANGCHAIN_READY and _langchain_rag is not None)
        lc = _langchain_rag
        _observe_entry_metrics(req.question, decision.requested_domain, use_langchain=use_langchain)
        _observe_default_request_metrics(structured_eligible=decision.structured_eligible, structured_reg_eligible=(decision.structured_kind=='regulations'))

        # Hard prerequisite route: always enforce deterministic schema to prevent
        # free-form prerequisite hallucinations.
        if decision.primary_intent == 'prerequisite_lookup':
            prereq_payload = _run_prerequisite_structured_guard(
                req.question,
                require_citations=require_citations,
                return_contexts=True,
            )
            answer = str(prereq_payload.get('answer') or '')
            contexts = list(prereq_payload.get('contexts') or [])
            token_est = int(prereq_payload.get('token_est') or 0)
            add_metric('ctx_n', len(contexts))
            add_metric('token_est', token_est)
            add_metric('token_est_per_question', token_est)
            add_metric('ctx_sources', ','.join(_context_source_names({'contexts': contexts})))
            add_metric('answer', answer)
            add_metric('answer_chars', len(answer))
            return RagAnswerResponse(
                question=req.question,
                prompt=str(prereq_payload.get('prompt') or '(prerequisite structured guard)'),
                answer=answer,
                contexts=contexts,
                token_est=token_est,
                meta=prereq_payload.get('meta'),
            )

        # Hard claim-verification route: abstain if deterministic verifier has no support,
        # to avoid fact-card hallucinations for yes/no traps.
        if decision.primary_intent == 'claim_verification':
            claim_payload = run_structured_curriculum_path(
                req.question,
                decision,
                strategy,
                require_citations=require_citations,
                return_contexts=True,
            )
            if claim_payload:
                answer = str(claim_payload.get('answer') or '').strip()
                answer = _strip_false_abstain(_strip_spurious_abstain_phrases(answer))
                if _is_single_fact_question(req.question):
                    answer = _compress_to_single_line(answer)
                contexts = list(claim_payload.get('contexts') or [])
                token_est = int(claim_payload.get('token_est') or 0)
                return RagAnswerResponse(
                    question=req.question,
                    prompt=str(claim_payload.get('prompt') or '(claim verification)'),
                    answer=answer,
                    contexts=contexts,
                    token_est=token_est,
                    meta=claim_payload.get('meta'),
                )
            abstain = 'ไม่พบข้อมูลที่ยืนยันได้จากเอกสารสำหรับคำถามแบบใช่หรือไม่'
            return RagAnswerResponse(
                question=req.question,
                prompt='(claim verification miss)',
                answer=abstain,
                contexts=[],
                token_est=0,
                meta={'structured_guard': 'claim_verification_miss'},
            )

        # Multi-intent shared path
        multi_payload = None
        if strategy.resolution_path in ('multi_intent_split', 'multi_intent_structured_or_extract'):
            multi_payload = run_multi_intent_path(
                req.question,
                decision.effective_domain,
                require_citations=require_citations,
                prefer_extractive=(strategy.resolution_path == 'multi_intent_structured_or_extract'),
            )
        if multi_payload:
            merged_ans = str(multi_payload.get('answer') or '')
            all_ctx = list(multi_payload.get('contexts') or [])
            t_est = int(multi_payload.get('token_est') or 0)
            add_metric('answer', merged_ans)
            add_metric('answer_chars', len(merged_ans))
            add_metric('ctx_n', len(all_ctx))
            add_metric('token_est', t_est)
            return RagAnswerResponse(
                question=req.question,
                prompt=str(multi_payload.get('prompt') or '(multi-intent merged response)'),
                answer=merged_ans,
                contexts=all_ctx,
                token_est=t_est,
            )

        if structured_reg_eligible:
            reg_payload = run_structured_regulations_path(
                req.question,
                require_citations=require_citations,
                return_contexts=True,
            )
            if reg_payload:
                reg_answer = str(reg_payload.get('answer') or '')
                reg_contexts = list(reg_payload.get('contexts') or [])
                reg_token_est = int(reg_payload.get('token_est') or 0)
                add_metric('structured_regulations_bypass_langchain', 1)
                add_metric('use_langchain', 0)
                add_metric('ctx_n', len(reg_contexts))
                add_metric('token_est', reg_token_est)
                add_metric('token_est_per_question', reg_token_est)
                add_metric('ctx_sources', ','.join(_context_source_names({'contexts': reg_contexts})))
                add_metric('answer', reg_answer)
                add_metric('answer_chars', len(reg_answer))
                return RagAnswerResponse(
                    question=req.question,
                    prompt=str(reg_payload.get('prompt') or '(structured regulations answer)'),
                    answer=reg_answer,
                    contexts=reg_contexts,
                    token_est=reg_token_est,
                    meta=reg_payload.get('meta') or None,
                )

        if decision.structured_kind == 'curriculum':
            curr_payload = run_structured_curriculum_path(
                req.question,
                decision,
                strategy,
                require_citations=require_citations,
                return_contexts=True,
            )
            if curr_payload:
                structured = str(curr_payload.get('answer') or '')
                contexts = list(curr_payload.get('contexts') or [])
                token_est = int(curr_payload.get('token_est') or 0)
                add_metric('ctx_n', len(contexts))
                add_metric('token_est', token_est)
                add_metric('token_est_per_question', token_est)
                add_metric('ctx_sources', ','.join(_context_source_names({'contexts': contexts})))
                add_metric('answer', structured)
                add_metric('answer_chars', len(structured))
                return RagAnswerResponse(
                    question=req.question,
                    prompt=str(curr_payload.get('prompt') or '(structured curriculum answer)'),
                    answer=structured,
                    contexts=contexts,
                    token_est=token_est,
                    meta=curr_payload.get('meta'),
                )

        try:
            strict_reg_fallback = _should_use_regulations_strict_fallback(req.question, decision.effective_domain)
            if strict_reg_fallback:
                add_metric('structured_regulations_strict_mode', 1)
                add_metric('path_nonstructured_used', 1)
                with time_block('rag_query'):
                    result = rag_query_domain(req.question, 'regulations')
            else:
                if use_langchain and lc is not None:
                    add_metric('path_langchain_used', 1)
                    dom_l = (decision.effective_domain or '').strip().lower()
                    # For announcements/calendar-like questions, retrieval-only first is faster
                    # and usually enough for deterministic extractors.
                    use_query_only_langchain = (
                        dom_l == 'announcements'
                        or decision.primary_intent in ('registration_policy', 'calendar_deadline')
                    )
                    with time_block('langchain_rag'):
                        if use_query_only_langchain:
                            add_metric('langchain_query_only_mode', 1)
                            result = lc.rag_query_langchain(req.question, effective_domain)
                        else:
                            result = lc.rag_answer_langchain(req.question, effective_domain)
                else:
                    add_metric('path_nonstructured_used', 1)
                    with time_block('rag_query'):
                        result = rag_query_domain(req.question, effective_domain) if effective_domain else rag_query(req.question)
        except Exception as e:
            logger.error("/rag/answer failed: %s\n%s", str(e), traceback.format_exc())
            add_metric('error', 1)
            add_metric('failure_intent', _infer_primary_intent(req.question))
            return RagAnswerResponse(
                question=req.question,
                prompt=f"(exception) {type(e).__name__}: {e}",
                answer=f"(exception) {type(e).__name__}: {e}",
                contexts=[],
                token_est=0,
            )

        result_contexts = _normalize_contexts_for_eval(result.get('contexts') or [], default_domain=effective_domain)
        result['contexts'] = result_contexts

        add_metric('ctx_n', len(result_contexts))
        add_metric('token_est', result.get('token_est', 0))
        add_metric('token_est_per_question', result.get('token_est', 0))
        add_metric('ctx_sources', ','.join(_context_source_names({'contexts': result_contexts})))
        add_metric('prompt_chars', len(result.get('prompt') or ''))

        # Build chat style messages for models that support it
        system_msg = { 'role': 'system', 'content': 'คุณคือผู้ช่วยของภาควิชาวิศวกรรมคอมพิวเตอร์ ใช้เฉพาะข้อมูลในบริบทเท่านั้น ตอบโดยตรงและชัดเจน ห้ามให้ลิงก์/URL ภายนอก เว้นแต่ปรากฏอยู่ในบริบท หากคำถามกำกวมให้ถามกลับ 1 คำถามสั้น ๆ เพื่อขอรายละเอียดที่จำเป็น หากมีหลักฐานครบให้ตอบตรง ๆ และไม่ต้องเติมข้อความปฏิเสธท้ายคำตอบ' }
        user_msg = { 'role': 'user', 'content': result['prompt'] }

        # Hard guardrails: if no context, never hallucinate.
        if not (result.get('contexts') or []):
            answer = _clarify_when_no_context(req.question) or _FALLBACK
        else:
            # If we can deterministically answer from the retrieved context, do it.
            extracted = _try_extract_total_credits(result.get('prompt') or '', question=req.question)
            if extracted:
                answer = extracted
            else:
                extracted_instructor = _try_extract_course_instructors(
                    result.get('prompt') or '',
                    question=req.question,
                    contexts=result.get('contexts') or [],
                    domain=effective_domain,
                )
                if extracted_instructor:
                    answer = extracted_instructor
                else:
                    extracted_leave = _try_extract_intermission_leave(result.get('prompt') or '', question=req.question)
                    if extracted_leave:
                        answer = extracted_leave
                    else:
                        extracted_w = _try_extract_withdraw_w_dates(result.get('prompt') or '', question=req.question)
                        if extracted_w:
                            answer = extracted_w
                        else:
                            extracted_announce_time = _try_extract_announcements_temporal_answer(
                                result.get('prompt') or '',
                                req.question,
                                domain=effective_domain,
                            )
                            if extracted_announce_time:
                                answer = extracted_announce_time
                            else:
                            # Exam-room policies can be multi-intent (e.g., มาสาย + ออกชั่วคราว).
                            # Don't return early on the first extractor hit; combine when applicable.
                                extracted_exam_late = _try_extract_exam_late_entry_rule(result.get('prompt') or '', question=req.question)
                                extracted_exam_temp = _try_extract_exam_temp_leave_rule(result.get('prompt') or '', question=req.question)
                                extracted_exam_exit = _try_extract_exam_exit_rule(result.get('prompt') or '', question=req.question)

                                if extracted_exam_late and extracted_exam_temp:
                                    answer = f"{extracted_exam_late}\n{extracted_exam_temp}"
                                elif extracted_exam_late:
                                    answer = extracted_exam_late
                                elif extracted_exam_exit:
                                    answer = extracted_exam_exit
                                elif extracted_exam_temp:
                                    answer = extracted_exam_temp
                                else:
                                    curriculum_guard_answer = _curriculum_consistency_guard(req.question, effective_domain)
                                    if curriculum_guard_answer:
                                        answer = curriculum_guard_answer
                                    else:
                                        guarded = _low_confidence_guardrail(req.question, result)
                                        if guarded:
                                            add_metric('guardrail_triggered', 1)
                                            answer = guarded
                                        else:
                                            if _USE_LANGCHAIN:
                                                answer = result.get('answer') or ''
                                                # Query-only langchain path may intentionally skip generation.
                                                if not (answer or '').strip():
                                                    with time_block('llm_generate'):
                                                        answer = llm_engine.generate(result['prompt'], messages=[system_msg, user_msg])
                                            else:
                                                with time_block('llm_generate'):
                                                    answer = llm_engine.generate(result['prompt'], messages=[system_msg, user_msg])

                    answer = _enforce_answer_completeness(
                        req.question,
                        answer or '',
                        domain=effective_domain,
                    )
                    answer = _strip_false_abstain(_strip_spurious_abstain_phrases(answer or ''))
                    if _is_single_fact_question(req.question):
                        answer = _compress_to_single_line(answer)

                    # Optionally enforce citations when we have context.
                    if require_citations and (result.get('contexts') or []) and answer and not answer.strip().startswith('('):
                        had_citations_before = _has_citations(answer)
                        if not had_citations_before:
                            add_metric('citation_repair_attempt', 1)
                        with time_block('repair_citations_llm'):
                            answer = _repair_answer_with_citations(answer, result.get('prompt') or '')
                        with time_block('sanitize_citations'):
                            answer = _sanitize_answer_citations(answer, result.get('prompt') or '')
                        if (not had_citations_before) and _has_citations(answer):
                            add_metric('citation_repair_success', 1)

                        with time_block('enforce_citations'):
                            answer = _force_answer_citations(answer, result.get('prompt') or '', result.get('contexts') or [])
                        if not _has_citations(answer):
                            add_metric('citation_enforcement_failed', 1)
                            answer = _force_answer_citations(
                                'ไม่พบข้อความยืนยันโดยตรงในเอกสารที่ค้นได้',
                                result.get('prompt') or '',
                                result.get('contexts') or [],
                            )

            # If generation is unavailable/disabled, preserve the diagnostic message.
            if not (answer or '').strip().startswith('('):
                # Clean and validate answer - keep it natural without enforcing citations
                with time_block('clean_answer'):
                    answer = _clean_answer_text(answer, strip_citations=(not require_citations))

                # If model uses fallback phrase, it must be the entire answer.
                if _FALLBACK in answer and answer != _FALLBACK:
                    answer = _FALLBACK

        if (answer or '').strip() == _FALLBACK:
            add_metric('fallback_answer_used', 1)
            add_metric('failure_intent', _infer_primary_intent(req.question))

        final_contexts = _merge_contexts_with_answer_citations(
            result.get('contexts') or [],
            answer or '',
            default_domain=effective_domain,
        )
        result['contexts'] = final_contexts
        add_metric('ctx_n', len(final_contexts))
        add_metric('ctx_sources', ','.join(_context_source_names({'contexts': final_contexts})))

        add_metric('answer', (answer or '').strip())
        add_metric('answer_chars', len((answer or '').strip()))

        return RagAnswerResponse(
            question=req.question,
            prompt=result['prompt'],
            answer=answer,
            contexts=final_contexts,
            token_est=result['token_est'],
            meta=result.get('meta'),
        )

@app.get('/v1/models')
def list_models():
    """OpenAI API compatible models endpoint for OpenWeb-UI."""
    import time
    from .config import LLM_MODEL
    
    return {
        "object": "list",
        "data": [
            {
                "id": LLM_MODEL or "typhoon-v2.5-30b-a3b-instruct",
                "object": "model",
                "created": int(time.time()),
                "owned_by": "cpe-chat-rag"
            }
        ]
    }

@app.post('/v1/chat/completions')
def openai_compatible_endpoint(request: dict):
    """OpenAI API compatible endpoint for OpenWeb-UI integration."""
    import time
    import uuid

    if not isinstance(request, dict):
        request = {}

    messages = _coerce_chat_messages(request.get('messages', []))
    domain = request.get('domain', None)  # Custom parameter for domain selection
    session_id = _extract_session_id_from_request(request)
    
    # Extract question from chat history (keep follow-up context)
    raw_last_user = ""
    for msg in reversed(messages):
        if (msg.get('role') or '').strip().lower() == 'user':
            raw_last_user = _content_to_text(msg.get('content', ''))
            break

    question = _sanitize_user_question_text(_build_effective_question(messages, raw_last_user))
    question, domain, lock_applied, lock_reason = _apply_session_followup_lock(question, domain, session_id)
    followup_meta = _analyze_followup_entities(messages, question)
    decision = analyze_route(question, domain)
    structured_eligible = bool(decision.structured_kind == 'curriculum' and decision.structured_eligible)
    structured_reg_eligible = bool(decision.structured_kind == 'regulations')
    use_langchain = bool(_USE_LANGCHAIN and _LANGCHAIN_READY and _langchain_rag is not None)
    lc = _langchain_rag

    if (os.getenv("RAG_TIMING", "0") or "0").strip().lower() in ("1", "true", "yes", "on"):
        try:
            logger.info("[EFFECTIVE_Q] %s", (question or '').replace("\n", " | ")[:500])
        except Exception:
            pass

    with request_timing(
        'v1_chat_completions',
        endpoint='/v1/chat/completions',
        domain=domain,
        model=request.get('model', 'typhoon-rag'),
        msg_n=len(messages or []),
        session_id=session_id or None,
    ):
        strategy = select_resolution_strategy(decision)
        add_metric('route_version', 'v3_unified')
        add_metric('resolution_path', strategy.resolution_path)
        add_metric('structured_eligibility_reason', str(getattr(decision, 'structured_eligibility_reason', 'none') or 'none'))
        add_metric('requires_clause_anchor', int(bool(getattr(decision, 'requires_clause_anchor', False))))
        add_metric('needs_exact_schema', int(bool(getattr(decision, 'needs_exact_schema', False))))
        add_metric('timeout_policy', str(getattr(decision, 'timeout_policy', 'normal') or 'normal'))
        _observe_entry_metrics(question, decision.requested_domain, use_langchain=use_langchain)
        _observe_default_request_metrics(
            structured_eligible=decision.structured_eligible,
            structured_reg_eligible=(decision.structured_kind == 'regulations'),
        )
        add_metric('routing_domain_initial', (decision.requested_domain or 'auto'))
        add_metric('routing_domain_final', (decision.effective_domain or 'auto'))
        add_metric('followup_latest_entity', str(followup_meta.get('followup_latest_entity') or ''))
        add_metric('followup_previous_entity', str(followup_meta.get('followup_previous_entity') or ''))
        add_metric('followup_entity_overridden', int(followup_meta.get('followup_entity_overridden') or 0))
        add_metric('followup_entity_conflict', int(followup_meta.get('followup_entity_conflict') or 0))
        add_metric('session_has_id', int(bool(session_id)))
        add_metric('followup_session_domain_lock_applied', int(lock_applied))
        add_metric('followup_session_domain_lock_reason', lock_reason)
        _remember_session_followup_hint(session_id, question, decision)

        summary_fast = _build_followup_summary_answer(
            raw_last_user or question,
            question,
            domain or decision.effective_domain,
        )
        if summary_fast:
            summary_fast = _finalize_user_answer_text(question, summary_fast)
            add_metric('followup_summary_fast_path', 1)
            add_metric('answer', summary_fast)
            add_metric('answer_chars', len(summary_fast))
            return {
                "id": f"chatcpe-{uuid.uuid4().hex[:12]}",
                "object": "chat.completion",
                "created": int(time.time()),
                "model": request.get('model', 'typhoon-rag'),
                "choices": [
                    {
                        "index": 0,
                        "message": {"role": "assistant", "content": summary_fast},
                        "finish_reason": "stop",
                    }
                ],
                "usage": {"prompt_tokens": 0, "completion_tokens": 0, "total_tokens": 0},
            }

        if strategy.resolution_path == 'full_rag' and _is_short_ambiguous_followup(raw_last_user or question):
            add_metric('followup_clarify_short_ambiguous', 1)
            clarify = (
                "ต้องการให้สรุปเรื่องไหนครับ: 1) มาสายเข้าสอบ 2) ออกจากห้องสอบชั่วคราว "
                "หรือพิมพ์ว่า 'สรุปทั้งสองข้อ'"
            )
            clarify = _finalize_user_answer_text(question, clarify)
            add_metric('answer', clarify)
            add_metric('answer_chars', len(clarify))
            return {
                "id": f"chatcpe-{uuid.uuid4().hex[:12]}",
                "object": "chat.completion",
                "created": int(time.time()),
                "model": request.get('model', 'typhoon-rag'),
                "choices": [
                    {
                        "index": 0,
                        "message": {"role": "assistant", "content": clarify},
                        "finish_reason": "stop",
                    }
                ],
                "usage": {"prompt_tokens": 0, "completion_tokens": 0, "total_tokens": 0},
            }

        if decision.primary_intent == 'prerequisite_lookup':
            prereq_payload = _run_prerequisite_structured_guard(
                question,
                require_citations=False,
                return_contexts=False,
            )
            prereq_answer = _finalize_user_answer_text(question, str(prereq_payload.get('answer') or ''))
            add_metric('ctx_n', 0)
            add_metric('token_est', 0)
            add_metric('token_est_per_question', 0)
            add_metric('ctx_sources', '')
            add_metric('answer', prereq_answer)
            add_metric('answer_chars', len(prereq_answer))
            return {
                "id": f"chatcpe-{uuid.uuid4().hex[:12]}",
                "object": "chat.completion",
                "created": int(time.time()),
                "model": request.get('model', 'typhoon-rag'),
                "choices": [
                    {
                        "index": 0,
                        "message": {"role": "assistant", "content": prereq_answer},
                        "finish_reason": "stop",
                    }
                ],
                "usage": {"prompt_tokens": 0, "completion_tokens": 0, "total_tokens": 0},
            }

        # Multi-intent shared path
        multi_payload = None
        if strategy.resolution_path in ('multi_intent_split', 'multi_intent_structured_or_extract'):
            multi_payload = run_multi_intent_path(
                question,
                decision.effective_domain,
                require_citations=False,
                prefer_extractive=(strategy.resolution_path == 'multi_intent_structured_or_extract'),
            )
        if multi_payload:
            merged_ans = _finalize_user_answer_text(question, str(multi_payload.get('answer') or ''))
            t_est = int(multi_payload.get('token_est') or 0)
            add_metric('answer', merged_ans)
            add_metric('answer_chars', len(merged_ans))
            import time
            import uuid
            return {
                "id": f"chatcpe-{uuid.uuid4().hex[:12]}",
                "object": "chat.completion",
                "created": int(time.time()),
                "model": request.get('model', 'typhoon-rag'),
                "choices": [
                    {
                        "index": 0,
                        "message": {"role": "assistant", "content": merged_ans},
                        "finish_reason": "stop",
                    }
                ],
                "usage": {"prompt_tokens": 0, "completion_tokens": 0, "total_tokens": t_est},
            }

        if _is_meta_followup_generation_prompt(raw_last_user) or _is_meta_followup_generation_prompt(question):
            add_metric('meta_prompt_isolated', 1)
            if not _ENABLE_META_TASKS:
                # Skip UX meta-tasks in production to avoid wasted LLM latency.
                empty_answer = ''
                add_metric('answer', empty_answer)
                add_metric('answer_chars', 0)
                return {
                    "id": f"chatcpe-{uuid.uuid4().hex[:12]}",
                    "object": "chat.completion",
                    "created": int(time.time()),
                    "model": request.get('model', 'typhoon-rag'),
                    "choices": [
                        {
                            "index": 0,
                            "message": {"role": "assistant", "content": empty_answer},
                            "finish_reason": "stop",
                        }
                    ],
                    "usage": {"prompt_tokens": 0, "completion_tokens": 0, "total_tokens": 0},
                }

        if decision.primary_intent == 'claim_verification':
            claim_payload = run_structured_curriculum_path(
                question,
                decision,
                strategy,
                require_citations=False,
                return_contexts=False,
            )
            if claim_payload:
                claim_answer = _finalize_user_answer_text(
                    question,
                    _compress_to_single_line(
                        _strip_false_abstain(_strip_spurious_abstain_phrases(str(claim_payload.get('answer') or '')))
                    ),
                )
            else:
                claim_answer = 'ไม่พบข้อมูลที่ยืนยันได้จากเอกสารสำหรับคำถามแบบใช่หรือไม่'
            add_metric('answer', claim_answer)
            add_metric('answer_chars', len(claim_answer))
            return {
                "id": f"chatcpe-{uuid.uuid4().hex[:12]}",
                "object": "chat.completion",
                "created": int(time.time()),
                "model": request.get('model', 'typhoon-rag'),
                "choices": [
                    {
                        "index": 0,
                        "message": {"role": "assistant", "content": claim_answer},
                        "finish_reason": "stop",
                    }
                ],
                "usage": {"prompt_tokens": 0, "completion_tokens": 0, "total_tokens": 0},
            }
            with time_block('llm_generate'):
                answer = llm_engine.generate(question, messages=messages)
            answer = _finalize_user_answer_text(question, answer)
            add_metric('answer', (answer or '').strip())
            add_metric('answer_chars', len((answer or '').strip()))
            return {
                "id": f"chatcpe-{uuid.uuid4().hex[:12]}",
                "object": "chat.completion",
                "created": int(time.time()),
                "model": request.get('model', 'typhoon-rag'),
                "choices": [
                    {
                        "index": 0,
                        "message": {"role": "assistant", "content": answer},
                        "finish_reason": "stop",
                    }
                ],
                "usage": {"prompt_tokens": 0, "completion_tokens": 0, "total_tokens": 0},
            }

        if structured_reg_eligible:
            reg_payload = run_structured_regulations_path(
                question,
                require_citations=False,
                return_contexts=False,
            )
            if reg_payload:
                reg_answer = _finalize_user_answer_text(question, str(reg_payload.get('answer') or ''))
                add_metric('ctx_n', 0)
                add_metric('token_est', 0)
                add_metric('token_est_per_question', 0)
                add_metric('ctx_sources', '')
                add_metric('answer', reg_answer)
                add_metric('answer_chars', len(reg_answer))
                import time
                import uuid
                return {
                    "id": f"chatcpe-{uuid.uuid4().hex[:12]}",
                    "object": "chat.completion",
                    "created": int(time.time()),
                    "model": request.get('model', 'typhoon-rag'),
                    "choices": [
                        {
                            "index": 0,
                            "message": {"role": "assistant", "content": reg_answer},
                            "finish_reason": "stop",
                        }
                    ],
                    "usage": {"prompt_tokens": 0, "completion_tokens": 0, "total_tokens": 0},
                }

        # Structured curriculum shortcut for OpenWebUI (works even without retrieval)
        if structured_eligible:
            curr_payload = run_structured_curriculum_path(
                question,
                decision,
                strategy,
                require_citations=False,
                return_contexts=False,
            )
            if curr_payload:
                structured = _finalize_user_answer_text(question, str(curr_payload.get('answer') or ''))
                add_metric('ctx_n', 0)
                add_metric('token_est', 0)
                add_metric('token_est_per_question', 0)
                add_metric('ctx_sources', '')
                add_metric('answer', structured)
                add_metric('answer_chars', len(structured))
                import time
                import uuid
                return {
                    "id": f"chatcpe-{uuid.uuid4().hex[:12]}",
                    "object": "chat.completion",
                    "created": int(time.time()),
                    "model": request.get('model', 'typhoon-rag'),
                    "choices": [
                        {
                            "index": 0,
                            "message": {"role": "assistant", "content": structured},
                            "finish_reason": "stop",
                        }
                    ],
                    "usage": {"prompt_tokens": 0, "completion_tokens": 0, "total_tokens": 0},
                }

        if not question:
            add_metric('error', 1)
            add_metric('failure_intent', 'empty_question')
            return {
                "error": "No user message found in request"
            }

        # Get RAG response
        try:
            if use_langchain and lc is not None:
                add_metric('path_langchain_used', 1)
                with time_block('langchain_rag'):
                    result = lc.rag_answer_langchain(question, domain)
            else:
                add_metric('path_nonstructured_used', 1)
                with time_block('rag_query'):
                    result = rag_query_domain(question, domain) if domain else rag_query(question)
        except Exception as e:
            add_metric('error', 1)
            add_metric('failure_intent', _infer_primary_intent(question))
            return {
                "error": f"RAG query failed: {str(e)}"
            }

        add_metric('ctx_n', len(result.get('contexts') or []))
        add_metric('token_est', result.get('token_est', 0))
        add_metric('token_est_per_question', result.get('token_est', 0))
        add_metric('ctx_sources', ','.join(_context_source_names(result)))
        add_metric('prompt_chars', len(result.get('prompt') or ''))

        # Build system message for RAG context (clean answers, no forced citations)
        system_msg = { 'role': 'system', 'content': 'คุณคือผู้ช่วยของภาควิชาวิศวกรรมคอมพิวเตอร์ ใช้เฉพาะข้อมูลในบริบทเท่านั้น ตอบโดยตรงและชัดเจน ห้ามคัดลอกบริบททั้งก้อน ห้ามให้ลิงก์/URL ภายนอก เว้นแต่ปรากฏอยู่ในบริบท หากคำถามกำกวมให้ถามกลับ 1 คำถามสั้น ๆ เพื่อขอรายละเอียดที่จำเป็น หากมีหลักฐานครบให้ตอบตรง ๆ และไม่ต้องเติมข้อความปฏิเสธท้ายคำตอบ' }
        user_msg = { 'role': 'user', 'content': result['prompt'] }

        # Generate answer
        if not (result.get('contexts') or []):
            answer = _clarify_when_no_context(question) or _FALLBACK
        else:
            extracted = _try_extract_total_credits(result.get('prompt') or '', question=question)
            if extracted:
                answer = extracted
            else:
                extracted_instructor = _try_extract_course_instructors(
                    result.get('prompt') or '',
                    question=question,
                    contexts=result.get('contexts') or [],
                    domain=domain,
                )
                if extracted_instructor:
                    answer = extracted_instructor
                else:
                    extracted_leave = _try_extract_intermission_leave(result.get('prompt') or '', question=question)
                    if extracted_leave:
                        answer = extracted_leave
                    else:
                        extracted_w = _try_extract_withdraw_w_dates(result.get('prompt') or '', question=question)
                        if extracted_w:
                            answer = extracted_w
                        else:
                            extracted_exam_late = _try_extract_exam_late_entry_rule(result.get('prompt') or '', question=question)
                            if extracted_exam_late:
                                answer = extracted_exam_late
                            else:
                                curriculum_guard_answer = _curriculum_consistency_guard(question, domain)
                                if curriculum_guard_answer:
                                    answer = curriculum_guard_answer
                                else:
                                    guarded = _low_confidence_guardrail(question, result)
                                    if guarded:
                                        add_metric('guardrail_triggered', 1)
                                        answer = guarded
                                    else:
                                        if _USE_LANGCHAIN:
                                            answer = result.get('answer') or ''
                                        else:
                                            with time_block('llm_generate'):
                                                answer = llm_engine.generate(result['prompt'], messages=[system_msg, user_msg])

            if not (answer or '').strip().startswith('('):
                answer = _strip_false_abstain(_strip_spurious_abstain_phrases(answer))
                if _is_single_fact_question(question):
                    answer = _compress_to_single_line(answer)
                answer = _finalize_user_answer_text(question, answer)

        if (answer or '').strip() == _FALLBACK:
            add_metric('fallback_answer_used', 1)
            add_metric('failure_intent', _infer_primary_intent(question))

        add_metric('answer', (answer or '').strip())
        add_metric('answer_chars', len((answer or '').strip()))

        # Return OpenAI-compatible response
        return {
            "id": f"chatcpe-{uuid.uuid4().hex[:12]}",
            "object": "chat.completion",
            "created": int(time.time()),
            "model": request.get('model', 'typhoon-rag'),
            "choices": [
                {
                    "index": 0,
                    "message": {
                        "role": "assistant",
                        "content": answer
                    },
                    "finish_reason": "stop"
                }
            ],
            "usage": {
                "prompt_tokens": result.get('token_est', 0),
                "completion_tokens": 0,
                "total_tokens": result.get('token_est', 0)
            }
        }

@app.get('/health')
def health():
    return {'status': 'ok'}


def _truthy_env(v: str) -> bool:
    return (v or "").strip().lower() in {"1", "true", "yes", "y"}


def _public_config() -> dict:
    # Import locally to avoid import cycles at module import time.
    from app import config as cfg  # type: ignore

    # Explicit allow-list (anything secret-like is never included).
    env_allow = [
        "DATA_DIR",
        "CHROMA_DIR",
        "SQLITE_PATH",
        "CPE_INDEX_ROOT",
        "CPE_DOMAIN",
        "EMBEDDING_MODEL",
        "EMBED_BATCH",
        "EMBEDDING_DIM",
        "TOKEN_BUDGET",
        "RRF_K",
        "MAX_CONTEXTS",
        "LLM_ENABLE",
        "LLM_PROVIDER",
        "LLM_MODEL",
        "LLM_MAX_TOKENS",
        "LLM_TEMPERATURE",
        "OPENAI_BASE_URL",
        "OPENAI_TIMEOUT_S",
        "TYPHOON_BASE_URL",
        "TYPHOON_TIMEOUT_S",
        "NEO4J_URI",
        "NEO4J_USERNAME",
        "NEO4J_USER",
        "NEO4J_DATABASE",
        "RAG_USE_LANGCHAIN",
        "RAG_LC_MULTIQUERY",
        "RAG_LC_MULTIQUERY_N",
        "RAG_LC_MULTIQUERY_ALL",
        "RAG_LC_PARALLEL",
        "RAG_LC_PARALLEL_WORKERS",
        "RAG_LC_RERANK",
        "RAG_LC_RERANK_TOPN",
        "RAG_LC_RERANK_ALL",
        "RAG_LC_COMPRESS",
        "RAG_LC_COMPRESS_MAX_CHARS",
        "RAG_LC_COMPRESS_ALL",
        "RAG_LC_ROUTE_LLM",
        "RAG_LC_STRUCTURED",
        "RAG_LC_ENFORCE_CITATIONS",
    ]

    deny = ("KEY", "TOKEN", "SECRET", "PASSWORD")
    env_out = {}
    for k in env_allow:
        if not k:
            continue
        if any(d in k.upper() for d in deny):
            continue
        if k in os.environ:
            env_out[k] = os.environ.get(k)

    # Also include resolved (post-default) values from config.py.
    resolved = {
        "ROOT_DIR": str(getattr(cfg, "ROOT_DIR", "")),
        "DATA_DIR": str(getattr(cfg, "DATA_DIR", "")),
        "CHROMA_DIR": str(getattr(cfg, "CHROMA_DIR", "")),
        "SQLITE_PATH": str(getattr(cfg, "SQLITE_PATH", "")),
        "EMBEDDING_MODEL": getattr(cfg, "EMBEDDING_MODEL", ""),
        "EMBED_BATCH": getattr(cfg, "EMBED_BATCH", None),
        "EMBEDDING_DIM": getattr(cfg, "EMBEDDING_DIM", None),
        "TOKEN_BUDGET": getattr(cfg, "TOKEN_BUDGET", None),
        "RRF_K": getattr(cfg, "RRF_K", None),
        "MAX_CONTEXTS": getattr(cfg, "MAX_CONTEXTS", None),
        "LLM_ENABLE": getattr(cfg, "LLM_ENABLE", None),
        "LLM_PROVIDER": getattr(cfg, "LLM_PROVIDER", ""),
        "LLM_MODEL": getattr(cfg, "LLM_MODEL", ""),
        "LLM_MAX_TOKENS": getattr(cfg, "LLM_MAX_TOKENS", None),
        "LLM_TEMPERATURE": getattr(cfg, "LLM_TEMPERATURE", None),
    }

    # Redact any accidental secrets.
    def _redact_key(k: str, v):
        if any(d in (k or "").upper() for d in deny):
            return "***REDACTED***"
        return v

    env_out = {k: _redact_key(k, v) for k, v in env_out.items()}
    resolved = {k: _redact_key(k, v) for k, v in resolved.items()}

    return {
        "service": {"name": "rag-service", "version": getattr(app, "version", "")},
        "env": env_out,
        "resolved": resolved,
    }


@app.get('/debug/config')
def debug_config():
    # Disabled by default; enable explicitly for local debugging & experiment tracking.
    if not _truthy_env(os.getenv("RAG_EXPOSE_CONFIG", "0")):
        raise HTTPException(status_code=404, detail="Not found")
    return _public_config()
