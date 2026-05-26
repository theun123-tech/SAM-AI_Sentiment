"""
websocket_server.py — Production voice pipeline with Output Media streaming

Audio delivery:
  Primary: Cartesia WebSocket → PCM chunks → audio page WebSocket → AudioWorklet
  Fallback: Cartesia REST → MP3 → output_audio API (if audio page not connected)
"""

import asyncio
import json
import time
import base64
import os
import re as _re
import random
from aiohttp import web
import aiohttp
from collections import deque

from Trigger import TriggerDetector
from Agent import PMAgent, FILLERS, _GEMINI_AVAILABLE
from Speaker import CartesiaSpeaker, _mix_noise, get_duration_ms
from stt import RmsVAD
from external_apis import (
    JiraClient,
    JiraAuthError,
    JiraNotFoundError,
    JiraTransitionError,
    JiraPermissionError,
)
from external_apis import AzureExtractor, JIRA_RESPONSE_PROMPT, JIRA_INTENT_PROMPT
from standup import StandupFlow
import storage as session_store

# Per-speaker Flux STT (client mode, multi-party support)
from stt import FluxSessionManager
from addressee_decider import AddresseeDecider, ContextBundle, Decision

# ── LangGraph DialogueManager (Week 4 Phase 1: observer mode) ──────────────
# Imported optionally so failures don't break production. If any week 1-3
# file is missing or broken, the toggle auto-disables itself with a warning.
try:
    from dialogue import DialogueManager
    from dialogue import (
        CheckpointManager,
        compute_conversation_id as _dm_compute_conv_id,
    )

    _DIALOGUE_MANAGER_AVAILABLE = True
except Exception as _dm_import_err:
    DialogueManager = None  # type: ignore
    CheckpointManager = None  # type: ignore
    _dm_compute_conv_id = None  # type: ignore
    _DIALOGUE_MANAGER_AVAILABLE = False
    print(f"[WebSocketServer] ⚠️  DialogueManager unavailable: {_dm_import_err}")

# Deepgram Flux for standup STT (separate from Recall's Deepgram)
# Stage R: warm the rotator cache. The actual key per call/session is fetched
# via key_rotator.key_for_session(...) below — DEEPGRAM_API_KEY here just
# indicates whether Deepgram is configured at all (for boolean gates).
try:
    from key_rotator import load_keys as _kr_load_keys

    _kr_load_keys("DEEPGRAM")
except Exception:
    pass
DEEPGRAM_API_KEY = os.environ.get("DEEPGRAM_API_KEY", "") or (
    os.environ.get("DEEPGRAM_API_KEYS", "").split(",")[0].strip()
    if os.environ.get("DEEPGRAM_API_KEYS", "").strip()
    else ""
)
GROQ_API_KEY = os.environ.get("GROQ_API_KEY", "") or (
    os.environ.get("GROQ_API_KEYS", "").split(",")[0].strip()
    if os.environ.get("GROQ_API_KEYS", "").strip()
    else ""
)

# ── Per-Speaker Flux toggle (client mode only) ──────────────────────────────
# When True AND mode != "standup":
#   - Client mode runs N Flux connections, one per participant
#   - AddresseeDecider (Groq LLM) picks who Sam responds to in multi-party
#   - Recall.ai STT is NOT used (recall_bot.py also checks this)
# When False: client mode uses Recall.ai's built-in STT as before.
# Standup mode: UNAFFECTED regardless of this flag.
USE_PER_SPEAKER_FLUX = os.environ.get("USE_PER_SPEAKER_FLUX", "1") != "0"

# ══════════════════════════════════════════════════════════════════════════════
# FEATURE 4 FLAGS — Flip to False to revert to previous behavior
# ══════════════════════════════════════════════════════════════════════════════
# Set via env vars for easy toggling without code changes. Default ON.
# Example: USE_UNIFIED_RESEARCH=0 python main_meeting.py ... (disables new flow)

USE_UNIFIED_RESEARCH = os.environ.get("USE_UNIFIED_RESEARCH", "1") != "0"
USE_DYNAMIC_FILLERS = os.environ.get("USE_DYNAMIC_FILLERS", "1") != "0"
USE_SMART_PRELOAD = os.environ.get("USE_SMART_PRELOAD", "1") != "0"
USE_CONVERSATION_MEMORY = os.environ.get("USE_CONVERSATION_MEMORY", "1") != "0"
RESEARCH_PROVIDER = os.environ.get("RESEARCH_PROVIDER", "brave").strip().lower()
# ──────────────────────────────────────────────────────────────────────────────
# Stage 2: unified research architecture flag.
#   "unified" (default) → use the new _unified_research_v2 path: planner-driven,
#                         conditional parallel Exa+Jira fetch, single synthesis
#                         with always-injected profile/agenda/memory blocks.
#   "legacy"            → skip v2, fall through to existing USE_UNIFIED_RESEARCH
#                         and the original parallel Jira+web+Azure block.
# v2 returns None on any error → legacy block runs as safety net.
# ──────────────────────────────────────────────────────────────────────────────
RESEARCH_ARCHITECTURE = (
    os.environ.get("RESEARCH_ARCHITECTURE", "unified").strip().lower()
)
# ── Week 4: DialogueManager toggle ──────────────────────────────────────────
# When "1": LangGraph-based dialogue manager runs alongside existing pipeline
#           (observer mode). NLU + Policy decisions are logged but NOT enforced.
#           Trigger.py still decides whether Sam responds.
# When "0" (default): DialogueManager is inert. Zero impact on behavior.
# Only active in client mode — standup mode NEVER uses DialogueManager.
USE_DIALOGUE_MANAGER = os.environ.get("USE_DIALOGUE_MANAGER", "0") != "0"

# Preload caps for smart-preload mode
SMALL_PROJECT_THRESHOLD = 100  # At/below this many tickets → load everything
PRELOAD_MAX_LARGE = 100  # Cap for large projects (sprint + priority + recent)


def ts():
    return time.strftime("%H:%M:%S")


_HONORIFIC_RE = _re.compile(
    r"^(?:dr|mr|mrs|ms|miss|prof|professor|sir|madam|ma'am)\.?\s+",
    _re.IGNORECASE,
)
_NAME_CHANGE_RE = _re.compile(
    r"(?:call me|my name is|actually it'?s|people call me|you can call me)\s+(\w+)",
    _re.IGNORECASE,
)
_CASUAL_NAME_WORDS = frozenset(
    {
        "boss",
        "buddy",
        "mate",
        "chief",
        "dude",
        "bro",
        "sis",
        "pal",
        "friend",
        "matey",
        "captain",
        "sir",
        "ma'am",
        "madam",
    }
)
_NAME_CHANGE_CONFIRMATIONS = [
    "Got it, {name} — noted.",
    "{name}, got it — I'll use that.",
]


def _extract_first_name(name: str) -> str:
    """Strip honorifics and return capitalized first name. 'Dr. Rahul Mehta' → 'Rahul'."""
    if not name or name in ("", "Unknown"):
        return name or ""
    cleaned = _HONORIFIC_RE.sub("", name.strip())
    parts = cleaned.split()
    if not parts:
        return name.strip()
    return parts[0].capitalize()


def _greeting_time_slot() -> str:
    hour = time.localtime().tm_hour
    if 5 <= hour < 12:
        return "morning"
    if 12 <= hour < 17:
        return "afternoon"
    if 17 <= hour < 21:
        return "evening"
    return "late"


_CLIENT_GREETING_OPENERS = {
    "morning": [
        "Good morning, {first}. Good to have you.",
        "Morning, {first}. Glad you're here.",
        "Hey {first}, good morning — good to have you.",
    ],
    "afternoon": [
        "Good afternoon, {first}. Good to have you.",
        "Afternoon, {first}. Glad you're here.",
        "Hey {first}, good afternoon — good to have you.",
    ],
    "evening": [
        "Good evening, {first}. Good to have you.",
        "Evening, {first}. Glad you're here.",
        "Hey {first}, good evening — good to have you.",
    ],
    "late": [
        "Hey {first}. Good to have you.",
        "Hi {first}. Glad you're here.",
        "Hey {first} — good to have you on the line.",
    ],
}


def elapsed(since: float) -> str:
    return f"{(time.time() - since) * 1000:.0f}ms"


WORDS_PER_SECOND = 3.2
PCM_SAMPLE_RATE = 48000  # Cartesia WebSocket output
PCM_BYTES_PER_SEC = PCM_SAMPLE_RATE * 2  # 16-bit mono

_ACK_PHRASES = frozenset(
    {
        "sure",
        "ok",
        "okay",
        "yeah",
        "yes",
        "go ahead",
        "alright",
        "right",
        "hmm",
        "mhm",
        "cool",
        "got it",
        "fine",
        "yep",
        "yup",
        "carry on",
        "go on",
        "continue",
        "waiting",
        "i'm waiting",
        "i am waiting",
        "no problem",
        "take your time",
        "np",
        "hello",
        "hi",
        "hey",
        "huh",
        "what",
        "sorry",
    }
)

# ── Backchannel detection (production-grade) ────────────────────────────────
# When Sam is speaking and user emits a short listener acknowledgment,
# we DON'T want to interrupt Sam — they're just saying "I'm listening."
#
# Design rules:
#   - Single-word backchannels: the user is acknowledging, keep speaking
#   - Multi-word (2-word) backchannels: still acknowledging, keep speaking
#   - 3+ word utterances: user is taking the floor, interrupt
#   - Unknown single/double words: interrupt (unknown = probably meaningful)
#
# Intentionally EXCLUDED from backchannels (these SHOULD interrupt):
#   - "stop", "wait", "hold on", "pause", "bye" — explicit interrupts
#   - "hello", "hi", "hey" — might be "Hey Sam, stop"
#   - "what", "sorry", "huh" — "What?" "Sorry?" "Huh?" = needs clarification
#   - "no", "actually", "but" — disagreement, user wants to respond
_BACKCHANNEL_SINGLE = frozenset(
    {
        "okay",
        "ok",
        "yeah",
        "yes",
        "sure",
        "right",
        "hmm",
        "mhm",
        "mmhmm",
        "alright",
        "cool",
        "uhhuh",
        "yep",
        "yup",
        "ya",
        "umm",
        "uh",
        "continue",
        "go",
        "please",
        "interesting",
        "really",
        "nice",
        "great",
        "awesome",
        "perfect",
    }
)

_BACKCHANNEL_DOUBLE = frozenset(
    {
        "got it",
        "i see",
        "i know",
        "go on",
        "go ahead",
        "carry on",
        "makes sense",
        "that's right",
        "uh huh",
        "mm hmm",
        "mm-hmm",
        "no problem",
        "take your time",
        "sounds good",
        "for sure",
        "of course",
        "all right",
        "keep going",
        "makes sense",
        "fair enough",
        "i understand",
        "noted",
    }
)


def _is_backchannel(text: str) -> bool:
    """Return True if text is a listener acknowledgment (don't interrupt).

    Backchannels are short utterances users say while listening to indicate
    attention ("mhm", "okay", "got it"). These should NOT interrupt Sam —
    the user expects Sam to keep talking.

    Returns False for:
      - Unknown single/double words (probably meaningful, interrupt)
      - Any utterance of 3+ words (user taking the floor, interrupt)
      - Empty text
    """
    if not text:
        return False
    cleaned = text.lower().strip().rstrip(".?!,").strip()
    if not cleaned:
        return False
    words = cleaned.split()
    if len(words) == 1:
        return cleaned in _BACKCHANNEL_SINGLE
    if len(words) == 2:
        return cleaned in _BACKCHANNEL_DOUBLE
    # 3+ words = real utterance, never a backchannel
    return False


# Matches robotic AI opener phrases at the start of LLM responses.
# Applied to the first sentence of every TTS output to keep Sam's voice natural.
_FILLER_OPENER_RE = _re.compile(
    r"^(Sure|Of\s+course|Absolutely|Certainly|Definitely|Great|No\s+problem)[,!]?\s*",
    _re.IGNORECASE,
)

# ── Phantom STT filter ──────────────────────────────────────────────────────
# STT (Flux) sometimes hallucinates single words like "two" or "seven" from
# breathing, background noise, or silence between Sam's TTS output. These
# phantom transcriptions trigger FAST INTERRUPT and stop Sam mid-sentence
# even though the user never actually spoke.
#
# Known hallucinations seen in production logs:
#   "two"   — appears between Sam's chunked TTS audio bursts (most common)
#   "seven" — same pattern as "two", less frequent
#
# We filter these as no-ops in interim transcripts. Multi-word transcripts
# always pass through — if the user actually says "two of the tickets are
# done", that's real speech and should interrupt normally.
_PHANTOM_SINGLE_WORDS = frozenset({"two", "seven"})


def _is_phantom_filler(text: str) -> bool:
    """Return True if text is a known STT hallucination (suppress as no-op).

    STRICT MATCHING — only single words from _PHANTOM_SINGLE_WORDS qualify.
    Multi-word transcripts NEVER match, even if they contain "two" or
    "seven" — those are real speech.

    Returns False for:
      - Empty text
      - Multi-word transcripts (always real speech)
      - Single words NOT in the phantom registry
    """
    if not text:
        return False
    cleaned = text.lower().strip().rstrip(".?!,").strip()
    if not cleaned:
        return False
    # Strict single-word match — multi-word releases never qualify
    if " " in cleaned:
        return False
    return cleaned in _PHANTOM_SINGLE_WORDS


def _is_incomplete_sentence(text: str) -> bool:
    """Return True if the text ends with a conjunction or preposition, indicating an incomplete thought."""
    if not text:
        return False
    # Clean trailing punctuation
    cleaned = text.strip().lower().rstrip(".,!?*-\"'_")
    words = cleaned.split()
    if not words:
        return False
    last_word = words[-1]
    incompletes = {
        "so",
        "and",
        "but",
        "on",
        "with",
        "for",
        "because",
        "i've",
        "i'm",
        "my",
        "to",
        "of",
        "or",
        "at",
        "in",
        "if",
        "then",
        "the",
        "a",
        "an",
        "their",
        "our",
        "your",
    }
    return last_word in incompletes


_INTERRUPT_ACKS = [
    "Oh sorry, go ahead.",
    "My bad, what were you saying?",
    "Sure, I'm listening.",
    "Oh, go on.",
]

_TRANSCRIPTION_FIXES = [
    (
        _re.compile(
            r"\b(?:NF\s*Cloud|Enuf\s*Cloud|Enough\s*Cloud|Nav\s*Cloud|Anav\s*Cloud|Arnav\s*Cloud|Anab\s*Cloud|NFClouds?|EnoughClouds?|NavClouds?|AnavCloud)\b",
            _re.IGNORECASE,
        ),
        "AnavClouds",
    ),
    (
        _re.compile(
            r"\b(?:Sales\s*Force|Sells\s*Force|Cells\s*Force|SalesForce)\b",
            _re.IGNORECASE,
        ),
        "Salesforce",
    ),
]


def _fix_transcription(text):
    result = text
    for p, r in _TRANSCRIPTION_FIXES:
        result = p.sub(r, result)
    return result


def _is_ack(text):
    fragments = _re.split(r"[.!?,]+", text.strip().lower())
    return (
        all(f.strip() in _ACK_PHRASES or f.strip() == "" for f in fragments)
        and text.strip() != ""
    )


# ── Spoken number → ticket ID pre-converter ──────────────────────────────────
_SPOKEN_NUMBERS = {
    "zero": "0",
    "one": "1",
    "two": "2",
    "three": "3",
    "four": "4",
    "five": "5",
    "six": "6",
    "seven": "7",
    "eight": "8",
    "nine": "9",
    "ten": "10",
    "eleven": "11",
    "twelve": "12",
    "thirteen": "13",
    "fourteen": "14",
    "fifteen": "15",
    "sixteen": "16",
    "seventeen": "17",
    "eighteen": "18",
    "nineteen": "19",
    "twenty": "20",
    "thirty": "30",
    "forty": "40",
    "fifty": "50",
}


def _convert_spoken_ticket_refs(text: str, project_key: str) -> str:
    """Convert spoken ticket references to proper IDs before LLM processing.
    'scrum five' → 'SCRUM-5', 'ticket number twenty three' → 'SCRUM-23'."""
    result = text
    pk_lower = project_key.lower()
    words = result.split()
    new_words = []
    i = 0
    while i < len(words):
        word_lower = words[i].strip(".,!?").lower()

        # Check if this word is a ticket reference trigger
        is_trigger = word_lower in (pk_lower, "ticket", "issue", "number", "task")

        if is_trigger and i + 1 < len(words):
            # Collect following number words
            num_parts = []
            j = i + 1
            while j < len(words):
                w = words[j].strip(".,!?").lower()
                # Skip filler words between trigger and number
                if w in ("number", "no", "num", "#"):
                    j += 1
                    continue
                if w in _SPOKEN_NUMBERS:
                    num_parts.append(_SPOKEN_NUMBERS[w])
                    j += 1
                elif w.isdigit():
                    num_parts.append(w)
                    j += 1
                else:
                    break

            if num_parts:
                # Handle compound numbers: "twenty" + "three" = 23
                if (
                    len(num_parts) == 2
                    and int(num_parts[0]) >= 20
                    and int(num_parts[1]) < 10
                ):
                    ticket_num = str(int(num_parts[0]) + int(num_parts[1]))
                else:
                    ticket_num = "".join(num_parts)
                ticket_id = f"{project_key}-{ticket_num}"
                new_words.append(ticket_id)
                i = j
                print(
                    f'[STT→Ticket] Converted: "{" ".join(words[i - j + i : j])}" → {ticket_id}'
                )
                continue

        new_words.append(words[i])
        i += 1

    converted = " ".join(new_words)
    if converted != text:
        print(f'[STT→Ticket] "{text}" → "{converted}"')
    return converted


def _get_adaptive_delay(text: str) -> float:
    """Compute the adaptive silence budget (in seconds) based on text characteristics.

    Target budgets:
      - SHORT / COMPLETE (<6 words, ends with ".", "No.", "Yes.", "Done.", etc.): 0.4s (400ms)
      - MID-LENGTH (6-15 words, complete structure): 0.7s (700ms)
      - LONG / INCOMPLETE (>15 words, ends with conjunction/preposition, or complex): 1.2s (1200ms)
    """
    if not text:
        return 0.4

    words = text.strip().split()
    word_count = len(words)
    cleaned_lower = text.strip().lower()

    # Check if ends with standard sentence terminal punctuation or common complete single words
    ends_complete = cleaned_lower.endswith((".", "!", "?"))

    short_completes = {"no", "yes", "done", "none", "clear", "fine", "no blockers"}
    if cleaned_lower.rstrip(".,!?").strip() in short_completes:
        ends_complete = True

    # Identify incomplete endings (ends with conjunction or preposition)
    ends_incomplete = _is_incomplete_sentence(text)

    # Detect coordinate conjunctions or transitions suggesting multiple ideas/topics
    has_complex_transitions = any(
        word in words
        for word in [
            "and",
            "but",
            "because",
            "so",
            "actually",
            "however",
            "also",
            "plus",
        ]
    )
    has_punctuation_pause = "," in text or ";" in text or "—" in text

    # Match multiple distinct development concepts/topics
    topic_keywords = {
        "auth",
        "payment",
        "jira",
        "database",
        "ui",
        "frontend",
        "backend",
        "server",
        "ticket",
        "bug",
        "feature",
        "sprint",
        "blocker",
        "working on",
        "done with",
        "update",
    }
    matched_topics = sum(1 for kw in topic_keywords if kw in cleaned_lower)

    has_multiple_topics = (
        has_complex_transitions or has_punctuation_pause or (matched_topics >= 2)
    )

    # Tier 1: SHORT / COMPLETE answers
    if word_count < 6 and ends_complete and not ends_incomplete:
        return 0.4

    # Tier 3: LONG / INCOMPLETE / COMPLEX answers
    if word_count > 15 or ends_incomplete or has_multiple_topics:
        return 1.2

    # Tier 2: MID-LENGTH answers
    return 0.7


# ── Insight derivation helpers ─────────────────────────────────────────────
# Pure functions — no LLM call, no I/O, ~0ms each.
# Called once per final user utterance alongside the existing filler logic.


def _derive_emotion(text: str, sentiment: Optional[str] = None) -> dict:
    """Derive dominant emotion + per-category scores from text + Deepgram sentiment.

    Returns:
        {
            "dominant": str,        # e.g. "focused", "frustration", "joy"
            "scores": {
                "joy":         float,
                "frustration": float,
                "stress":      float,
                "confidence":  float,
                "confusion":   float,
            }
        }

    All scores are normalised so they sum to 1.0.
    """
    lower = text.lower() if text else ""

    frustration = any(
        k in lower
        for k in [
            "stuck",
            "blocker",
            "blocked",
            "can't",
            "cannot",
            "frustrated",
            "issue",
            "problem",
            "fail",
            "failed",
            "broken",
            "error",
        ]
    )
    stress = any(
        k in lower
        for k in [
            "urgent",
            "deadline",
            "asap",
            "critical",
            "behind",
            "overdue",
            "pressure",
            "rush",
        ]
    )
    joy = any(
        k in lower
        for k in [
            "done",
            "finished",
            "resolved",
            "complete",
            "completed",
            "wrapped",
            "merged",
            "great",
            "happy",
            "nice",
            "awesome",
            "excited",
        ]
    )
    confusion = any(
        k in lower
        for k in [
            "not sure",
            "unclear",
            "confused",
            "don't know",
            "wondering",
            "unsure",
            "uncertain",
            "maybe",
        ]
    )

    # Reinforce from Deepgram sentiment
    if sentiment == "negative":
        frustration = True
    elif sentiment == "positive":
        joy = True

    raw = {
        "joy": 0.6 if joy else 0.0,
        "frustration": 0.7 if frustration else 0.0,
        "stress": 0.6 if stress else 0.0,
        "confidence": 0.5 if (sentiment == "positive" and not frustration) else 0.15,
        "confusion": 0.5 if confusion else 0.0,
    }
    total = sum(raw.values()) or 1.0
    scores = {k: round(v / total, 2) for k, v in raw.items()}

    dominant = max(scores, key=scores.get)
    # If all signals are weak (no strong keyword hit), call it "focused"
    if max(scores.values()) < 0.25:
        dominant = "focused"
        scores["confidence"] = round(min(scores.get("confidence", 0) + 0.3, 1.0), 2)

    return {"dominant": dominant, "scores": scores}


def _derive_user_intent(text: str) -> dict:
    """Classify user utterance into one of four intent categories.

    Returns:
        {"label": str, "score": float}

    Labels: providing_update | raising_blocker | asking_question | giving_feedback
    Score: heuristic confidence 0.0–1.0 based on keyword match count.
    """
    lower = text.lower() if text else ""

    blocker_kw = [
        "stuck",
        "blocker",
        "blocked",
        "can't",
        "cannot",
        "issue",
        "problem",
        "fail",
        "failed",
        "help",
        "broken",
        "error",
    ]
    update_kw = [
        "done",
        "finished",
        "worked on",
        "completed",
        "i've",
        "today",
        "yesterday",
        "update",
        "progress",
        "pushed",
        "deployed",
        "merged",
    ]
    question_kw = [
        "?",
        "what",
        "how",
        "when",
        "can you",
        "do you",
        "should",
        "could you",
        "would you",
        "is there",
        "are there",
    ]
    feedback_kw = [
        "think",
        "feel",
        "seems",
        "maybe",
        "suggest",
        "opinion",
        "feedback",
        "improve",
        "could be",
        "perhaps",
        "recommend",
    ]

    hit_counts = {
        "raising_blocker": sum(1 for k in blocker_kw if k in lower),
        "providing_update": sum(1 for k in update_kw if k in lower),
        "asking_question": sum(1 for k in question_kw if k in lower),
        "giving_feedback": sum(1 for k in feedback_kw if k in lower),
    }

    top_label = max(hit_counts, key=hit_counts.get)
    top_count = hit_counts[top_label]
    confidence = min(round(top_count * 0.25, 2), 1.0)

    # No keyword hit at all → default to providing_update with low confidence
    if top_count == 0:
        return {"label": "providing_update", "score": 0.3}

    return {"label": top_label, "score": confidence}


def _compute_session_summary(utterance_log: list) -> dict:
    """Aggregate per-utterance insight records into a session-level summary.

    Returns:
        {
            "overall_sentiment":    str,    # modal sentiment across all utterances
            "dominant_emotion":     str,    # modal dominant emotion
            "blockers_flagged":     int,    # count of raising_blocker intents
            "avg_confidence_score": float,  # mean confidence emotion score
        }
    """
    if not utterance_log:
        return {}

    sentiments = [u.get("sentiment", {}).get("label", "neutral") for u in utterance_log]
    overall_sentiment = (
        max(set(sentiments), key=sentiments.count) if sentiments else "neutral"
    )

    emotions = [u.get("emotions", {}).get("dominant", "focused") for u in utterance_log]
    dominant_emotion = max(set(emotions), key=emotions.count) if emotions else "focused"

    blockers_flagged = sum(
        1
        for u in utterance_log
        if u.get("intent", {}).get("label") == "raising_blocker"
    )

    conf_scores = [
        u.get("emotions", {}).get("scores", {}).get("confidence", 0.0)
        for u in utterance_log
    ]
    avg_confidence = (
        round(sum(conf_scores) / len(conf_scores), 2) if conf_scores else 0.0
    )

    return {
        "overall_sentiment": overall_sentiment,
        "dominant_emotion": dominant_emotion,
        "blockers_flagged": blockers_flagged,
        "avg_confidence_score": avg_confidence,
    }


class BotSession:
    STRAGGLER_WAIT = 0.2  # Reduced from 0.4 for faster non-direct response
    STRAGGLER_DIRECT = 0.0  # No straggler for "Sam, ..." — direct address is complete
    WAIT_TIMEOUT = 2.0

    def __init__(self, session_id, bot_id, server):
        self.session_id = session_id
        self.bot_id = bot_id
        self.server = server
        self.tag = f"[S:{session_id[:8]}]"

        self.username = ""
        self.meeting_url = ""
        self.mode = "client_call"
        self.started_at = time.time()

        self.agent = PMAgent()
        self.speaker = CartesiaSpeaker(bot_id=bot_id, session_id=session_id)
        self.trigger = TriggerDetector()
        self.vad = RmsVAD()

        self.jira = JiraClient()
        self.azure_extractor = AzureExtractor()

        self._speaking = False  # Backed by property — setter notifies AddresseeDecider
        self.audio_playing = False
        self.convo_history = deque(maxlen=10)
        self.current_task = None
        self.current_text = ""
        self.current_speaker = ""
        self.interrupt_event = asyncio.Event()
        self.generation = 0

        self.buffer = []
        self.partial_text = ""
        self.partial_speaker = ""
        self.last_flushed_text = ""

        self.was_interrupted = False
        self.playing_ack = False
        self._partial_interrupted = (
            False  # Interrupted via interim transcript (fast path)
        )
        self._partial_interrupt_time = 0  # When partial interrupt happened
        self._current_audio_duration = (
            0  # Duration of currently playing audio (seconds)
        )
        self.eot_task = None
        self.searching = False

        # Pre-fired dynamic filler task (Ship 4 — fire-after-EOT pattern).
        # Started after EOT decides RESPOND, runs in parallel with the
        # response pipeline (NLU → Policy → Router → Agent). When the
        # router returns RESEARCH, this task is almost always ready,
        # giving us contextual fillers without latency overhead. When
        # the router returns PM, this task gets cancelled (one wasted
        # Groq call per PM turn — acceptable trade-off for research
        # turn quality).
        self._pending_filler_task: asyncio.Task | None = None

        self.audio_event_count = 0
        self.max_conf = 0.0
        self.debug_audio_file = None

        self._jira_context = ""
        self._ticket_cache = []  # Structured list of pre-loaded tickets

        # Stage 2.5: research context cache (kept as fallback under
        # RESEARCH_JOURNAL_ENABLED=0). Replaced in normal operation by
        # the journal+rewriter design below.
        self._research_cache = self._make_empty_cache()

        # Stage 2.6: research journal pointer (the actual journal lives on
        # self.agent.journal — we just keep a reference here for clarity).
        # Also the rewriter task: _handle_addressee_decision fires it in
        # parallel with EOT/addressee, _unified_research_v2 awaits the result.
        self._research_journal = None  # set after agent is wired
        self._last_rewriter_task: asyncio.Task | None = None
        self._last_rewritten_query: str | None = None

        # ── Option C: Deferred Ticket Creation ──
        # Instead of creating tickets mid-meeting (which often produces garbage
        # titles from ambiguous requests), we record the user's intent here and
        # let Azure create high-quality tickets at meeting-end with full context.
        #
        # Each entry: {"user_said": "...", "extracted_summary": "...", "at_time": "..."}
        # Passed to Azure extraction as EXPLICIT CREATION SIGNALS (not meta-actions
        # to ignore, but confirmed user requests to act on).
        self._pending_creation_intents: list[dict] = []

        # ── Feature 4 Memory: Conversation-scoped summaries ──
        # Attendees in this meeting (populated from Recall.ai participant events
        # during first 60 seconds). Sorted, lowercase-normalized for stable IDs.
        self._attendees: set[str] = set()
        self._attendees_locked = False  # True after lock window passes
        self._memory_lock_task_started = False  # Guard: only start the lock task once

        # Derived from attendees: stable ID for the conversation memory thread
        self._conversation_id: str = ""

        # Delayed turn taking state tasks
        self._delayed_standup_task: Optional[asyncio.Task] = None
        self._delayed_client_task: Optional[asyncio.Task] = None

        # Thinking filler / acknowledgement timing and sentiment trackers
        self._flux_latest_sentiment: Optional[str] = None
        self._standup_filler_duration: float = 0.0
        self._standup_filler_relay_start: float = 0.0
        self._last_filler: Optional[str] = None

        # F1: numeric sentiment score from Deepgram (None if not available)
        self._last_sentiment_score: Optional[float] = None
        # F2: session-level empathy mode — flips True when rolling avg score is negative
        self._empathy_mode: bool = False
        self._session_sentiment_scores: list[float] = []
        # F8: active-listening backchannel state
        self._backchannel_task: Optional[asyncio.Task] = None
        self._backchannel_last_played: float = 0.0
        self._backchannel_last_token: Optional[str] = None

        # Per-utterance insight log (sentiment, emotion, intent) — persisted to
        # session_insights.json in real-time; session summary written at session end.
        self._utterance_log: list[dict] = []

        # Memory loaded at session start from past meetings with this same group.
        # _memory_full: ~1000 tokens, injected into PM/research response prompts
        # _memory_header: ~50 tokens, injected into unified research planner
        self._memory_full: str = ""
        self._memory_header: str = ""

        # ── Client mode contextual silence reprompt ──
        # If user goes silent for 20 seconds after Sam finishes speaking,
        # Sam sends a gentle contextual reprompt ("Still there?", "Anything else?", etc).
        # Max 2 reprompts per silence window, then Sam stays silent until user speaks.
        # Cancelled on ANY user transcript (partial or final).
        self._client_silence_task: asyncio.Task | None = None
        self._client_reprompt_count = 0
        self._user_left = False
        self._session_closed = False
        self._active_name: str = ""
        self._last_greeting_variation = -1
        self._last_sam_intent: str | None = (
            None  # "question", "creation", "greeting", "completion", "answer", "general"
        )

        # Output Media: audio page WebSocket connection
        self.audio_ws = None  # Set when audio page connects

        # Standup mode
        self.standup_flow = None
        self._standup_buffer = []
        self._standup_timer = None
        self._standup_finished = False  # Guard: prevent double finish
        self._auto_left = False  # Guard: prevent double leave

        # Flux STT (own Deepgram connection for standup)
        self._stt_queue = None  # asyncio.Queue for audio chunks → Flux
        self._stt_task = None  # Background task running stream_deepgram()
        self._flux_enabled = False  # True when Flux is active for this session
        self._flux_audio_buf = b""  # Re-chunk buffer for 80ms chunks (2560 bytes)
        _FLUX_CHUNK_SIZE = 2560  # 80ms at 16kHz S16LE (recommended by Deepgram)
        self._FLUX_CHUNK_SIZE = _FLUX_CHUNK_SIZE
        self._flux_standup_audio_logged = False  # log first routed chunk once

        # Flux speech_off debounce — Recall's participant_events.speech_off signals
        # user stopped speaking. We convert the current Flux interim text to FINAL
        # after a debounce window (allows mid-sentence pauses without premature finalize).
        # If speech_on fires within the debounce window, timer is cancelled.
        self._flux_last_interim_text = (
            ""  # latest interim text from Flux (cleared on FINAL)
        )
        self._flux_speech_off_task = None  # debounce timer task
        self._FLUX_SPEECH_OFF_DEBOUNCE_MS = (
            300  # delay before treating speech_off as turn-end
        )

        # Speculative processing (EagerEndOfTurn → pre-compute Groq before EndOfTurn confirms)
        self._speculative_task = None  # Background Groq classify task
        self._speculative_text = ""  # Transcript used for speculation

        # ── Per-Speaker Flux (client mode only, USE_PER_SPEAKER_FLUX gated) ──
        # FluxSessionManager: N parallel Flux connections, one per participant
        # AddresseeDecider: LLM-based addressee detection for multi-party meetings
        # Initialized in setup() only when mode != "standup" and toggle is on.
        # Standup mode never creates these (uses existing _stt_task single-Flux).
        self._flux_manager: FluxSessionManager | None = None
        self._addressee_decider: AddresseeDecider | None = None
        self._sam_last_response: str = ""  # For addressee LLM context

        # ── Week 4: DialogueManager (observer mode in Phase 1) ──────────────
        # Runs NLU + Policy on every turn, logs decisions, persists state.
        # Trigger.py still drives actual speak/silent until Phase 4 flips the switch.
        # Initialized in setup() only when USE_DIALOGUE_MANAGER=1 and mode!="standup".
        self._dialogue_manager = None  # type: DialogueManager | None
        self._checkpoint_mgr = None  # type: CheckpointManager | None

        # ── Phase 2+3: meeting setup (agenda/tickets/scope) from UI ──────
        # server.py attaches this dict onto the session BEFORE setup() runs.
        # Shape: {"agenda": [...], "scope_in": [...], "scope_out": [...],
        #         "ticket_keys": [...], "planned_duration_minutes": int}
        # Empty dict = no setup data, observer falls back to cache-only behavior.
        self._meeting_setup: dict = {}

        # Phase 4B: cache DM mode once at session start (avoids per-turn
        # os.environ.get races with dotenv load timing). Populated in setup().
        self._dm_mode: int = 1  # default observer

    @property
    def _per_speaker_flux_active(self) -> bool:
        """True when per-speaker Flux is running (client mode + toggle on)."""
        return self._flux_manager is not None

    @property
    def speaking(self) -> bool:
        """True when Sam is currently producing audio/responding."""
        return self._speaking

    @speaking.setter
    def speaking(self, value: bool) -> None:
        """Setter that notifies AddresseeDecider of state changes.

        AddresseeDecider pauses its silence timer while Sam is speaking
        and resumes (back to LISTENING) when Sam stops.
        """
        previously = self._speaking
        self._speaking = bool(value)
        if self._addressee_decider and previously != self._speaking:
            try:
                self._addressee_decider.on_sam_speaking_changed(self._speaking)
            except Exception as e:
                print(f"[{ts()}] {self.tag} ⚠️  AddresseeDecider notify failed: {e}")

    @property
    def _streaming_mode(self) -> bool:
        """True if Output Media audio page is connected."""
        return self.audio_ws is not None and not self.audio_ws.closed

    async def setup(self):
        self.agent.start()
        self.agent.session_type = self.mode  # "client_call" → Gemini, "standup" → Groq
        await self.speaker.warmup()
        await self.vad.setup()
        if self.jira.enabled:
            await self.jira.test_connection()
            await self._sync_pending_tickets()
            await self._preload_jira_context()

        # Feature 4 Memory: lock task will be started when first attendee joins
        # (not at session init — the bot takes time to join the meeting, so
        # starting the timer at init causes the lock to fire before anyone is present).
        # See participant_events.join handler for the actual trigger.

        # ── Initialize per-speaker Flux (client mode only) ──────────────────
        # Standup mode: NEVER initialize — it uses existing single-Flux via _stt_task.
        # Client mode: initialize only if toggle + Deepgram key + Groq key are set.
        if (
            self.mode != "standup"
            and USE_PER_SPEAKER_FLUX
            and DEEPGRAM_API_KEY
            and GROQ_API_KEY
        ):
            # Stage R: lock one Deepgram key to this session for its lifetime
            try:
                from key_rotator import key_for_session as _key_for_session

                _dg_key = (
                    _key_for_session("DEEPGRAM", self.session_id) or DEEPGRAM_API_KEY
                )
            except Exception:
                _dg_key = DEEPGRAM_API_KEY
            self._flux_manager = FluxSessionManager(
                api_key=_dg_key,
                on_final=self._on_flux_final_client,
                on_interim=self._on_flux_interim_client,
                keyterms=None,  # No keyterms — avoid echo→keyterm hallucination
                tag=self.tag,
            )
            self._addressee_decider = AddresseeDecider(
                groq_api_key=GROQ_API_KEY,
                get_context=self._build_addressee_context,
                on_decision=self._handle_addressee_decision,
                tag=self.tag,
            )
            print(f"[{ts()}] {self.tag} 🎙️  Per-speaker Flux + AddresseeDecider enabled")
        elif self.mode != "standup" and USE_PER_SPEAKER_FLUX:
            missing = []
            if not DEEPGRAM_API_KEY:
                missing.append("DEEPGRAM_API_KEY")
            if not GROQ_API_KEY:
                missing.append("GROQ_API_KEY")
            print(
                f"[{ts()}] {self.tag} ⚠️  Per-speaker Flux DISABLED — missing: {missing}"
            )

        # ── Week 4 Phase 1: Initialize DialogueManager (OBSERVER mode) ──────
        # Runs NLU + Policy alongside the existing pipeline. Decisions logged.
        # Trigger.py still drives Sam's actual speak/silent. Standup mode skipped.
        # We initialize eagerly with a stub conversation_id — if attendees aren't
        # yet known, we use a session-scoped fallback. Cross-session memory is
        # handled by your existing Feature 4 Memory (not DialogueManager).
        if (
            USE_DIALOGUE_MANAGER
            and _DIALOGUE_MANAGER_AVAILABLE
            and self.mode != "standup"
        ):
            try:
                # Stable conv_id: prefer Feature 4 Memory's conversation_id if
                # computed already; else use session_id. DialogueManager mostly
                # uses this for checkpoint keying, not memory lookup.
                dm_conv_id = self._conversation_id or f"session-{self.session_id[:8]}"

                self._checkpoint_mgr = CheckpointManager(tag=self.tag)
                await self._checkpoint_mgr.initialize()

                # Observer mode: agent_callback is a no-op logger.
                # In Phase 4, this will wire into the real Agent pipeline.
                async def _observer_agent_callback(text, speaker, state):
                    print(
                        f"[{ts()}] {self.tag} 👁️  [OBSERVER] "
                        f"Agent callback suppressed (Trigger.py is driving)"
                    )

                self._dialogue_manager = DialogueManager(
                    conversation_id=dm_conv_id,
                    agent_callback=_observer_agent_callback,
                    checkpoint_mgr=self._checkpoint_mgr,
                    session_id=self.session_id,
                    tag=self.tag,
                )

                # Phase 2+3: build initialization from (a) UI setup and (b) live
                # ticket cache. Setup drives agenda/scope; cache drives tickets.
                # Falls back to empty state if no setup was provided.
                setup = self._meeting_setup or {}
                agenda_items = []
                try:
                    from dialogue import AgendaItem

                    raw_agenda = setup.get("agenda") or []
                    for i, item in enumerate(raw_agenda):
                        if isinstance(item, str):
                            agenda_items.append(
                                AgendaItem(
                                    id=f"topic_{i + 1}",
                                    title=item.strip(),
                                    status="pending",
                                )
                            )
                        elif isinstance(item, dict) and item.get("title"):
                            agenda_items.append(
                                AgendaItem(
                                    id=item.get("id", f"topic_{i + 1}"),
                                    title=item["title"].strip(),
                                    status=item.get("status", "pending"),
                                    notes=item.get("notes", ""),
                                )
                            )
                except Exception as e:
                    print(
                        f"[{ts()}] {self.tag} ⚠️  Agenda build failed (using empty): {e}"
                    )
                # Ticket cache → state (uses tickets already pre-loaded by session)
                preloaded = {}
                try:
                    from dialogue import TicketData
                    import time as _t

                    for t in self._ticket_cache or []:
                        key = (t.get("key") or "").upper()
                        if not key:
                            continue
                        preloaded[key] = TicketData(
                            key=key,
                            summary=t.get("summary", ""),
                            status=t.get("status", ""),
                            assignee=t.get("assignee", ""),
                            priority=t.get("priority", ""),
                            description=t.get("description", ""),
                            updated=t.get("updated"),
                            cached_at=_t.time(),
                        )
                except Exception as e:
                    print(f"[{ts()}] {self.tag} ⚠️  Ticket cache build failed: {e}")
                # ── Client profile from "Know About Them" UI feature ─────────
                # The /api/clients/research endpoint returns profile_text; the UI
                # is responsible for sending it back in the /start setup body.
                # Try multiple key names defensively. If none match, profile stays
                # empty and Sam will speak honestly without grounding (the
                # synthesis prompts already handle empty client_profile_block).
                cp_raw = (
                    setup.get("client_profile")
                    or setup.get("client_profile_text")
                    or setup.get("profile_text")
                    or setup.get("clientProfile")
                    or setup.get("about_them")
                    or ""
                )
                client_profile_text = cp_raw.strip() if isinstance(cp_raw, str) else ""

                # Diagnostic — tells us in the logs whether the UI sent the
                # profile. Critical for fixing "online payment solution" and
                # "Rohan the CEO" hallucinations end-to-end.
                print(
                    f"[{ts()}] {self.tag} 📋 _meeting_setup keys: {sorted(setup.keys())}"
                )
                if client_profile_text:
                    print(
                        f"[{ts()}] {self.tag} 📋 client_profile: "
                        f"{len(client_profile_text)} chars (preview: "
                        f"{client_profile_text[:120]!r}...)"
                    )
                else:
                    print(
                        f"[{ts()}] {self.tag} 📋 client_profile: EMPTY — "
                        f"UI did not send it under any known key. Sam will "
                        f"answer company-fact questions without grounding."
                    )

                await self._dialogue_manager.initialize(
                    participants=sorted(self._attendees) if self._attendees else [],
                    agenda=agenda_items,
                    scope_in=setup.get("scope_in") or [],
                    scope_out=setup.get("scope_out") or [],
                    pre_loaded_tickets=preloaded,
                    prior_meeting_summaries=[],
                    commitments_inherited=[],
                    planned_duration_minutes=int(
                        setup.get("planned_duration_minutes") or 30
                    ),
                    client_profile=client_profile_text,
                )
                if setup or preloaded:
                    print(
                        f"[{ts()}] {self.tag} 📋 Setup injected: "
                        f"agenda={len(agenda_items)}, "
                        f"scope_in={len(setup.get('scope_in') or [])}, "
                        f"scope_out={len(setup.get('scope_out') or [])}, "
                        f"tickets={len(preloaded)}, "
                        f"client_profile={len(client_profile_text)} chars"
                    )

                # Phase 4B step 1: read + cache DM mode once, log it
                try:
                    self._dm_mode = int(os.environ.get("USE_DIALOGUE_MANAGER", "1"))
                except (ValueError, TypeError):
                    self._dm_mode = 1
                if self._dm_mode >= 2:
                    actions = "stay_silent, scope_redirect"
                    print(
                        f"[{ts()}] {self.tag} 🎮 [Phase4] ✅ mode={self._dm_mode} "
                        f"(driver) — will act on: {actions}"
                    )
                elif self._dm_mode == 1:
                    print(
                        f"[{ts()}] {self.tag} 🎮 [Phase4] 🟡 mode=1 "
                        f"(observer only — decisions logged, not acted on)"
                    )
                else:
                    print(
                        f"[{ts()}] {self.tag} 🎮 [Phase4] ⚪ mode={self._dm_mode} "
                        f"(DialogueManager disabled)"
                    )

                # Phase 3.5: wire DialogueManager into Agent so Sam's responses
                # include agenda/scope/prior-meeting context in every system prompt.
                try:
                    if hasattr(self.agent, "set_dialogue_manager"):
                        self.agent.set_dialogue_manager(self._dialogue_manager)
                        print(f"[{ts()}] {self.tag} 🔗 Agent ↔ DialogueManager wired")
                except Exception as e:
                    print(
                        f"[{ts()}] {self.tag} ⚠️  Agent DM wire failed (non-fatal): {e}"
                    )
                print(
                    f"[{ts()}] {self.tag} 🧠 DialogueManager OBSERVER active "
                    f"(conv_id={dm_conv_id[:8]}...)"
                )
            except Exception as e:
                print(
                    f"[{ts()}] {self.tag} ⚠️  DialogueManager init failed "
                    f"(non-fatal, continuing): {e}"
                )
                self._dialogue_manager = None
                self._checkpoint_mgr = None
        elif USE_DIALOGUE_MANAGER and not _DIALOGUE_MANAGER_AVAILABLE:
            print(
                f"[{ts()}] {self.tag} ⚠️  USE_DIALOGUE_MANAGER=1 but modules "
                f"not importable — see startup warning above"
            )

        print(f"[{ts()}] {self.tag} ✅ Session ready (bot: {self.bot_id[:12]})")

    async def _sync_pending_tickets(self):
        pending = session_store.get_pending_tickets()
        if not pending:
            return
        print(f"[{ts()}] {self.tag} 🔄 Syncing {len(pending)} pending ticket(s)...")
        synced = 0
        for item in pending:
            try:
                await self.jira.create_ticket(
                    summary=item.get("summary", ""),
                    issue_type=item.get("type", "Task"),
                    priority=item.get("priority", "Medium"),
                    description=item.get("description", ""),
                    labels=item.get("labels", []),
                )
                synced += 1
            except Exception as e:
                print(f"[{ts()}] {self.tag} ⚠️  Pending sync failed: {e}")
                break
        if synced > 0:
            session_store.clear_pending_tickets()
            print(f"[{ts()}] {self.tag} ✅ Synced {synced} pending ticket(s)")

    async def _preload_jira_context(self):
        """Load Jira tickets into cache at session start.

        Smart mode (USE_SMART_PRELOAD=True, default):
          - Small projects (≤100 tickets): load everything by recent update
          - Large projects (>100 tickets): load current sprint + high priority +
            recent (14d) + non-Done — capped at 100 most relevant

        Legacy mode (USE_SMART_PRELOAD=False): original 50-ticket recent-update load
        """
        try:
            base_filter = f"project = {self.jira.project} AND summary !~ 'Standup —'"

            if USE_SMART_PRELOAD:
                # Size probe — cheap (maxResults=0)
                total = await self.jira.count_tickets(base_filter)
                print(f"[{ts()}] {self.tag} 📊 Project size: {total} ticket(s)")

                if total <= SMALL_PROJECT_THRESHOLD:
                    # Small project: load everything by recency (your current behavior)
                    jql = f"{base_filter} ORDER BY updated DESC"
                    tickets = await self.jira.search_jql(
                        jql, max_results=SMALL_PROJECT_THRESHOLD
                    )
                    print(f"[{ts()}] {self.tag} 📥 Small project mode — loading all")
                else:
                    # Large project: current sprint + high priority + recent updates + open
                    # Fallback query without sprint clause if sprint() fails on some Jira configs
                    jql = (
                        f"{base_filter} AND ("
                        f"sprint in openSprints() "
                        f"OR priority in (Highest, High) "
                        f"OR updated >= -14d "
                        f"OR statusCategory != Done"
                        f") ORDER BY priority DESC, updated DESC"
                    )
                    try:
                        tickets = await self.jira.search_jql(
                            jql, max_results=PRELOAD_MAX_LARGE
                        )
                    except Exception as e:
                        # Sprint function not available on this Jira instance — retry without it
                        print(
                            f"[{ts()}] {self.tag} ⚠️  Smart JQL failed ({e}) — retrying without sprint clause"
                        )
                        jql_safe = (
                            f"{base_filter} AND ("
                            f"priority in (Highest, High) "
                            f"OR updated >= -14d "
                            f"OR statusCategory != Done"
                            f") ORDER BY priority DESC, updated DESC"
                        )
                        tickets = await self.jira.search_jql(
                            jql_safe, max_results=PRELOAD_MAX_LARGE
                        )
                    print(
                        f"[{ts()}] {self.tag} 📥 Large project mode — filtered load (sprint+priority+recent)"
                    )
            else:
                # Legacy mode — original 50-ticket recent-update load
                jql = f"{base_filter} ORDER BY updated DESC"
                tickets = await self.jira.search_jql(jql, max_results=50)

            if tickets:
                self._ticket_cache = tickets
                self._rebuild_jira_context()
                done_count = sum(1 for t in tickets if t.get("status") == "Done")
                print(
                    f"[{ts()}] {self.tag} 📥 Pre-loaded {len(tickets)} ticket(s) ({done_count} Done, standup subtasks excluded)"
                )
            else:
                print(f"[{ts()}] {self.tag} ⚠️  No tickets returned from pre-load")
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  Pre-load failed: {e}")

    def _rebuild_jira_context(self):
        """Rebuild _jira_context string from _ticket_cache."""
        if not self._ticket_cache:
            self._jira_context = "(no tickets loaded)"
            return
        lines = []
        for t in self._ticket_cache:
            line = f"  {t['key']}: {t['summary']} [{t['status']}] ({t['priority']}, {t['assignee']})"
            if t.get("description"):
                line += f" — {t['description'][:100]}"
            lines.append(line)
        self._jira_context = "JIRA TICKETS:\n" + "\n".join(lines)

    def _update_ticket_cache(self, ticket: dict):
        """Add or update a ticket in the cache."""
        for i, t in enumerate(self._ticket_cache):
            if t["key"] == ticket["key"]:
                self._ticket_cache[i] = ticket
                self._rebuild_jira_context()
                return
        self._ticket_cache.append(ticket)
        self._rebuild_jira_context()

    def _get_ticket_context_for_search(self) -> str:
        """Get a compact summary of project tech stack from ticket descriptions for search query generation."""
        if not self._ticket_cache:
            return ""
        parts = []
        for t in self._ticket_cache[:10]:
            desc = t.get("description", "")
            if desc:
                parts.append(f"{t['summary']}: {desc[:80]}")
            else:
                parts.append(t["summary"])
        return "Project tickets: " + "; ".join(parts)

    async def cleanup(self):
        self._session_closed = True
        self._cancel_client_silence_timer()
        if self.current_task and not self.current_task.done():
            self.current_task.cancel()
        if self.eot_task and not self.eot_task.done():
            self.eot_task.cancel()
        if self._delayed_standup_task and not self._delayed_standup_task.done():
            self._delayed_standup_task.cancel()
        if self._delayed_client_task and not self._delayed_client_task.done():
            self._delayed_client_task.cancel()

        # ── Per-speaker Flux cleanup (client mode) ─────────────────────────
        if self._addressee_decider:
            try:
                await self._addressee_decider.close()
            except Exception as e:
                print(f"[{ts()}] {self.tag} ⚠️  AddresseeDecider close failed: {e}")
            self._addressee_decider = None
        if self._flux_manager:
            try:
                await self._flux_manager.close_all()
            except Exception as e:
                print(f"[{ts()}] {self.tag} ⚠️  FluxManager close_all failed: {e}")
            self._flux_manager = None

        # ── Week 4 Phase 1: DialogueManager cleanup ────────────────────────
        # close() waits for pending persist tasks + does a final SQLite save.
        if self._dialogue_manager is not None:
            try:
                await self._dialogue_manager.close()
            except Exception as e:
                print(
                    f"[{ts()}] {self.tag} ⚠️  DialogueManager close failed "
                    f"(non-fatal): {e}"
                )
            self._dialogue_manager = None
        if self._checkpoint_mgr is not None:
            try:
                await self._checkpoint_mgr.close()
            except Exception as e:
                print(
                    f"[{ts()}] {self.tag} ⚠️  CheckpointManager close failed "
                    f"(non-fatal): {e}"
                )
            self._checkpoint_mgr = None

        # Save standup data if standup was in progress
        if self.standup_flow:
            self.standup_flow._cancel_silence_timer()
            if self._standup_timer and not self._standup_timer.done():
                self._standup_timer.cancel()
            # Stop Flux STT
            await self._stop_flux_stt()
            if self.standup_flow.data.get("yesterday", {}).get("raw"):
                await self._finish_standup()

        try:
            await self.speaker.close()
        except Exception:
            pass

        if len(self.agent.rag._entries) > 3:
            # Skip Jira extraction for standup mode — standup already creates subtasks
            skip_jira = self.mode == "standup"
            if skip_jira:
                print(
                    f"[{ts()}] {self.tag} ℹ️  Standup mode — skipping post-meeting Jira extraction"
                )
            await self._post_meeting_save(
                extract_jira=self.jira.enabled
                and self.azure_extractor.enabled
                and not skip_jira
            )

        try:
            await self.jira.close()
        except Exception:
            pass
        try:
            await self.azure_extractor.close()
        except Exception:
            pass
        # Drain Groq key health events into session insights for ops visibility
        try:
            health_events = self.agent.client.get_events_since(self.started_at)
            if health_events:
                session_store.append_utterance_insight(
                    self.session_id,
                    {
                        "timestamp": __import__("datetime")
                        .datetime.utcnow()
                        .strftime("%Y-%m-%dT%H:%M:%SZ"),
                        "speaker": "Sam",
                        "type": "groq_key_health",
                        "events": health_events,
                        "summary": {
                            "rate_limited": sum(
                                1
                                for e in health_events
                                if e.get("event") == "key_rate_limited"
                            ),
                            "exhausted": sum(
                                1
                                for e in health_events
                                if e.get("event") == "all_keys_exhausted"
                            ),
                            "rotations_recovered": sum(
                                1
                                for e in health_events
                                if e.get("event") == "rotation_success"
                            ),
                        },
                    },
                )
                print(
                    f"[{ts()}] {self.tag} 📊 Groq health: "
                    f"{len(health_events)} rotation event(s) logged to session insights"
                )
        except Exception:
            pass

        self.agent.reset()
        print(f"[{ts()}] {self.tag} 🧹 Session cleaned up")

    async def _post_meeting_save(self, extract_jira=True):
        print(f"[{ts()}] {self.tag} 📋 Meeting ended — processing session...")
        transcript_entries = [
            {
                "speaker": e.get("speaker", "?"),
                "text": e["text"],
                "time": e.get("time", 0),
            }
            for e in self.agent.rag._entries
        ]
        transcript_text = "\n".join(
            e["text"]
            for e in self.agent.rag._entries
            if e.get("speaker", "").lower() != "sam"
        )
        duration_min = int((time.time() - self.started_at) / 60)

        items = []
        if extract_jira:
            try:
                # OPTION C: Pass pending creation intents (from in-meeting CREATE
                # requests that were deferred). Azure treats these as EXPLICIT
                # user intents to create tickets, using full transcript context
                # for proper titles and descriptions.
                items = await self.azure_extractor.extract_action_items(
                    transcript_text,
                    pending_intents=self._pending_creation_intents,
                )
            except Exception as e:
                print(f"[{ts()}] {self.tag} ❌ Extraction failed: {e}")

        created_tickets = []
        if items and self.jira.enabled:
            user_cache = {}
            for item in items:
                try:
                    related = await self.jira.find_related_tickets(
                        item.get("summary", "")
                    )
                    if related:
                        rs = ", ".join(
                            f"{r['key']} ({r['summary'][:40]})" for r in related[:3]
                        )
                        item["description"] = (
                            item.get("description", "") + f"\n\nRelated: {rs}"
                        )

                    assignee_id = None
                    an = item.get("assignee")
                    if an and an.lower() not in ("null", "none", "unassigned", ""):
                        assignee_id = user_cache.get(an) or await self.jira.search_user(
                            an
                        )
                        if an not in user_cache:
                            user_cache[an] = assignee_id

                    result = await self.jira.create_ticket(
                        summary=item["summary"],
                        issue_type=item.get("type", "Task"),
                        priority=item.get("priority", "Medium"),
                        description=item.get("description", ""),
                        labels=item.get("labels", ["client-feedback"]),
                        assignee_id=assignee_id,
                    )
                    item["jira_key"] = result.get("key", "?")
                    created_tickets.append(item)
                    print(
                        f"[{ts()}] {self.tag} 📤 Created {item['jira_key']}: {item['summary']}"
                    )
                except JiraAuthError:
                    session_store.save_pending_ticket(item)
                    break
                except Exception as e:
                    print(f"[{ts()}] {self.tag} ⚠️  Failed — saving locally: {e}")
                    session_store.save_pending_ticket(item)

        session_data = {
            "session_id": self.session_id,
            "date": time.strftime("%Y-%m-%dT%H:%M:%SZ", time.gmtime()),
            "user": self.username,
            "mode": self.mode,
            "project": self.jira.project if self.jira.enabled else "",
            "meeting_url": self.meeting_url,
            "duration_minutes": duration_min,
            "transcript": transcript_entries,
            "summary": "; ".join(
                e["text"][:80]
                for e in transcript_entries
                if not e["text"].startswith("Sam:")
            )[:200],
            "feedback_count": len(items),
            "tickets_created": len(created_tickets),
            "action_items": [
                {
                    "type": i.get("type"),
                    "summary": i.get("summary"),
                    "priority": i.get("priority"),
                    "jira_key": i.get("jira_key", ""),
                    "assignee": i.get("assignee", ""),
                }
                for i in items
            ],
        }

        # Feature 4 Memory: generate conversation-scoped summary + save under conv_id.
        # This populates memory for future meetings with the same group of attendees.
        # Done before session_store.save_session so conv_id is available in session too.
        if (
            USE_CONVERSATION_MEMORY
            and self.mode != "standup"
            and self.azure_extractor.enabled
        ):
            try:
                # Lock attendees if not already locked (handles very short meetings)
                if not self._attendees_locked:
                    self._attendees_locked = True
                    if self._attendees:
                        self._conversation_id = self._compute_conversation_id(
                            self._attendees
                        )

                if self._conversation_id and self._attendees and transcript_text:
                    attendee_list = sorted(self._attendees)
                    print(
                        f"[{ts()}] {self.tag} 🧠 Generating conversation summary for "
                        f"conv_id={self._conversation_id[:8]}... attendees={attendee_list}"
                    )

                    summary = await self.azure_extractor.extract_session_summary(
                        transcript=transcript_text,
                        attendees=attendee_list,
                    )

                    if summary:
                        session_store.save_conversation_summary(
                            conversation_id=self._conversation_id,
                            summary=summary,
                            participants=attendee_list,
                            session_id=self.session_id,
                        )
                        session_data["conversation_id"] = self._conversation_id
                        session_data["conversation_summary"] = summary
            except Exception as e:
                print(
                    f"[{ts()}] {self.tag} ⚠️  Conversation summary failed (non-fatal): {e}"
                )

        try:
            # Standups have their own tab via standup_flow.save_standup() — don't
            # double-save them into sessions.json (which feeds the Sessions tab).
            # Client calls and other modes still save here as normal.
            if self.mode == "standup":
                print(
                    f"[{ts()}] {self.tag} ℹ️  Standup mode — skipping Sessions-tab save (standup already saved to Standups tab)"
                )
            else:
                session_store.save_session(session_data)
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  Save session failed: {e}")

        # Write session-level insights summary for client sessions
        if self.mode != "standup" and self._utterance_log:
            try:
                participants = (
                    sorted(self._attendees) if self._attendees else [self.username]
                )
                session_store.save_session_insights(
                    session_id=self.session_id,
                    session_type=self.mode,
                    date=time.strftime("%Y-%m-%d", time.gmtime()),
                    participants=participants,
                    summary=_compute_session_summary(self._utterance_log),
                )
            except Exception as e:
                print(
                    f"[{ts()}] {self.tag} ⚠️  Client session insights save failed (non-fatal): {e}"
                )

    # ── Conversation Memory (Feature 4) ───────────────────────────────────────

    @staticmethod
    def _compute_conversation_id(attendees: set) -> str:
        """Compute a stable conversation_id from a set of attendees.
        Same set of names → same ID. Different set → different ID.
        Privacy-safe by design: different attendee groups = different memory threads.
        """
        import hashlib

        if not attendees:
            return ""
        # Normalize: strip, lowercase, sort for stability
        names = sorted(a.strip().lower() for a in attendees if a and a.strip())
        if not names:
            return ""
        canonical = "|".join(names)
        return hashlib.sha256(canonical.encode()).hexdigest()[:16]

    async def _lock_attendees_and_load_memory(self, delay: float = 60.0):
        """Wait for attendees to gather, then lock the set and load memory.

        Runs as a background task shortly after session start. After `delay`
        seconds, we lock the attendee set (late joiners don't change conv_id)
        and compute the conversation_id, then load + reconcile memory.
        """
        if not USE_CONVERSATION_MEMORY:
            return

        await asyncio.sleep(delay)

        if self._attendees_locked:
            return  # already done
        self._attendees_locked = True

        if not self._attendees:
            print(f"[{ts()}] {self.tag} 🧠 No attendees detected — memory load skipped")
            return

        self._conversation_id = self._compute_conversation_id(self._attendees)
        attendee_list = sorted(self._attendees)
        print(
            f"[{ts()}] {self.tag} 🧠 Conversation locked: "
            f"conv_id={self._conversation_id[:8]}... attendees={attendee_list}"
        )

        await self._load_memory()

    async def _load_memory(self):
        """Load prior meeting summaries for this conversation_id.
        Builds _memory_full (for response generation) and _memory_header (for planner).
        """
        if not self._conversation_id:
            return

        try:
            summaries = session_store.get_conversation_summaries(
                self._conversation_id, limit=3
            )
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  Memory load failed: {e}")
            return

        if not summaries:
            print(
                f"[{ts()}] {self.tag} 🧠 No prior meetings with this group — fresh start"
            )
            return

        print(f"[{ts()}] {self.tag} 🧠 Loaded {len(summaries)} prior summary(ies)")

        # Reconcile with live Jira before formatting
        summaries = self._reconcile_memory_with_jira(summaries)

        # Build full memory (for PM/research response prompts)
        self._memory_full = self._format_full_memory(summaries)

        # Build compact header (for unified research planner)
        self._memory_header = self._format_memory_header(summaries)

    def _reconcile_memory_with_jira(self, summaries: list) -> list:
        """Annotate each summary's ticket references with CURRENT Jira status.

        Prevents stale memory from contradicting live data. If memory says
        'SCRUM-162 in progress' but Jira shows it Done, we annotate the summary
        so Sam uses current status.
        """
        if not self._ticket_cache:
            return summaries

        # Build lookup of current ticket states
        current_states = {t.get("key"): t for t in self._ticket_cache if t.get("key")}

        for entry in summaries:
            summary = entry.get("summary", {})
            refs = summary.get("tickets_referenced", [])
            updates = []

            for ref in refs:
                key = ref.get("key") if isinstance(ref, dict) else None
                if not key:
                    continue
                current = current_states.get(key)
                if not current:
                    continue

                historical_status = (
                    ref.get("status_at_time", "?") if isinstance(ref, dict) else "?"
                )
                current_status = current.get("status", "?")

                if historical_status != current_status:
                    updates.append(
                        f"{key}: was '{historical_status}' in that meeting, "
                        f"NOW '{current_status}' (use current)"
                    )

            if updates:
                summary["_reconciliation"] = updates

        return summaries

    def _format_full_memory(self, summaries: list) -> str:
        """Build the full memory block for PM/research response prompts.
        Returns ~1000-token structured context block.
        """
        lines = ["=== MEMORY FROM PRIOR MEETINGS WITH THIS GROUP ==="]
        lines.append(
            "(Use as context; do not recite unless asked. Current Jira state overrides historical status.)"
        )
        lines.append("")

        for i, entry in enumerate(summaries):
            date = entry.get("date", "?")[:10]  # YYYY-MM-DD
            s = entry.get("summary", {})

            lines.append(f"--- Meeting {i + 1} ({date}) ---")

            summary_text = s.get("summary_text", "").strip()
            if summary_text:
                lines.append(f"Summary: {summary_text}")

            decisions = s.get("decisions", [])
            if decisions:
                lines.append(f"Decisions: {'; '.join(decisions[:5])}")

            commitments = s.get("commitments", [])
            if commitments:
                commit_strs = []
                for c in commitments[:5]:
                    if isinstance(c, dict):
                        commit_strs.append(
                            f"{c.get('who', '?')} → {c.get('what', '?')} "
                            f"({c.get('when', 'unspecified')})"
                        )
                if commit_strs:
                    lines.append(f"Commitments: {'; '.join(commit_strs)}")

            open_items = s.get("open_items", [])
            if open_items:
                lines.append(f"Open items: {'; '.join(open_items[:5])}")

            # Reconciliation notes (stale ticket states)
            reconciliation = s.get("_reconciliation", [])
            if reconciliation:
                lines.append("Ticket status updates since this meeting:")
                for update in reconciliation:
                    lines.append(f"  - {update}")

            lines.append("")

        lines.append("=== END MEMORY ===")
        lines.append("")
        lines.append("Rules for using memory:")
        lines.append(
            "- Reference specific items only if user asks about past or continuity helps"
        )
        lines.append(
            "- If memory doesn't cover a topic, say you don't have that detail"
        )
        lines.append("- Current Jira state OVERRIDES historical status in memory")
        lines.append("- Don't invent details not in the memory above")

        return "\n".join(lines)

    def _format_memory_header(self, summaries: list) -> str:
        """Build compact header for unified research planner (~50 tokens)."""
        if not summaries:
            return ""

        # Aggregate topics and open items across summaries
        topics = []
        open_items = []
        for entry in summaries:
            s = entry.get("summary", {})
            topics.extend(s.get("topics", []))
            open_items.extend(s.get("open_items", []))

        # Dedupe preserving order
        seen = set()
        topics = [t for t in topics if not (t.lower() in seen or seen.add(t.lower()))][
            :5
        ]
        seen = set()
        open_items = [
            i for i in open_items if not (i.lower() in seen or seen.add(i.lower()))
        ][:3]

        parts = ["Context: Returning session with prior history."]
        if topics:
            parts.append(f"Recent topics: {', '.join(topics)}.")
        if open_items:
            parts.append(f"Open: {', '.join(open_items)}.")

        return " ".join(parts)

    # ── PHASE 1: Door #1 ticket enrichment helpers ────────────────────────────
    # When a research-route question mentions a specific ticket key (e.g.
    # "SCRUM-87"), we fetch the LIVE ticket from Jira and inject it into the
    # persona prompt sent to Brave AI Mode. This lets Brave answer with current
    # ticket state instead of guessing or hallucinating.

    def _detect_ticket_keys(self, text: str) -> list[str]:
        """Extract ticket keys (e.g. SCRUM-87) from user text.

        Returns up to 5 unique keys, in the order they appear. Uses the project
        prefix from self.jira.project (typically 'SCRUM') so this adapts if the
        Jira project changes. Falls back to common prefix patterns if Jira
        isn't configured.

        Examples:
          "What's the status of SCRUM-87?"        → ["SCRUM-87"]
          "Compare SCRUM-12, SCRUM-15, SCRUM-22"  → ["SCRUM-12", "SCRUM-15", "SCRUM-22"]
          "Tell me about my login bug"            → []   (no key mentioned)
          "Status of scrum 87"                    → ["SCRUM-87"] (case-insensitive, space-tolerant)
        """
        if not text:
            return []

        # Build pattern from the active project key (e.g. SCRUM, PROJ, ABC).
        # Fall back to a permissive 2-10 letter pattern if Jira not configured.
        if self.jira and self.jira.enabled and self.jira.project:
            project_prefix = _re.escape(self.jira.project)
        else:
            project_prefix = r"[A-Z][A-Z0-9_]{1,9}"

        # Pattern matches:
        #   SCRUM-87, scrum-87, SCRUM 87, scrum_87
        # Case-insensitive, allowing space/underscore between prefix and number.
        # Word boundaries prevent matching mid-word (e.g. "ABC-12345-X" → only ABC-12345).
        pattern = rf"\b({project_prefix})[\s_-]+(\d{{1,6}})\b"

        keys = []
        seen = set()
        for match in _re.finditer(pattern, text, _re.IGNORECASE):
            prefix = match.group(1).upper()
            number = match.group(2)
            key = f"{prefix}-{number}"
            if key not in seen:
                seen.add(key)
                keys.append(key)
                if len(keys) >= 5:  # Cap to avoid abuse / huge Jira fetches
                    break
        return keys

    def _format_fresh_tickets_for_prompt(self, tickets: list[dict]) -> str:
        """Format freshly-fetched Jira tickets for injection into Door #1's
        persona prompt.

        Output is prepended to project_context so Brave AI Mode reads these
        FIRST (highest priority info). Format is compact prose-friendly bullets
        that match the existing project_context style.

        Each ticket includes: key, status, summary, truncated description.
        Max ~150 chars per ticket to keep total prompt reasonable.
        """
        if not tickets:
            return ""

        lines = ["FRESHLY FETCHED FROM JIRA (live, just now):"]
        for t in tickets[:5]:  # Defensive cap
            if not isinstance(t, dict):
                continue
            key = t.get("key", "?")
            status = (t.get("status") or "?").strip()
            summary = (t.get("summary") or "(no summary)").strip()
            desc = (t.get("description") or "").strip()
            # Compact format: "- KEY (status): summary — description"
            line = f"- {key} ({status}): {summary}"
            if desc:
                # Truncate description aggressively — we just need a hint
                desc_clean = _re.sub(r"\s+", " ", desc).strip()
                if len(desc_clean) > 120:
                    desc_clean = desc_clean[:117] + "..."
                line += f" — {desc_clean}"
            lines.append(line)
        return "\n".join(lines)

    # ── Ship 3: agenda + client_profile blocks for Door #1 prompt ─────────────
    # These pull from session state (DialogueManager) and format them for
    # injection into the Brave persona prompt. They prevent the "agenda
    # hallucination" bug where Brave invented an agenda from ticket data.

    def _build_agenda_block_for_prompt(self) -> str:
        """Build the AGENDA section for Brave's structured prompt.

        Reads agenda from DialogueManager state. Formats as numbered bullets
        with status markers for each topic. Marks the current topic with an
        arrow so Brave knows what's being discussed right now.

        Returns "(no fixed agenda for today)" if no agenda is loaded — Brave's
        prompt instructions tell it to say so honestly rather than fabricate.
        """
        if self._dialogue_manager is None:
            return "(no fixed agenda for today)"
        try:
            snap = self._dialogue_manager.get_state_snapshot()
        except Exception:
            return "(no fixed agenda for today)"

        if "error" in snap:
            return "(no fixed agenda for today)"

        agenda = snap.get("agenda") or []
        if not agenda:
            return "(no fixed agenda for today)"

        topic_idx = snap.get("current_topic_index", -1)
        lines = []
        for i, item in enumerate(agenda):
            if isinstance(item, dict):
                title = (item.get("title") or "").strip()
                status = (item.get("status") or "pending").strip()
            else:
                title = str(item).strip()
                status = "pending"
            if not title:
                continue
            # Mark current topic with arrow; show status for done/skipped
            marker = "→" if i == topic_idx else " "
            status_tag = ""
            if status == "done":
                status_tag = " [DONE]"
            elif status == "skipped":
                status_tag = " [SKIPPED]"
            elif i == topic_idx:
                status_tag = " [CURRENT]"
            lines.append(f"{marker} {i + 1}. {title}{status_tag}")
        return "\n".join(lines) if lines else "(no fixed agenda for today)"

    def _build_client_profile_block_for_prompt(self) -> str:
        """Build the CLIENT PROFILE section for Brave's structured prompt.

        Combines two pieces:
          1. PEOPLE ON THIS CALL — explicit participant names so Brave addresses
             the right person (prevents Sam from making up names like "Rachel"
             or "Mike"). Reads from self._attendees (session-level) which is
             populated as people join the call. This is the authoritative
             source — DialogueManager's participants list is not always kept
             in sync.
          2. COMPANY BACKGROUND — research about the client's business, if a
             profile was loaded via the "Know About Them" feature.

        Returns "(no client profile loaded)" if neither attendees nor profile
        text exist (e.g. very early in the call before anyone has joined).
        """
        # Read attendees directly from session state (single source of truth).
        # DialogueManager's participants field is not reliably synced — using
        # self._attendees avoids the "Sam invents names" bug.
        names = sorted(
            n
            for n in (self._attendees or set())
            if n and n.strip() and n.strip().lower() != "sam"
        )

        # Client profile (from "Know About Them" UI, if loaded). This goes
        # through DialogueManager state because that's where the UI writes it.
        cp = ""
        if self._dialogue_manager is not None:
            try:
                snap = self._dialogue_manager.get_state_snapshot()
                if "error" not in snap:
                    cp = (snap.get("client_profile") or "").strip()
            except Exception:
                pass

        if not cp and not names:
            return "(no client profile loaded)"

        chunks = []

        # Sam's company (the bot is Sam @ AnavClouds, fixed identity)
        chunks.append(
            "OUR COMPANY: AnavClouds Software Solutions "
            "(Salesforce consulting, based in Jaipur, India)"
        )

        # People on the call — explicit and authoritative
        if names:
            if len(names) == 1:
                chunks.append(
                    f"ON THIS CALL: {names[0]} is the only client on this call. "
                    f'Address them as "{names[0]}". '
                    f"Do NOT use any other name — there is no one else here."
                )
            else:
                names_str = ", ".join(names)
                chunks.append(
                    f"ON THIS CALL: {names_str} ({len(names)} people total). "
                    f"Use only these names when addressing clients. "
                    f"Do NOT invent or use any other names."
                )

        # Stage 2.12: explicit speaker-to-profile binding.
        # Old heading "CLIENT BACKGROUND" was vague reference framing.
        # New heading tells Sam: the people on this call work at this
        # company; answer their personal-context questions from THIS profile,
        # not from web search.
        if cp:
            # Stage 2.7: cap raised from 600 to 2500. Production logs showed
            # the 1659-char profile was being chopped in half on every research
            # synthesis (profile=842 chars). Azure 4o-mini has 16k context
            # window — 2500 chars of profile is well within budget.
            if len(cp) > 2500:
                cp = cp[:2497].rsplit(" ", 1)[0] + "..."
            chunks.append(
                "CLIENT YOU'RE MEETING WITH "
                "(the person(s) on this call WORK AT the company described "
                "below. This is authoritative info about who they are and "
                'what their company does. When they ask "my company", '
                '"our team", "the CEO", "our work", "my industry" — '
                "the answer is in THIS profile. Do NOT search the web for "
                "personal questions about the speaker's company; ground "
                "your response in this profile. Use this context to make "
                "every recommendation specific to their actual business, "
                "products, and challenges. IMPORTANT: names mentioned IN "
                "this background — founders, executives, advisors — are "
                "usually NOT on the call; only address the speaker by the "
                "names listed under ON THIS CALL above):\n"
                f"{cp}"
            )

        return "\n".join(chunks)

    # ── Client Mode Contextual Reprompt ──────────────────────────────────────

    def _classify_sam_intent(self, sam_text: str) -> str:
        """Classify Sam's last response into an intent category.

        Used to pick a contextual reprompt when user goes silent. Simple
        keyword/pattern matching — good enough for template selection.
        """
        if not sam_text:
            return "general"

        text_lower = sam_text.lower().strip()

        # Greeting (strongest signal — usually at start of call)
        greeting_markers = [
            "welcome",
            "how are you",
            "good to see",
            "hey",
            "hi sahil",
            "hello",
        ]
        if any(m in text_lower[:60] for m in greeting_markers):
            return "greeting"

        # Ticket creation confirmation (mentions logging/creating + ticket)
        creation_markers = [
            "created",
            "logged",
            "log it",
            "logging",
            "i'll log",
            "i've logged",
            "i'll create",
            "i've created",
            "noted",
            "scrum-",
        ]
        if any(m in text_lower for m in creation_markers):
            return "creation"

        # Question to user (ends with ? — Sam needs an answer)
        if sam_text.rstrip().endswith("?"):
            return "question"

        # Task completion signals
        completion_markers = [
            "done",
            "sorted",
            "taken care of",
            "handled",
            "transitioned",
            "moved to",
            "updated",
        ]
        if any(m in text_lower for m in completion_markers):
            return "completion"

        # Default: Sam gave an informational answer
        return "answer"

    def _pick_contextual_reprompt(self) -> str:
        """Choose a reprompt template matching Sam's last intent.
        Uses the reprompt count (1st or 2nd) to pick variation.
        """
        intent = self._last_sam_intent or "general"
        count = self._client_reprompt_count  # 1 for first reprompt, 2 for second

        reprompts = {
            "question": [
                "Take your time with that one.",
                "When you're ready with the answer, I'm here.",
            ],
            "creation": [
                "Anything else we should log?",
                "Let me know if you want more tickets created.",
            ],
            "greeting": [
                "What would you like to discuss today?",
                "Ready when you are.",
            ],
            "completion": [
                "Anything else on your mind?",
                "What's next on your list?",
            ],
            "answer": [
                "Does that help clarify things?",
                "Let me know if you want to dig deeper.",
            ],
            "general": [
                "Still there?",
                "Let me know when you're ready.",
            ],
        }

        options = reprompts.get(intent, reprompts["general"])
        idx = min(count - 1, len(options) - 1)
        return options[idx] if idx >= 0 else options[0]

    def _start_client_silence_timer(self):
        """Start (or restart) the 20-second silence reprompt timer.
        Safe to call repeatedly — cancels any existing timer first.
        """
        if self.mode == "standup":
            return  # standup has its own reprompt system

        # Cancel any existing timer
        if self._client_silence_task and not self._client_silence_task.done():
            self._client_silence_task.cancel()

        self._client_silence_task = asyncio.create_task(self._client_silence_reprompt())

    def _cancel_client_silence_timer(self):
        """Cancel pending silence timer + reset reprompt counter.
        Called when user speaks (partial or final transcript).
        """
        if self._client_silence_task and not self._client_silence_task.done():
            self._client_silence_task.cancel()
        # Reset counter — user activity means next silence window starts fresh
        self._client_reprompt_count = 0

    async def _client_silence_reprompt(self):
        """Wait 30 seconds, then send a contextual reprompt if user still silent.
        Max 2 reprompts per silence window, then plays a recovery message and waits.
        """
        try:
            await asyncio.sleep(30.0)

            # Guards before reprompting
            if self._session_closed or self._user_left:
                return
            if self._client_reprompt_count >= 2:
                # Play a recovery message instead of going silent
                _first = (self.username or "").split()[0] if self.username else "there"
                _recovery = f"Hey {_first}, I might have missed that — could you say that again?"
                print(
                    f"[{ts()}] {self.tag} ⏰ Reprompt limit reached — playing recovery message"
                )
                self.speaking = True
                try:
                    await self._speak(_recovery, "reprompt-recovery", self.generation)
                except Exception as e:
                    print(f"[{ts()}] {self.tag} ⚠️  Recovery speak failed: {e}")
                finally:
                    self.speaking = False
                    self.audio_playing = False
                # Reset counter and wait a full 30s more before any further action
                self._client_reprompt_count = 0
                await asyncio.sleep(30.0)
                return
            if self.speaking or self.audio_playing:
                # Sam is already speaking — don't interrupt with a reprompt.
                # Restart timer so we try again after Sam finishes.
                self._start_client_silence_timer()
                return
            if self.playing_ack:
                # Interrupt ack is playing — wait
                self._start_client_silence_timer()
                return

            self._client_reprompt_count += 1
            prompt = self._pick_contextual_reprompt()

            print(
                f"[{ts()}] {self.tag} ⏰ Contextual reprompt "
                f"({self._client_reprompt_count}/2) "
                f'[intent={self._last_sam_intent}]: "{prompt}"'
            )

            # Add reprompt to transcript history (marked as Sam)
            try:
                self.agent.rag._entries.append(
                    {"speaker": "Sam", "text": prompt, "time": time.time()}
                )
            except Exception:
                pass  # non-fatal if rag state is unexpected

            # Speak the reprompt. Option A interrupt will cancel this if user
            # starts speaking during the reprompt itself.
            self.speaking = True
            try:
                await self._speak(prompt, "client-reprompt", self.generation)
            except Exception as e:
                print(f"[{ts()}] {self.tag} ⚠️  Reprompt speak failed: {e}")
                return
            finally:
                self.speaking = False
                self.audio_playing = False

            # Restart timer — after reprompt, wait another 20s for potential
            # second reprompt (if user still silent). Counter already incremented,
            # so second call will hit the limit check above.
            self._start_client_silence_timer()

        except asyncio.CancelledError:
            # User spoke — timer cleanly cancelled. No action needed.
            pass
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  Silence reprompt failed: {e}")

    # ── Event dispatch ────────────────────────────────────────────────────────

    async def handle_event(self, raw):
        t = time.time()
        try:
            payload = json.loads(raw)
        except Exception:
            return
        event = payload.get("event", "")

        if event == "transcript.data":
            # Per-speaker Flux active: Recall.ai is NOT sending STT in client mode.
            # But if transcript events somehow arrive (e.g., toggle was flipped
            # mid-session, or standup falls through), ignore them. Flux callbacks
            # handle transcripts in this mode.
            if self._per_speaker_flux_active:
                return

            inner = payload.get("data", {}).get("data", {})
            words = inner.get("words", [])
            text = " ".join(w.get("text", "") for w in words).strip()
            speaker = inner.get("participant", {}).get("name", "Unknown")
            if not text or speaker.lower() == "sam":
                return
            text = _fix_transcription(text)
            text = _re.sub(r"\s+", " ", text).strip().lstrip("-–— ").strip()
            if not text:
                return

            self.agent.log_exchange(speaker, text)
            print(f"\n[{ts()}] {self.tag} [{speaker}] {text}")
            # Append full user utterance to transcript file (main path)
            self._append_transcript(speaker, text)

            # Log per-utterance insight (sentiment unavailable on Recall.ai path)
            _delay = _get_adaptive_delay(text)
            self._log_utterance_insight(
                speaker=speaker,
                text=text,
                sentiment=None,
                filler_triggered=False,
                pause_detected=_delay > 0.4,
                adaptive_endpointing_used="slow"
                if _delay >= 1.2
                else ("medium" if _delay >= 0.7 else "fast"),
            )

            # User spoke — cancel any pending silence reprompt (client mode only)
            if self.mode != "standup":
                self._cancel_client_silence_timer()

            # ── Standup mode: buffer transcript, restart timer only when safe ──
            if self.standup_flow and not self.standup_flow.is_done:
                # Clear interrupt flag if this is the final transcript after a fast interrupt
                if self._partial_interrupted:
                    self._partial_interrupted = False
                    self._partial_interrupt_time = 0
                    self.partial_text = ""

                # When Flux is active, skip Recall's transcripts — Flux handles STT
                if self._flux_enabled:
                    return

                # Fallback: use Recall's transcripts with 1.2s timer
                self._standup_buffer.append(text)
                # Only cancel/restart timer when NOT processing
                if not self.standup_flow._processing:
                    if self._standup_timer and not self._standup_timer.done():
                        self._standup_timer.cancel()
                    self._standup_timer = asyncio.create_task(
                        self._flush_standup_buffer(speaker)
                    )
                return

            # ── Partial interrupt: audio already stopped via interim transcript ──
            if self._partial_interrupted:
                latency_ms = (time.time() - self._partial_interrupt_time) * 1000
                self._partial_interrupted = False
                self._partial_interrupt_time = 0
                print(
                    f"[{ts()}] {self.tag} ⚡ Fast interrupt complete: final transcript arrived {latency_ms:.0f}ms after audio stopped"
                )
                self.buffer.clear()
                self.partial_text = ""
                await self._play_interrupt_ack()
                # Don't return — fall through to process this text normally
                self.buffer.append((speaker, text, t))
                self._schedule_eot_check(speaker)
                return

            if self.was_interrupted:
                self.was_interrupted = False
                self.buffer.clear()
                self.partial_text = ""
                await self._play_interrupt_ack()
                return

            self.partial_text = ""
            self.partial_speaker = ""

            if self.last_flushed_text:
                flushed_w = set(self.last_flushed_text.lower().split())
                incoming_w = set(text.lower().split())
                sim = len(flushed_w & incoming_w) / max(
                    len(flushed_w), len(incoming_w), 1
                )
                if sim >= 0.7 or text.lower().strip() in self.last_flushed_text.lower():
                    self.last_flushed_text = ""
                    return
            self.last_flushed_text = ""

            if self.speaking and not self.playing_ack:
                # ── Backchannel filter ───────────────────────────────────
                # Short listener acknowledgments ("okay", "yeah", "got it")
                # mean "keep going", not "stop". Don't interrupt for these.
                # Applies regardless of which participant said it.
                if _is_backchannel(text):
                    print(
                        f'[{ts()}] {self.tag} 🎧 Backchannel (slow path): "{text[:30]}" — continuing'
                    )
                    return

                if self.current_speaker == speaker and _is_ack(text.lstrip("-–— ")):
                    return
                # Interrupt if Sam is anywhere in his speaking flow.
                # Don't gate on self.audio_playing — it can flicker False
                # between audio chunks, causing missed interrupts during
                # the micro-gap between streaming chunks.
                print(
                    f"[{ts()}] {self.tag} 🛑 Interrupt via final transcript (slow path)"
                )
                try:
                    await self._stop_all_audio()
                except Exception as e:
                    print(f"[{ts()}] {self.tag} ⚠️  Stop audio failed (non-fatal): {e}")
                self.interrupt_event.set()
                if self.current_task and not self.current_task.done():
                    self.current_task.cancel()
                self.speaking = False
                self.audio_playing = False
                self.buffer.clear()
                self.vad.end_turn()
                await self._play_interrupt_ack()
                return

            self.buffer.append((speaker, text, t))
            self._schedule_eot_check(speaker)

        elif event == "transcript.partial_data":
            # Per-speaker Flux active: interims come from Flux callbacks, not Recall.
            if self._per_speaker_flux_active:
                return

            inner = payload.get("data", {}).get("data", {})
            text = " ".join(w.get("text", "") for w in inner.get("words", [])).strip()
            speaker = inner.get("participant", {}).get("name", "Unknown")
            if text and speaker.lower() != "sam":
                self.partial_text = _fix_transcription(text)
                self.partial_speaker = speaker
                if self.eot_task and not self.eot_task.done():
                    self.eot_task.cancel()
                if self._delayed_client_task and not self._delayed_client_task.done():
                    self._delayed_client_task.cancel()

                # User started speaking — cancel silence reprompt immediately
                # (even if they speak at the 19.9th second, this catches it).
                if self.mode != "standup":
                    self._cancel_client_silence_timer()

                # ── Fast interrupt: stop Sam's audio on first interim words ──
                # Drop audio_playing guard — it flickers False between chunks.
                # Use self.speaking as the stable indicator of Sam's response mode.
                if (
                    self.speaking
                    and not self.playing_ack
                    and not self._partial_interrupted
                ):
                    # ── Backchannel filter ───────────────────────────────────
                    # Short listener acknowledgments ("okay", "yeah", "got it")
                    # mean "keep going", not "stop". Don't interrupt for these.
                    # Unknown/meaningful words still interrupt — only match list.
                    if _is_backchannel(text):
                        # User is just listening — suppress interrupt.
                        # Don't set _partial_interrupted so future REAL interrupts work.
                        print(
                            f'[{ts()}] {self.tag} 🎧 Backchannel (fast path): "{text[:30]}" — continuing'
                        )
                        return

                    # In standup Q&A phase, don't interrupt — user speech gets buffered
                    # EXCEPTION: if a re-prompt is playing, user is finally answering → interrupt!
                    if self.standup_flow and not self.standup_flow.is_done:
                        from standup import StandupState

                        is_reprompt = getattr(
                            self.standup_flow, "_playing_reprompt", False
                        )
                        if not is_reprompt:
                            if self.standup_flow.state not in (
                                StandupState.CONFIRM,
                                StandupState.SUMMARY,
                            ):
                                return  # Q&A phase — buffer, don't interrupt
                            # Only interrupt long audio (summary >5s), not short acks (<3s)
                            if self._current_audio_duration < 5.0:
                                return  # Short response — don't interrupt, buffer instead
                        else:
                            print(
                                f"[{ts()}] {self.tag} ⚡ Re-prompt interrupted — user is answering"
                            )

                    # OPTION A: Any transcribed word interrupts immediately.
                    # Nova-3 filters coughs/uhms/mhms before they become transcripts,
                    # so single-word transcripts are real intent (not noise).
                    word_count = len(text.split())
                    if word_count >= 1:
                        # Phantom STT filter: "two", "seven", etc. — known
                        # hallucinations from silence/breathing between Sam's
                        # TTS chunks. Suppress these as no-ops.
                        if _is_phantom_filler(text):
                            print(
                                f"[{ts()}] {self.tag} 🚫 Phantom filler "
                                f'ignored: "{text}"'
                            )
                            return
                        self._partial_interrupted = True
                        self._partial_interrupt_time = time.time()
                        print(
                            f'[{ts()}] {self.tag} ⚡ FAST INTERRUPT via interim: "{text[:40]}" ({word_count} words) — stopping audio'
                        )
                        try:
                            await self._stop_all_audio()
                        except Exception as e:
                            print(
                                f"[{ts()}] {self.tag} ⚠️  Stop audio failed (non-fatal): {e}"
                            )
                        self.interrupt_event.set()
                        if self.current_task and not self.current_task.done():
                            self.current_task.cancel()
                        # Cancel standup flush so _processing gets released
                        if self.standup_flow and not self.standup_flow.is_done:
                            if self._standup_timer and not self._standup_timer.done():
                                self._standup_timer.cancel()
                            self.standup_flow._processing = False
                        self.speaking = False
                        self.audio_playing = False
                        self.vad.end_turn()

        elif event == "participant_events.speech_off":
            # In standup mode with Flux: user stopped producing audio.
            # Flux can't detect silence-based EOT when mic is muted (no audio packets).
            # Start a debounce timer — if silence persists past threshold, treat Flux's
            # current interim as FINAL. If speech_on fires within debounce, cancel the timer.
            if (
                self.standup_flow
                and not self.standup_flow.is_done
                and self._flux_enabled
                and self._flux_last_interim_text
            ):
                speaker_name = (
                    payload.get("data", {})
                    .get("data", {})
                    .get("participant", {})
                    .get("name", "")
                )
                if _extract_first_name(speaker_name) == self.standup_flow.developer:
                    # Cancel any existing debounce (rare — back-to-back speech_off)
                    if (
                        self._flux_speech_off_task
                        and not self._flux_speech_off_task.done()
                    ):
                        self._flux_speech_off_task.cancel()
                    self._flux_speech_off_task = asyncio.create_task(
                        self._flux_debounce_finalize()
                    )

        elif event == "participant_events.speech_on":
            speaker = (
                payload.get("data", {})
                .get("data", {})
                .get("participant", {})
                .get("name", "Unknown")
            )
            # Cancel pending speech_off debounce — user resumed speaking, Flux will get more audio
            if self._flux_speech_off_task and not self._flux_speech_off_task.done():
                print(
                    f"[{ts()}] {self.tag} 🎤 speech_on — cancelling speech_off debounce"
                )
                self._flux_speech_off_task.cancel()
                self._flux_speech_off_task = None
            if self._delayed_standup_task and not self._delayed_standup_task.done():
                print(
                    f"[{ts()}] {self.tag} 🎤 speech_on — cancelling delayed standup response"
                )
                self._delayed_standup_task.cancel()
            if self._delayed_client_task and not self._delayed_client_task.done():
                print(
                    f"[{ts()}] {self.tag} 🎤 speech_on — cancelling delayed client response"
                )
                self._delayed_client_task.cancel()
            # In standup mode, don't interrupt on speech_on — too aggressive (fires on mic noise)
            # Only partial_data (actual transcribed words) should interrupt during CONFIRM/SUMMARY
            if self.standup_flow and not self.standup_flow.is_done:
                return
            if self.speaking and self.audio_playing and self.current_speaker != speaker:
                try:
                    await self._stop_all_audio()
                except Exception as e:
                    print(f"[{ts()}] {self.tag} ⚠️  Stop audio failed (non-fatal): {e}")
                self.interrupt_event.set()
                if self.current_task and not self.current_task.done():
                    self.current_task.cancel()
                # Release standup processing lock on interrupt
                if self.standup_flow and not self.standup_flow.is_done:
                    if self._standup_timer and not self._standup_timer.done():
                        self._standup_timer.cancel()
                    self.standup_flow._processing = False
                self.speaking = False
                self.audio_playing = False
                self.was_interrupted = True

        elif event == "audio_mixed_raw.data":
            if not self.vad.ready or self.audio_playing:
                return
            audio_b64 = payload.get("data", {}).get("data", {}).get("buffer", "")
            if audio_b64:
                try:
                    pcm = base64.b64decode(audio_b64)
                    for rms in self.vad.process_chunk(pcm):
                        self.vad.update_state(rms)
                    self.audio_event_count += 1
                    if self.audio_event_count == 1:
                        print(
                            f"[{ts()}] {self.tag} 🔊 First audio received ({len(pcm)} bytes)"
                        )
                except Exception:
                    pass

        elif event == "audio_separate_raw.data":
            # ── Standup mode: existing single-Flux path ─────
            if self._flux_enabled and self._stt_queue:
                inner = payload.get("data", {}).get("data", {})
                participant = inner.get("participant", {}).get("name", "")
                # Match on first name — standup uses the developer's first name
                # ("Piyush") but Recall.ai reports the full name from Google Meet
                # ("Piyush Sharma"). Without this normalization, audio is never
                # routed to Flux and the standup hangs.
                participant_first = _extract_first_name(participant) if participant else ""
                if (
                    participant
                    and self.standup_flow
                    and participant_first == self.standup_flow.developer
                ):
                    audio_b64 = inner.get("buffer", "")
                    if audio_b64:
                        try:
                            pcm = base64.b64decode(audio_b64)
                            if not self._flux_standup_audio_logged:
                                self._flux_standup_audio_logged = True
                                print(
                                    f"[{ts()}] {self.tag} 🎯 Flux standup audio routing ON "
                                    f"({participant_first}, {len(pcm)} bytes/chunk)"
                                )
                            self._flux_audio_buf += pcm
                            while len(self._flux_audio_buf) >= self._FLUX_CHUNK_SIZE:
                                chunk = self._flux_audio_buf[: self._FLUX_CHUNK_SIZE]
                                self._flux_audio_buf = self._flux_audio_buf[
                                    self._FLUX_CHUNK_SIZE :
                                ]
                                await self._stt_queue.put(chunk)
                        except Exception as e:
                            print(
                                f"[{ts()}] {self.tag} ⚠️  Flux standup audio route failed: {e}"
                            )

            # ── Client mode: route to per-speaker Flux manager ──────────
            elif self._per_speaker_flux_active:
                inner = payload.get("data", {}).get("data", {})
                participant = inner.get("participant", {})
                p_id = str(participant.get("id", ""))
                p_name = participant.get("name", "Unknown") or "Unknown"

                # Skip Sam's own audio (bot doesn't normally appear in separate streams,
                # but belt-and-suspenders).
                if p_name.lower() == "sam" or not p_id:
                    pass
                else:
                    audio_b64 = inner.get("buffer", "")
                    if audio_b64:
                        try:
                            pcm = base64.b64decode(audio_b64)
                            await self._flux_manager.route_audio(p_id, p_name, pcm)
                        except Exception as e:
                            # Non-fatal — manager logs internally
                            pass

        elif event == "participant_events.join":
            name = (
                payload.get("data", {})
                .get("data", {})
                .get("participant", {})
                .get("name", "Unknown")
            )
            if name and name.lower() != "sam":
                print(f"[{ts()}] {self.tag} 👋 {name} joined")
                self._active_name = _extract_first_name(name)
                # User is back (or new user joined) — reprompts should work again
                self._user_left = False
                # Feature 4 Memory: record attendee + start lock task on first join.
                # We start the 30s timer when the FIRST attendee joins (not at session
                # init) because the bot/participants take variable time to join.
                if USE_CONVERSATION_MEMORY and not self._attendees_locked:
                    self._attendees.add(name.strip())
                    if not self._memory_lock_task_started and self.mode != "standup":
                        self._memory_lock_task_started = True
                        print(
                            f"[{ts()}] {self.tag} 🧠 Memory lock timer started (30s window)"
                        )
                        asyncio.create_task(
                            self._lock_attendees_and_load_memory(delay=30.0)
                        )
                if self.mode == "standup":
                    asyncio.create_task(self._start_standup(name))
                else:
                    asyncio.create_task(self._greet(name, t))

        elif event == "participant_events.leave":
            inner = payload.get("data", {}).get("data", {})
            p = inner.get("participant", {})
            name = p.get("name", "Unknown")
            p_id = str(p.get("id", ""))
            if name and name.lower() != "sam":
                print(f"[{ts()}] {self.tag} 👋 {name} left")
                # Close this speaker's Flux session if per-speaker mode is active
                if self._per_speaker_flux_active and p_id:
                    try:
                        await self._flux_manager.close_session(p_id)
                    except Exception as e:
                        print(f"[{ts()}] {self.tag} ⚠️  Flux close_session failed: {e}")
                # Mark user left + cancel any pending silence reprompt.
                # No point reprompting an empty room.
                self._user_left = True
                if self._client_silence_task and not self._client_silence_task.done():
                    self._client_silence_task.cancel()

    # ── EOT ───────────────────────────────────────────────────────────────────

    @staticmethod
    def _is_direct_address(text: str) -> bool:
        """Check if text starts with 'Sam' — direct address, skip EOT + straggler."""
        t = text.strip().lower()
        return (
            t.startswith("sam,")
            or t.startswith("sam ")
            or t == "sam"
            or t.startswith("hey sam")
            or t.startswith("hi sam")
            or t.startswith("hello sam")
        )

    def _maybe_fire_pending_filler(self, text: str) -> None:
        """Ship 4: Pre-fire dynamic filler after EOT decides RESPOND.

        Starts the Groq filler generation in the background so it cooks in
        parallel with NLU + Policy + Router (~1.5-2s of pipeline). By the
        time the router decides RESEARCH, the filler is almost always ready.

        Skip rules:
          - Dynamic fillers disabled (USE_DYNAMIC_FILLERS=0)
          - Utterance too short (<6 words) — likely small talk, not a
            research question, no need to burn Groq quota
          - Existing pending filler not yet consumed — cancel old, start fresh

        The task is stored in self._pending_filler_task and consumed (or
        cancelled) by the response pipeline downstream.
        """
        if not USE_DYNAMIC_FILLERS:
            return

        # Skip filler for short utterances (small talk, acknowledgments).
        # These rarely route to RESEARCH and don't need contextual fillers.
        word_count = len(text.split())
        if word_count < 6:
            return

        # Cancel any stale pending task from a previous turn that didn't
        # get consumed (defensive — shouldn't normally happen).
        if (
            self._pending_filler_task is not None
            and not self._pending_filler_task.done()
        ):
            self._pending_filler_task.cancel()

        # Fire the new filler — runs in background, harvested at router time.
        self._pending_filler_task = asyncio.create_task(
            self.agent.generate_dynamic_filler(text)
        )
        print(
            f"[{ts()}] {self.tag} 🎨 Pre-fired dynamic filler "
            f"(running in parallel with pipeline)"
        )

    # ══════════════════════════════════════════════════════════════════════
    # Per-speaker Flux integration (client mode only)
    # ══════════════════════════════════════════════════════════════════════

    # ── F2: Empathy mode ────────────────────────────────────────────────────

    def _update_empathy_state(self, score: float) -> None:
        """Track rolling sentiment score; flip _empathy_mode on sustained negativity."""
        self._session_sentiment_scores.append(score)
        # Keep last 5 finals for rolling average
        if len(self._session_sentiment_scores) > 5:
            self._session_sentiment_scores = self._session_sentiment_scores[-5:]
        avg = sum(self._session_sentiment_scores) / len(self._session_sentiment_scores)
        if avg < -0.25 and not self._empathy_mode:
            self._empathy_mode = True
            print(
                f"[{ts()}] {self.tag} 💛 Empathy mode activated (avg score={avg:.2f})"
            )

    # ── F8: Backchannel active-listening tokens ──────────────────────────────

    async def _maybe_play_backchannel(
        self, gen: int, speaker: str = "", word_count: int = 0
    ) -> None:
        """Play a single backchannel token only during a genuine mid-speech pause.

        The 400ms sleep IS the pause-detection window. While the user speaks
        continuously, each new interim cancels this task before the sleep expires —
        so no audio is ever queued. A real pause of 400ms+ lets the sleep complete,
        then the token plays. is_final also cancels cleanly during the sleep.
        """
        try:
            # Pause-detection window — cancelled here if user keeps speaking or is_final fires
            await asyncio.sleep(0.4)
        except asyncio.CancelledError:
            raise  # clean exit, no audio played

        # Cooldown: 8 seconds between tokens
        if time.time() - self._backchannel_last_played < 8.0:
            return

        # Strict alternation: Hmm → Mhm → Hmm → ...
        token = "Mhm" if self._backchannel_last_token == "Hmm" else "Hmm"

        try:
            await self._stream_and_relay(token, gen)
        except asyncio.CancelledError:
            raise
        except Exception:
            return

        now = time.time()
        self._backchannel_last_played = now
        self._backchannel_last_token = token
        print(f'[{ts()}] {self.tag} 🎵 Backchannel: "{token}"')

        # Inline transcript log — sits between user utterances in session_insights.json
        try:
            from datetime import datetime as _dt

            _iso = _dt.utcnow().strftime("%Y-%m-%dT%H:%M:%SZ")
            session_store.append_utterance_insight(
                self.session_id,
                {
                    "timestamp": _iso,
                    "speaker": "Sam",
                    "type": "active_listening_token",
                    "token_played": token,
                    "trigger": "interim_pause",
                    "mid_utterance_of": speaker,
                    "word_count_at_trigger": word_count,
                    "cooldown_reset_at": _iso,
                },
            )
        except Exception:
            pass

    def _cancel_backchannel_task(self) -> None:
        if self._backchannel_task and not self._backchannel_task.done():
            self._backchannel_task.cancel()
        self._backchannel_task = None

    # ── F8: Strip robotic filler openers from LLM output ────────────────────

    def _strip_filler_opener(self, text: str) -> str:
        return _FILLER_OPENER_RE.sub("", text).lstrip(", ").strip()

    # ── Post-final acknowledgement filler (disabled — backchannels replace) ──

    def _needs_acknowledgement_filler(
        self, text: str, sentiment: Optional[str] = None
    ) -> bool:
        # Enable for client meetings on substantive turns (>5 words)
        if self.mode == "client_call" and len(text.strip().split()) > 5:
            return True
        return False

    def _select_acknowledgement_filler(
        self, text: str, sentiment: Optional[str] = None
    ) -> str:
        lower_text = text.lower()
        words = text.strip().split()
        word_count = len(words)

        if self.mode == "client_call":
            # Professional pool for client meetings
            # 1. Blocker / problem / negative sentiment
            if (
                "blocker" in lower_text
                or "stuck" in lower_text
                or "issue" in lower_text
                or sentiment == "negative"
            ):
                pool = [
                    "Understood, let me look into that...",
                    "Got it — that's worth digging into...",
                    "Right, I hear you...",
                ]
            # 2. Positive news
            elif (
                any(
                    c in lower_text
                    for c in ["done", "finished", "resolved", "complete", "merged"]
                )
                or sentiment == "positive"
            ):
                pool = [
                    "Good to hear — give me a moment...",
                    "Noted, let me pull that up...",
                    "That tracks — one sec...",
                ]
            # 3. Complex / many details
            elif word_count > 25 or bool(_re.search(r"\b\d+\b", lower_text)):
                pool = [
                    "Got it, let me think on that...",
                    "Interesting — give me just a moment...",
                    "One second, processing that...",
                ]
            # 4. Neutral
            else:
                pool = [
                    "Right, let me check on that...",
                    "Got it — one moment...",
                    "Understood, give me a sec...",
                ]
        else:
            # Original standup pool
            # 1. Blocker / problem / negative sentiment
            if (
                "blocker" in lower_text
                or "stuck" in lower_text
                or sentiment == "negative"
            ):
                pool = [
                    "Ohh, I see...",
                    "Oof, okay, that sounds tough...",
                    "Oh, I get it, that's not ideal...",
                ]
            # 2. Positive news
            elif (
                any(
                    c in lower_text
                    for c in [
                        "done",
                        "finished",
                        "resolved",
                        "complete",
                        "wrapped up",
                        "merged",
                    ]
                )
                or sentiment == "positive"
            ):
                pool = ["Oh nice!", "Awesome, got it...", "Great, glad to hear that..."]
            # 3. Many details / complex
            elif word_count > 25 or bool(_re.search(r"\b\d+\b", lower_text)):
                pool = [
                    "Got it, give me a sec...",
                    "Hmm okay, let me think about that...",
                    "Okay, let me process those details...",
                ]
            # 4. Neutral long update
            else:
                pool = ["Mmm-hmm, okay...", "Mmm, got it...", "Hmm, right..."]

        # Rotate through pool randomly so it never repeats twice in a row
        last_filler = getattr(self, "_last_filler", None)
        available = [f for f in pool if f != last_filler]
        if not available:
            available = pool

        chosen = random.choice(available)
        self._last_filler = chosen
        return chosen

    async def _on_flux_final_client(
        self,
        speaker: str,
        text: str,
        sentiment: Optional[str] = None,
        sentiment_score: Optional[float] = None,
    ) -> None:
        """Final transcript from a per-speaker Flux session (client mode).

        Logs the exchange + hands off to AddresseeDecider which decides
        (after 1s silence) who Sam should respond to.
        """
        # Cancel any pending backchannel — user finished speaking
        self._cancel_backchannel_task()

        text = _fix_transcription(text or "")
        text = _re.sub(r"\s+", " ", text).strip().lstrip("-–— ").strip()
        if not text or speaker.lower() == "sam":
            return

        if sentiment:
            self._flux_latest_sentiment = sentiment

        # Update sentiment state — drives empathy mode for client meetings
        if sentiment_score is not None:
            self._last_sentiment_score = sentiment_score
            self._update_empathy_state(sentiment_score)

        self.agent.log_exchange(speaker, text)
        print(f"\n[{ts()}] {self.tag} [{speaker}] {text}")
        # Append full user utterance to transcript file (standup path)
        self._append_transcript(speaker, text)

        # Log per-utterance sentiment / emotion / intent insight
        _delay = _get_adaptive_delay(text)
        self._log_utterance_insight(
            speaker=speaker,
            text=text,
            sentiment=sentiment,
            filler_triggered=False,
            pause_detected=_delay > 0.4,
            sentiment_score=sentiment_score,
            adaptive_endpointing_used="slow"
            if _delay >= 1.2
            else ("medium" if _delay >= 0.7 else "fast"),
        )

        # User spoke — cancel any pending silence reprompt
        self._cancel_client_silence_timer()

        # Clear any fast-interrupt flag set during Sam's audio
        if self._partial_interrupted:
            latency_ms = (time.time() - self._partial_interrupt_time) * 1000
            self._partial_interrupted = False
            self._partial_interrupt_time = 0
            print(
                f"[{ts()}] {self.tag} ⚡ Fast interrupt complete: final "
                f"transcript arrived {latency_ms:.0f}ms after audio stopped"
            )
            self.partial_text = ""

        if await self._maybe_handle_name_change(text):
            return

        # Hand off to AddresseeDecider — it will wait 1s of silence then decide
        if self._addressee_decider:
            self._addressee_decider.on_turn_completed(speaker, text)

    async def _on_flux_interim_client(
        self,
        speaker: str,
        text: str,
        sentiment: Optional[str] = None,
        sentiment_score: Optional[float] = None,
    ) -> None:
        """Interim transcript from a per-speaker Flux session (client mode).

        Feeds AddresseeDecider (resets silence timer) and runs fast-interrupt
        logic if Sam is currently speaking.
        """
        if not text:
            return

        if sentiment:
            self._flux_latest_sentiment = sentiment

        # Log interim update (matches standup "🎯 Flux interim" format)
        print(f'[{ts()}] {self.tag} 🎯 [{speaker}] interim: "{text[:60]}"')

        # Reset AddresseeDecider's silence timer — speech is happening
        if self._addressee_decider:
            self._addressee_decider.on_speech_activity()

        # Cancel any pending reprompt (user is speaking)
        self._cancel_client_silence_timer()

        # F8: active listening tokens — cancel+restart backchannel debounce on every interim.
        # 400ms sleep in _maybe_play_backchannel is the pause-detection window.
        # Suppress during first 60s of the meeting to avoid interrupting the opening.
        _bc_words = len(text.strip().split())
        _meeting_age = time.time() - self.started_at
        if _bc_words > 5 and not self.speaking and _meeting_age > 60.0:
            self._cancel_backchannel_task()
            self._backchannel_task = asyncio.create_task(
                self._maybe_play_backchannel(
                    self.generation,
                    speaker=speaker,
                    word_count=_bc_words,
                )
            )

        if self._delayed_client_task and not self._delayed_client_task.done():
            print(
                f'[{ts()}] {self.tag} ⏱️ Client response delayed task cancelled due to interim speech: "{text[:40]}"'
            )
            self._delayed_client_task.cancel()

        # ── Fast interrupt (same logic as transcript.partial_data path) ──
        if self.speaking and not self.playing_ack and not self._partial_interrupted:
            # Backchannel filter: short acks shouldn't interrupt
            if _is_backchannel(text):
                print(
                    f"[{ts()}] {self.tag} 🎧 Backchannel (fast path) from "
                    f'{speaker}: "{text[:30]}" — continuing'
                )
                return

            # Track partial_text / partial_speaker for existing logic
            self.partial_text = _fix_transcription(text)
            self.partial_speaker = speaker

            # Any transcribed word interrupts (Flux filters non-speech too)
            word_count = len(text.split())
            if word_count >= 1:
                # Phantom STT filter: "two", "seven", etc. — known
                # hallucinations from silence/breathing between Sam's TTS
                # chunks. Suppress these as no-ops to prevent false
                # mid-response interrupts.
                if _is_phantom_filler(text):
                    print(
                        f"[{ts()}] {self.tag} 🚫 Phantom filler "
                        f'ignored from {speaker}: "{text}"'
                    )
                    return
                self._partial_interrupted = True
                self._partial_interrupt_time = time.time()
                print(
                    f"[{ts()}] {self.tag} ⚡ FAST INTERRUPT via interim "
                    f'from {speaker}: "{text[:40]}" ({word_count} words) '
                    f"— stopping audio"
                )
                try:
                    await self._stop_all_audio()
                except Exception as e:
                    print(f"[{ts()}] {self.tag} ⚠️  Stop audio failed: {e}")
                self.interrupt_event.set()
                if self.current_task and not self.current_task.done():
                    self.current_task.cancel()
                self.speaking = False
                self.audio_playing = False
                self.vad.end_turn()

    def _build_addressee_context(self) -> ContextBundle:
        """Called by AddresseeDecider to snapshot current conversation context.

        Returns participants, Sam's last response, and recent exchanges
        for the Groq LLM addressee-decision prompt.
        """
        # Current attendees (from Recall.ai participant events)
        participants = sorted(self._attendees) if self._attendees else []
        if "Sam" not in participants:
            participants_for_prompt = participants + ["Sam (you)"]
        else:
            participants_for_prompt = participants

        # Recent conversation — pull from RAG's entry list (speaker-tagged)
        history: list[str] = []
        try:
            entries = self.agent.rag._entries[-12:]  # last 12 entries
            for e in entries:
                speaker = e.get("speaker", "?")
                text = e.get("text", "")
                if text:
                    history.append(f"{speaker}: {text}")
        except Exception:
            pass

        return ContextBundle(
            participants=participants_for_prompt,
            sam_last_response=self._sam_last_response,
            conversation_history=history,
        )

    async def _handle_addressee_decision(self, decision: Decision) -> None:
        """AddresseeDecider returned a decision — route to existing pipeline.

        Option X: feeds the chosen text into self.buffer and triggers
        _schedule_eot_check, so Trigger.py still makes the final YES/NO call.
        """
        if decision.type == "none":
            # Nobody addressed Sam — stay silent, don't trigger pipeline
            return

        if self.speaking:
            # Already responding — the interrupt path handles this.
            # Once interrupted, a new turn-completion will re-trigger AddresseeDecider.
            return

        if not decision.text or not decision.speakers:
            return

        # Determine which speaker name to attribute to the buffer entry.
        # For respond_both, use a composite name so Trigger.py / Agent see
        # it as a multi-addressee input.
        if decision.type == "respond_both":
            speaker = " & ".join(decision.speakers)
        else:
            speaker = decision.speakers[0]

        # Push the text into the existing pipeline (Option X):
        # buffer → _schedule_eot_check → Trigger.py → response
        t0 = time.time()
        self.buffer.append((speaker, decision.text, t0))
        print(
            f"[{ts()}] {self.tag} ➡️  Addressee pipeline: {speaker} "
            f"(type={decision.type})"
        )

        # ── Week 4 Phase 1: Observer-mode DialogueManager ──────────────────
        # Feed the turn to DialogueManager IN PARALLEL with Trigger pipeline.
        # DialogueManager runs NLU + Policy, logs decisions, persists state.
        # Fire-and-forget: errors are logged but never block the main pipeline.
        if self._dialogue_manager is not None:
            asyncio.create_task(
                self._run_dialogue_manager_observer(decision.text, speaker)
            )

        # ── Stage 2.6: query rewriter (parallel with EOT/addressee) ───────
        # Fire-and-forget. _unified_research_v2 awaits the result later.
        # Latest decision wins — cancel any in-flight prior rewrite.
        try:
            if self._last_rewriter_task and not self._last_rewriter_task.done():
                self._last_rewriter_task.cancel()
            convo_lines = list(self.convo_history)[-5:] if self.convo_history else []
            convo_str = (
                "\n".join(convo_lines) if convo_lines else "(start of conversation)"
            )
            self._last_rewriter_task = asyncio.create_task(
                self.agent.rewrite_query(decision.text, convo_str)
            )
            self._last_rewritten_query = None  # cleared until task resolves
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  Rewriter task spawn failed: {e}")
            self._last_rewriter_task = None

        self._schedule_eot_check(speaker)

    async def _speak_recap(self) -> None:
        """Phase 6 step 2: generate + speak end-of-meeting recap.

        Pulls state snapshot from DialogueManager, formats a compact data
        block (commitments, topics, open questions), runs one LLM call for
        a natural 30-second wrap-up, and speaks it via Speaker. Finally
        marks recap_delivered=True in state to prevent double-delivery.

        Safe to call from:
          - Observer (verbal end-of-meeting signal)
          - /stop endpoint (button press)
        Idempotent: respects recap_delivered flag via caller gating.
        """
        try:
            await asyncio.sleep(0.3)  # let any cancel settle
            if self.speaking or self.audio_playing:
                print(
                    f"[{ts()}] {self.tag} 🎮 [DRIVER] recap skipped — already speaking"
                )
                return

            dm = getattr(self, "_dialogue_manager", None)
            if dm is None:
                print(f"[{ts()}] {self.tag} ⚠️  recap skipped — no DM")
                return

            try:
                snap = dm.get_state_snapshot()
            except Exception as e:
                print(f"[{ts()}] {self.tag} ⚠️  recap snapshot failed: {e}")
                return

            if "error" in snap:
                print(f"[{ts()}] {self.tag} ⚠️  recap skipped — state error")
                return

            if snap.get("recap_delivered", False):
                print(f"[{ts()}] {self.tag} 🎮 [DRIVER] recap already delivered — skip")
                return

            # Format data block for the LLM
            commits = snap.get("commitments_open") or []
            topics_cov = snap.get("topics_resolved") or []
            topics_def = snap.get("topics_deferred") or []
            open_qs = snap.get("open_questions") or []
            participants = snap.get("participants") or []

            lines = []
            sep = ", "
            if participants:
                lines.append(
                    f"Participants: {sep.join(str(p) for p in participants[:5])}"
                )
            if commits:
                lines.append("Commitments captured this meeting:")
                for c in commits[:5]:
                    if not isinstance(c, dict):
                        continue
                    owner = c.get("owner") or "Someone"
                    action = c.get("action") or "do something"
                    deadline = c.get("deadline")
                    ln = f"  - {owner} will {action}"
                    if deadline:
                        ln += f" by {deadline}"
                    lines.append(ln)
            if topics_cov:
                lines.append(
                    f"Topics covered: {sep.join(str(t) for t in topics_cov[:5])}"
                )
            if topics_def:
                lines.append(
                    f"Topics deferred: {sep.join(str(t) for t in topics_def[:3])}"
                )
            if open_qs:
                lines.append(f"Open questions: {sep.join(str(q) for q in open_qs[:3])}")

            if not lines:
                print(f"[{ts()}] {self.tag} 🎮 [DRIVER] recap skipped — empty state")
                return

            data_block = "\n".join(lines)

            system = (
                "You are Sam, a senior PM at AnavClouds Software Solutions, on a live "
                "voice call that is wrapping up. Speak a warm, brief wrap-up in 4-6 "
                "sentences (~30 seconds spoken). Rules:\n"
                '1. Start directly — no "let me summarize" preamble\n'
                "2. Mention each commitment naturally, by name. Format example: "
                '"<NAME>, you are <ACTION> by <DEADLINE>" '
                '(not "<NAME> committed to <ACTION>"). '
                "<NAME> is a placeholder — replace with the actual owner from MEETING DATA below. "
                "Do NOT keep the angle brackets in your output.\n"
                "3. Mention what was deferred if anything\n"
                "4. Flag open questions for next time if any\n"
                '5. End with a warm sign-off ("great session, catch you later")\n'
                '6. Say ticket keys naturally: "SCRUM-244" not "SCRUM dash 244"\n'
                "7. Pick 2-3 most important items — do not list everything\n"
                "8. CRITICAL: only use names that appear in the Participants list or "
                "Commitments captured below. NEVER invent a name. If a commitment has "
                'no clear owner, say "the team" or "we" instead. Names that are not '
                "in MEETING DATA must not appear in your output.\n\n"
                f"MEETING DATA:\n{data_block}"
            )

            try:
                text = await asyncio.wait_for(
                    self.agent._llm_call(
                        "Please give the end-of-meeting recap now.",
                        system,
                        max_tokens=250,
                    ),
                    timeout=15.0,
                )
            except asyncio.TimeoutError:
                print(f"[{ts()}] {self.tag} ⚠️  recap LLM timeout (15s)")
                return
            except Exception as e:
                print(f"[{ts()}] {self.tag} ⚠️  recap LLM failed: {e}")
                return

            if not text or not text.strip():
                print(f"[{ts()}] {self.tag} ⚠️  recap LLM returned empty")
                return

            text = text.strip()
            print(
                f"[{ts()}] {self.tag} 🎮 [DRIVER] recap "
                f"({len(text)} chars): {text[:80]}..."
            )
            self._log_sam(text)
            self.speaking = True
            try:
                await self._speak(text, "recap", self.generation)
            finally:
                self.speaking = False
                self.audio_playing = False

            # Mark delivered so a later /stop or second verbal trigger doesn't re-deliver
            try:
                dm.mark_recap_delivered()
            except Exception as e:
                print(f"[{ts()}] {self.tag} ⚠️  mark_recap_delivered failed: {e}")

        except asyncio.CancelledError:
            raise
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  recap failed (non-fatal): {e}")

    # Stage 2.10 Checkpoint 1: skip journal on live-fetch policy
    def _policy_demanded_live_fetch(self) -> tuple[bool, str]:
        """Return (True, reason) if the most recent Policy decision was
        respond_with_research with a freshness hint, indicating fresh data
        is required. Used by both smart brain and quick brain to skip the
        journal lookup and go straight to research.

        Read order:
          1. self._dialogue_manager.get_last_decision() — the structured decision
          2. Match against known live-fetch reasoning strings from dialogue.py:
             - "live fetch needed"
             - "freshness hint"
             - "not cached"

        Kill switch: POLICY_OVERRIDE_JOURNAL=0 → always returns (False, "")
        so the journal lookup proceeds regardless of policy.
        """
        import os as _os

        if _os.environ.get("POLICY_OVERRIDE_JOURNAL", "1").strip() == "0":
            return (False, "kill switch")

        try:
            if self._dialogue_manager is None:
                return (False, "no DM")
            decision = self._dialogue_manager.get_last_decision()
            if decision is None:
                return (False, "no decision")

            action = getattr(decision, "action", None)
            action_str = action.value if hasattr(action, "value") else str(action)
            reasoning = (getattr(decision, "reasoning", "") or "").lower()

            # Live-fetch signals from dialogue.py Policy reasoning strings
            live_fetch_signals = [
                "live fetch needed",
                "freshness hint",
                "not cached",
                "fresh fetch",
                "needs fresh",
            ]

            if action_str == "respond_with_research":
                for signal in live_fetch_signals:
                    if signal in reasoning:
                        return (True, f"Policy: {signal}")
                # respond_with_research without explicit live-fetch hint
                # is still a research path — caller can choose to skip
                # journal or not. We return False here to let the journal
                # try, since the reasoning string didn't demand fresh data.
            return (False, f"action={action_str}")
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  Policy check error: {type(e).__name__}: {e}")
            return (False, "error")

    # Stage 2.10 Checkpoint 3: stall-phrase detection
    @staticmethod
    def _is_stall_response(text: str) -> tuple[bool, str]:
        """Detect when an LLM response is a stalling placeholder rather than
        a real answer. Returns (True, matched_phrase) or (False, "").

        Stall phrases are things humans say when they don't know but want to
        be polite — "let me check", "give me a sec", "I'll get back to you".
        For Sam, these are non-answers that need to fall through to real
        research.

        Kill switch: STALL_DETECTION_ENABLED=0 → always returns (False, "")
        """
        import os as _os
        import re as _re

        if _os.environ.get("STALL_DETECTION_ENABLED", "1").strip() == "0":
            return (False, "")
        if not text or not text.strip():
            return (False, "")

        # Check the first ~200 chars — stalls are always at the beginning
        head = text.strip()[:200].lower()

        # Phrases that indicate Sam is promising future action instead of answering
        stall_patterns = [
            r"let me (?:check|look|pull|grab|fetch|see|review|verify)",
            r"i(?:'ll| will) (?:check|look|pull|grab|fetch|get back|verify|review)",
            r"give me (?:a|one|just a) (?:moment|sec|second|minute)",
            r"hold on (?:while|a sec|a moment)",
            r"bear with me",
            r"one (?:moment|sec|second) (?:while|please)",
            r"i need to (?:check|look|verify|pull|fetch)",
            r"let me (?:just )?(?:take a |have a )?(?:quick )?(?:look|peek)",
        ]

        for pattern in stall_patterns:
            m = _re.search(pattern, head)
            if m:
                return (True, m.group(0))

        return (False, "")

    async def _fast_pm_response(self, user_text: str) -> None:
        """Router skip: general fast-path for high-confidence respond_direct.

        Used when Policy decided respond_direct but the utterance does not
        reference cached tickets (e.g. clarification requests, acknowledgments,
        small talk, statement responses). Inlines meeting context (current
        topic, recent commitments, scope) so Sam can reply naturally without
        going through Router + research.

        Latency: ~1-2s (one LLM call + TTS first chunk) vs. 3-6s full path.
        """
        try:
            await asyncio.sleep(0.2)  # let cancel settle
            if self.speaking or self.audio_playing:
                print(
                    f"[{ts()}] {self.tag} 🎮 [DRIVER] fast-pm skipped "
                    f"— already speaking"
                )
                return

            # Gather meeting context for the LLM
            state_parts = []
            try:
                snap = self._dialogue_manager.get_state_snapshot()
                if "error" not in snap:
                    # Current agenda topic
                    agenda = snap.get("agenda") or []
                    topic_idx = snap.get("current_topic_index", -1)
                    if agenda and 0 <= topic_idx < len(agenda):
                        cur = agenda[topic_idx]
                        title = cur.get("title", "") if isinstance(cur, dict) else ""
                        if title:
                            state_parts.append(f"Current topic: {title}")
                    # Recent open commitments (brief)
                    commits = snap.get("commitments_open") or []
                    if commits:
                        items = []
                        for c in commits[:2]:
                            if isinstance(c, dict):
                                items.append(
                                    f"{c.get('owner', '?')} will {c.get('action', '?')}"
                                )
                        if items:
                            state_parts.append(
                                "Recent commitments: " + "; ".join(items)
                            )
                    # Scope (brief)
                    scope_in = snap.get("scope_in") or []
                    if scope_in:
                        state_parts.append(
                            f"In scope today: {', '.join(str(s) for s in scope_in[:4])}"
                        )
            except Exception:
                pass

            context_block = "\n".join(state_parts) if state_parts else ""

            # Participant guard — fixes "Tom"/"Mike"/etc. hallucinations.
            # _build_client_profile_block_for_prompt() lists the actual people
            # on the call. Without this block, the LLM invents generic names
            # when the prompt says "use their name."
            client_profile_block = self._build_client_profile_block_for_prompt()

            # ─── Stage 2.8 + 2.10: quick brain journal lookup ─────────────
            # Stage 2.10 Checkpoint 1: skip journal entirely if Policy demanded
            # live fetch — quick brain can't fetch, but at least we won't ship
            # a stalling answer from a stale entry.
            import os as _os_qb

            prior_research_block = ""
            qb_live_fetch, qb_reason = self._policy_demanded_live_fetch()
            if qb_live_fetch:
                print(
                    f"[{ts()}] {self.tag} 📔 Quick-brain skipping journal — {qb_reason}"
                )
            elif _os_qb.environ.get("QUICK_BRAIN_JOURNAL_ENABLED", "1").strip() != "0":
                try:
                    journal = getattr(self.agent, "journal", None)
                    if journal is not None and journal.size > 0:
                        # Prefer the rewritten query (entity-resolved) if the
                        # rewriter task already finished. Otherwise use raw text.
                        search_query = user_text
                        try:
                            if (
                                self._last_rewriter_task is not None
                                and self._last_rewriter_task.done()
                                and not self._last_rewriter_task.cancelled()
                            ):
                                rq = self._last_rewriter_task.result()
                                if rq and isinstance(rq, str) and rq.strip():
                                    search_query = rq.strip()
                        except Exception:
                            pass

                        # Stage 2.10 Checkpoint 2: stricter journal hits
                        try:
                            qb_strict_thresh = float(
                                _os_qb.environ.get("JOURNAL_MIN_SCORE", "0.7")
                            )
                        except ValueError:
                            qb_strict_thresh = 0.7
                        qb_peek_thresh = 0.5

                        matches = await journal.search(
                            search_query, top_k=1, min_score=qb_peek_thresh
                        )
                        if matches:
                            score, entry = matches[0]
                            n_tickets = len(entry.get("jira_tickets") or [])
                            n_web = len(entry.get("web_results") or [])
                            has_data = n_tickets > 0 or n_web > 0

                            # Accept hit only if score-strict OR has-data
                            if score < qb_strict_thresh and not has_data:
                                print(
                                    f"[{ts()}] {self.tag} 📔 Quick-brain journal "
                                    f"weak hit (score={score:.3f}, no data) — "
                                    f"treating as miss"
                                )
                                matches = []  # downgrade to miss

                        if matches:
                            score, entry = matches[0]
                            n_tickets = len(entry.get("jira_tickets") or [])
                            n_web = len(entry.get("web_results") or [])
                            print(
                                f"[{ts()}] {self.tag} 📔 Quick-brain journal HIT: "
                                f"score={score:.3f}, data=(t={n_tickets},w={n_web}), "
                                f"q='{entry.get('question', '')[:60]}'"
                            )

                            # Build PRIOR RESEARCH block
                            cached_synth = (entry.get("synthesis_output") or "").strip()
                            tickets = entry.get("jira_tickets") or []
                            web_results = entry.get("web_results") or []

                            block_lines = []
                            if cached_synth:
                                block_lines.append(
                                    f'What you said earlier in this call: "{cached_synth[:600]}"'
                                )
                            if tickets:
                                tlines = []
                                for t in tickets[:4]:
                                    key = t.get("key", "?")
                                    summary = (t.get("summary") or "").strip()[:80]
                                    status = t.get("status") or "?"
                                    tlines.append(f"  - {key} [{status}]: {summary}")
                                if tlines:
                                    block_lines.append(
                                        "Tickets discussed:\n" + "\n".join(tlines)
                                    )
                            if web_results:
                                wlines = []
                                for r in web_results[:2]:
                                    title = (r.get("title") or "").strip()[:80]
                                    content = (r.get("content") or "").strip()[:200]
                                    if content:
                                        wlines.append(f"  - {title}: {content}")
                                if wlines:
                                    block_lines.append(
                                        "Web research from earlier:\n"
                                        + "\n".join(wlines)
                                    )

                            if block_lines:
                                prior_research_block = (
                                    "\n\nPRIOR RESEARCH ON THIS TOPIC "
                                    "(use this to answer the user's follow-up "
                                    "naturally — they're asking about something "
                                    "you already covered):\n" + "\n\n".join(block_lines)
                                )
                        else:
                            print(f"[{ts()}] {self.tag} 📔 Quick-brain journal MISS")
                except Exception as e:
                    print(
                        f"[{ts()}] {self.tag} ⚠️  Quick-brain journal lookup failed "
                        f"(non-fatal): {type(e).__name__}: {e}"
                    )

            system = (
                "You are Sam, a senior PM at AnavClouds Software Solutions, on a "
                "live voice call. Respond to what the user said in 1-2 sentences. "
                "Rules:\n"
                "- Natural and warm. Use contractions.\n"
                "- Address the user by name ONLY if their name appears in the "
                "WHO IS ON THIS CALL section below. Do NOT invent names. Do NOT "
                "use placeholder names like Tom, Mike, Sarah, John, Rachel. If "
                "no name is listed, just speak naturally without addressing "
                "anyone by name.\n"
                '- Do NOT use: "seriously", "honestly", "actually", "as I said", '
                '"obviously" — these sound condescending.\n'
                '- No "let me check" filler — you are answering directly.\n'
                "- If you do not know, say so briefly. Do not invent specifics.\n"
                "- Under 25 words total. You are on voice, keep it tight.\n"
                "\nWHO IS ON THIS CALL:\n" + client_profile_block
            )
            if context_block:
                system = system + "\n\nMEETING CONTEXT:\n" + context_block
            if prior_research_block:
                system = system + prior_research_block

            try:
                resp_text = await asyncio.wait_for(
                    self.agent._llm_call(user_text, system, max_tokens=120),
                    timeout=8.0,
                )
            except asyncio.TimeoutError:
                print(f"[{ts()}] {self.tag} ⚠️  fast-pm LLM timeout (8s)")
                return
            except Exception as e:
                print(f"[{ts()}] {self.tag} ⚠️  fast-pm LLM failed: {e}")
                return

            if not resp_text or not resp_text.strip():
                return

            resp_text = resp_text.strip()

            # Stage 2.10 Checkpoint 3: stall-phrase detection
            # If the LLM responded with "let me check on Jira" or similar
            # placeholder text, it's promising action instead of answering.
            # Quick brain can't fetch, so this would leave the user hanging.
            # Skip the response and let the trigger pipeline handle it via
            # the research path.
            is_stall, stall_phrase = self._is_stall_response(resp_text)
            if is_stall:
                print(
                    f"[{ts()}] {self.tag} 🛑 Quick-brain stall detected: "
                    f"'{stall_phrase}' — skipping response, "
                    f"trigger pipeline will handle research"
                )
                # Don't speak, don't log as Sam's response. The Trigger pipeline
                # is still active (not cancelled in this path), so it will
                # produce a real answer via _unified_research_v2.
                return

            print(
                f"[{ts()}] {self.tag} 🎮 [DRIVER] fast-pm response "
                f"({len(resp_text)} chars): {resp_text[:80]}..."
            )
            self._log_sam(resp_text)
            self.speaking = True
            try:
                await self._speak(resp_text, "fast_pm", self.generation)
            finally:
                self.speaking = False
                self.audio_playing = False

        except asyncio.CancelledError:
            raise
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  fast-pm failed (non-fatal): {e}")

    async def _fast_cached_response(
        self, user_text: str, ticket_keys: list, cached_tickets: dict
    ) -> None:
        """Phase 4B step 3: fast-path response using cached Jira tickets.

        Called when Policy decides respond_direct with use_ticket_cache=True
        and the utterance references cached tickets. Cancels Trigger, skips
        Router + research, runs a single LLM call with the cached ticket data
        inlined into a focused system prompt, and speaks the result.

        Typical latency: ~2s (one LLM call + TTS) vs. ~8-10s on full path.
        """
        try:
            await asyncio.sleep(0.3)  # let cancel cleanup settle
            if self.speaking or self.audio_playing:
                print(
                    f"[{ts()}] {self.tag} 🎮 [DRIVER] fast-path skipped "
                    f"— already speaking"
                )
                return

            # Build compact ticket context — only the keys we found in cache
            ticket_lines = []
            for key in ticket_keys[:3]:  # cap at 3 tickets for prompt size
                t = cached_tickets.get(key) or {}
                summary = str(t.get("summary", "")).strip()
                status = str(t.get("status", "")).strip() or "unknown"
                assignee = str(t.get("assignee", "")).strip() or "unassigned"
                if summary:
                    if len(summary) > 200:
                        summary = summary[:197] + "..."
                    ticket_lines.append(
                        f"- {key}: {summary} | status={status} | assignee={assignee}"
                    )
                else:
                    ticket_lines.append(
                        f"- {key}: (cached but no summary) status={status}"
                    )

            if not ticket_lines:
                print(
                    f"[{ts()}] {self.tag} ⚠️  [DRIVER] fast-path no ticket lines "
                    f"after lookup — aborting"
                )
                return

            # Participant guard — same fix as _fast_pm_response. Lists the
            # actual people on the call so Sam can't invent names.
            client_profile_block = self._build_client_profile_block_for_prompt()

            fast_system = (
                "You are Sam, a senior PM at AnavClouds Software Solutions, on a live "
                "voice call. Answer the user concisely in 1-3 sentences using ONLY the "
                'ticket data below. Speak conversationally, no "let me check" filler — '
                "you already have the data. Mention ticket keys naturally (e.g. "
                '"SCRUM-244"), not like "SCRUM dash 244".\n\n'
                "Address the user by name ONLY if their name appears in WHO IS ON THIS "
                "CALL below. Do NOT invent names. Do NOT use placeholder names like "
                "Tom, Mike, Sarah, John, Rachel. If no name is listed, just speak "
                "naturally without addressing anyone by name.\n\n"
                "WHO IS ON THIS CALL:\n" + client_profile_block + "\n\n"
                "CACHED TICKET DATA:\n" + "\n".join(ticket_lines)
            )

            # Use Agent's _llm_call for persona consistency + shared rotator
            try:
                text = await self.agent._llm_call(
                    user_text, fast_system, max_tokens=150
                )
            except Exception as e:
                print(f"[{ts()}] {self.tag} ⚠️  [DRIVER] fast-path LLM failed: {e}")
                return

            if not text or not text.strip():
                print(f"[{ts()}] {self.tag} ⚠️  [DRIVER] fast-path LLM returned empty")
                return

            text = text.strip()
            print(
                f"[{ts()}] {self.tag} 🎮 [DRIVER] fast-path response "
                f"({len(text)} chars): {text[:80]}..."
            )
            self._log_sam(text)
            self.speaking = True
            try:
                await self._speak(text, "fast_cached", self.generation)
            finally:
                self.speaking = False
                self.audio_playing = False
        except asyncio.CancelledError:
            # Someone cancelled us (new user turn arrived) — fine, just exit
            raise
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  [DRIVER] fast-path failed (non-fatal): {e}")

    async def _speak_redirect(self, text: str, label: str = "scope_redirect") -> None:
        """Phase 4A/4B: speak a canned line for any Policy-driven override.

        Runs as a background task from the DialogueManager observer when
        Policy takes a driving action (scope_redirect, transition_topic,
        ask_clarification). `label` is passed to the speaker for log
        classification. Short delay (300ms) lets the cancelled Agent task's
        cleanup settle before we start new audio.
        """
        try:
            await asyncio.sleep(0.3)
            # If something else is already speaking, skip (safer than overlap)
            if self.speaking or self.audio_playing:
                print(
                    f"[{ts()}] {self.tag} 🎮 [DRIVER] Skipping scope redirect "
                    f"— already speaking"
                )
                return
            self._log_sam(text)
            self.speaking = True
            try:
                await self._speak(text, label, self.generation)
            finally:
                self.speaking = False
                self.audio_playing = False
        except Exception as e:
            print(
                f"[{ts()}] {self.tag} ⚠️  Scope redirect speak failed (non-fatal): {e}"
            )

    async def _run_dialogue_manager_observer(self, text: str, speaker: str) -> None:
        """Fire-and-forget DialogueManager turn processing.

        Runs NLU + Policy, logs the decision, persists state. Any error is
        caught and logged — never propagated to the main response pipeline.

        Phase 4A: if USE_DIALOGUE_MANAGER >= 2, acts on the Policy decision:
          - stay_silent (conf>=0.7)   → cancels Sam's in-flight response
          - scope_redirect (conf>=0.7) → cancels + speaks a canned redirect
        Other actions: still handled by Trigger.py path.
        """
        if self._dialogue_manager is None:
            return
        try:
            await self._dialogue_manager.process_turn(text, speaker)
        except Exception as e:
            print(
                f"[{ts()}] {self.tag} ⚠️  DialogueManager observer error "
                f"(non-fatal): {e}"
            )
            return

        # Phase 4B step 1: use cached mode, log what we considered
        if self._dm_mode < 2:
            return  # observer-only; do not act on decisions

        try:
            decision = self._dialogue_manager.get_last_decision()
        except AttributeError as e:
            # Almost certainly: dialogue_manager.py was not patched with
            # get_last_decision(). Rerun apply_phase_4a.py or restore from backup.
            print(
                f"[{ts()}] {self.tag} ⚠️  [4B-DEBUG] get_last_decision "
                f"method missing on DialogueManager: {e}"
            )
            print(
                f"[{ts()}] {self.tag}        → dialogue_manager.py patch "
                f"did not fully land; rerun apply_phase_4a.py"
            )
            return
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  get_last_decision failed (non-fatal): {e}")
            return
        if decision is None:
            return

        # Normalize action (could be enum or string)
        action = decision.action
        action_str = action.value if hasattr(action, "value") else str(action)
        confidence = getattr(decision, "confidence", 1.0)

        # Phase 4B 1+2+3 + Phase 6 step 2: all action types we act on
        handled_actions = {
            "stay_silent",
            "scope_redirect",
            "transition_topic",
            "ask_clarification",
            "respond_direct",
            "deliver_recap",
        }
        if action_str not in handled_actions:
            print(
                f"[{ts()}] {self.tag} 🎮 [4B-DEBUG] eval action={action_str} "
                f"conf={confidence:.2f} → skip (not handled in 4A, "
                f"will be added in 4B step 2)"
            )
            return

        # Confidence gate — protects against NLU misclassifications
        if confidence < 0.7:
            print(
                f"[{ts()}] {self.tag} 🎮 [4B-DEBUG] eval action={action_str} "
                f"conf={confidence:.2f} → skip (conf<0.7)"
            )
            return
        # High-confidence action, will act
        print(
            f"[{ts()}] {self.tag} 🎮 [4B-DEBUG] eval action={action_str} "
            f"conf={confidence:.2f} → ACT"
        )

        # Action: stay_silent — cancel the in-flight response task
        if action_str == "stay_silent":
            task = self.current_task
            if task and not task.done():
                task.cancel()
                print(
                    f"[{ts()}] {self.tag} 🎮 [DRIVER] Policy stay_silent "
                    f"→ cancelled response (conf={confidence:.2f})"
                )
            else:
                # Policy arrived too late — Sam already finished responding.
                # Log so we can measure how often this happens.
                print(
                    f"[{ts()}] {self.tag} 🎮 [DRIVER] Policy stay_silent "
                    f"arrived too late — response already complete"
                )
            return

        # Action: scope_redirect — cancel + speak canned redirect
        if action_str == "scope_redirect":
            task = self.current_task
            if task and not task.done():
                task.cancel()
                print(
                    f"[{ts()}] {self.tag} 🎮 [DRIVER] Policy scope_redirect "
                    f"→ cancelled response (conf={confidence:.2f})"
                )
            else:
                # Sam already responded; the redirect will follow as a
                # second turn. Still useful — user hears the redirect.
                print(
                    f"[{ts()}] {self.tag} 🎮 [DRIVER] Policy scope_redirect "
                    f"(response already in progress — redirect follows)"
                )
            topic = getattr(decision, "scope_topic_raised", None) or ""
            topic = topic.strip()
            if topic and len(topic) <= 40:
                redirect_text = (
                    f"{topic[0].upper() + topic[1:]} is outside today's focus — "
                    f"want me to note it for next time?"
                )
            else:
                redirect_text = (
                    "That's outside today's focus — want me to note it for next time?"
                )
            # Fire redirect as a background task (short delay lets
            # cancellation settle before new audio begins)
            asyncio.create_task(self._speak_redirect(redirect_text))
            return

        # Phase 4B step 2: transition_topic — acknowledge + introduce new topic
        if action_str == "transition_topic":
            task = self.current_task
            if task and not task.done():
                task.cancel()
                print(
                    f"[{ts()}] {self.tag} 🎮 [DRIVER] Policy transition_topic "
                    f"→ cancelled response (conf={confidence:.2f})"
                )
            else:
                print(
                    f"[{ts()}] {self.tag} 🎮 [DRIVER] Policy transition_topic "
                    f"(response already in progress — transition follows)"
                )
            new_topic = getattr(decision, "transition_to", None) or ""
            new_topic = new_topic.strip() if isinstance(new_topic, str) else ""
            from_topic = getattr(decision, "transition_from", None) or ""
            print(
                f"[{ts()}] {self.tag} 🎮 [DRIVER] Topic transition: "
                f"{from_topic!r} → {new_topic!r}"
            )
            if new_topic:
                # Cap to a reasonable length for TTS
                topic_short = (
                    new_topic if len(new_topic) <= 80 else new_topic[:77] + "..."
                )
                transition_text = f"Got it, let's move on to {topic_short}."
            else:
                transition_text = "Okay, let's move on to the next topic."
            asyncio.create_task(
                self._speak_redirect(transition_text, "transition_topic")
            )
            return

        # Phase 4B step 2: ask_clarification — cancel + ask for specifics
        if action_str == "ask_clarification":
            task = self.current_task
            if task and not task.done():
                task.cancel()
                print(
                    f"[{ts()}] {self.tag} 🎮 [DRIVER] Policy ask_clarification "
                    f"→ cancelled response (conf={confidence:.2f})"
                )
            else:
                print(
                    f"[{ts()}] {self.tag} 🎮 [DRIVER] Policy ask_clarification "
                    f"(response already in progress — clarification follows)"
                )
            options = getattr(decision, "clarification_options", None) or []
            if isinstance(options, list) and options:
                # Clean + cap options
                clean = [str(o).strip() for o in options if o and str(o).strip()]
                clean = clean[:3]  # max 3 options for TTS
                if len(clean) >= 2:
                    joined = ", ".join(clean[:-1]) + f", or {clean[-1]}"
                    clarify_text = f"Could you clarify — do you mean {joined}?"
                elif len(clean) == 1:
                    clarify_text = f"Just to confirm, are you asking about {clean[0]}?"
                else:
                    clarify_text = "Sorry, could you say that again?"
            else:
                clarify_text = "Sorry, could you clarify what you meant?"
            asyncio.create_task(self._speak_redirect(clarify_text, "ask_clarification"))
            return

        # Router skip: fast-path for ALL high-confidence respond_direct.
        # Two variants, picked by available context:
        #   (a) Cached ticket referenced → _fast_cached_response (ticket data)
        #   (b) No cached ticket → _fast_pm_response (general meeting context)
        # Skips Router LLM (800-3800ms) + research path entirely.
        #
        # Ship 3 fix: ALWAYS probe for ticket keys regardless of the
        # `use_ticket_cache` flag. The flag was sometimes False even when
        # Policy explicitly logged "Ticket(s) all cached — use cache",
        # causing ticket questions to fall through to _fast_pm_response
        # which doesn't know about specific tickets and would hallucinate
        # wrong ticket data (e.g. answering about SCRUM-244 when asked
        # about SCRUM-200).
        if action_str == "respond_direct":
            if confidence < 0.85:
                return  # low conf — let Trigger handle (fallback)

            # Always probe for ticket keys in user text — ignore the
            # potentially-stale use_ticket_cache flag from policy.
            ticket_hits = []
            cached_tickets = {}
            try:
                import re as _re_local

                ticket_keys = _re_local.findall(r"\b([A-Z]+-\d+)\b", text.upper())
                if ticket_keys:
                    dm_state = self._dialogue_manager.get_state_snapshot()
                    cached_tickets = dm_state.get("pre_loaded_tickets") or {}
                    ticket_hits = [k for k in ticket_keys if k in cached_tickets]
                    if ticket_hits:
                        print(
                            f"[{ts()}] {self.tag} 🎯 Fast-path ticket probe: "
                            f"detected {ticket_keys}, cache hits: {ticket_hits}"
                        )
                    elif ticket_keys:
                        print(
                            f"[{ts()}] {self.tag} 🎯 Fast-path ticket probe: "
                            f"detected {ticket_keys} but none in cache "
                            f"— routing to research path instead"
                        )
                        # User asked about specific tickets that aren't cached.
                        # Don't invent answers via _fast_pm_response. Let the
                        # research path handle it (Door #1 enrichment will
                        # fetch them fresh from Jira).
                        return  # falls through to Trigger → research path
            except Exception as _e:
                print(f"[{ts()}] {self.tag} ⚠️  Fast-path ticket probe failed: {_e}")

            # Cancel Trigger regardless of variant
            task = self.current_task
            if task and not task.done():
                task.cancel()
            else:
                # No active Trigger to take over — do nothing
                return

            if ticket_hits:
                print(
                    f"[{ts()}] {self.tag} 🎮 [DRIVER] respond_direct "
                    f"cached-ticket fast-path (conf={confidence:.2f}, tickets={ticket_hits})"
                )
                asyncio.create_task(
                    self._fast_cached_response(text, ticket_hits, cached_tickets)
                )
            else:
                print(
                    f"[{ts()}] {self.tag} 🎮 [DRIVER] respond_direct "
                    f"general fast-path (conf={confidence:.2f})"
                )
                asyncio.create_task(self._fast_pm_response(text))
            return

        # Phase 6 step 2: deliver_recap — generate + speak end-of-meeting wrap-up
        if action_str == "deliver_recap":
            task = self.current_task
            if task and not task.done():
                task.cancel()
                print(
                    f"[{ts()}] {self.tag} 🎮 [DRIVER] Policy deliver_recap "
                    f"→ cancelled Trigger (conf={confidence:.2f})"
                )
            else:
                print(
                    f"[{ts()}] {self.tag} 🎮 [DRIVER] Policy deliver_recap "
                    f"(no active Trigger task) conf={confidence:.2f}"
                )
            asyncio.create_task(self._speak_recap())
            return

        # Other actions (respond_with_research, etc.) remain Trigger-driven.

    # ══════════════════════════════════════════════════════════════════════

    def _schedule_eot_check(self, speaker):
        if self.eot_task and not self.eot_task.done():
            self.eot_task.cancel()
        self.eot_task = asyncio.create_task(self._run_eot_check(speaker))

    async def _run_eot_check(self, speaker):
        try:
            result = self._get_buffer_text()
            if not result or self.speaking:
                return
            spk, full_text, t0 = result
            context = "\n".join(self.convo_history)

            # ── Fast path: direct address skips EOT classifier + straggler ──
            if self._is_direct_address(full_text):
                print(
                    f"[{ts()}] {self.tag} ⚡ Direct address — skipping EOT + straggler"
                )
                # No straggler wait at all
                # Direct-addressed questions still benefit from pre-fired filler
                # (most are research questions). Skip for short utterances.
                self._maybe_fire_pending_filler(full_text)
            else:
                # Normal path: run EOT classifier
                decision = await self.agent.check_end_of_turn(full_text, context)
                if decision == "RESPOND":
                    # Ship 4: Pre-fire dynamic filler IMMEDIATELY when EOT
                    # decides RESPOND. This gives Groq ~1.5-2s head start
                    # while NLU + Policy + Router run downstream. By the time
                    # we get to the router decision, the filler is usually
                    # already ready, so we get contextual fillers without
                    # waiting for them.
                    self._maybe_fire_pending_filler(full_text)
                    await asyncio.sleep(self.STRAGGLER_WAIT)  # 200ms
                else:
                    await asyncio.sleep(self.WAIT_TIMEOUT)

            if self.speaking or not self.buffer:
                return
            result = self._get_buffer_text()
            if not result:
                return
            spk, full_text, t0 = result
            self.buffer.clear()
            self.partial_text = ""
            self.vad.end_turn()
            self.last_flushed_text = full_text
            self._start_process(full_text, spk, t0)
        except asyncio.CancelledError:
            return

    def _get_buffer_text(self):
        if not self.buffer and not self.partial_text:
            return None
        if self.buffer:
            speaker = self.buffer[-1][0]
            t0 = self.buffer[0][2]
            full_text = " ".join(txt for _, txt, _ in self.buffer)
            if self.partial_text and self.partial_text not in full_text:
                full_text += " " + self.partial_text
        else:
            speaker = self.partial_speaker or "Unknown"
            t0 = time.time()
            full_text = self.partial_text
        return speaker, full_text, t0

    def _start_process(self, text, speaker, t0):
        if self._delayed_client_task and not self._delayed_client_task.done():
            self._delayed_client_task.cancel()

        self.generation += 1
        self.current_text = text
        self.current_speaker = speaker
        self.interrupt_event.clear()
        self.convo_history.append(f"{speaker}: {text}")

        # Compute adaptive delay
        target_delay = _get_adaptive_delay(text)
        total_delay = max(0.0, target_delay - 0.4)

        print(
            f'[{ts()}] {self.tag} ⏱️ Client response delay: {total_delay:.1f}s (target={target_delay:.1f}s, additional={total_delay:.1f}s) for text: "{text[:40]}"'
        )

        async def _run_client_process():
            try:
                await asyncio.sleep(total_delay)
                self.current_task = asyncio.create_task(
                    self._process(text, speaker, t0, self.generation)
                )
                await self.current_task
            except asyncio.CancelledError:
                print(
                    f"[{ts()}] {self.tag} ⏱️ Client response delay cancelled (user resumed speaking)"
                )

        self._delayed_client_task = asyncio.create_task(_run_client_process())

    # ── Audio helpers ─────────────────────────────────────────────────────────

    async def _stop_all_audio(self):
        """Stop audio in both streaming and fallback mode."""
        if self._streaming_mode:
            # Streaming mode: only clear AudioWorklet buffer via WebSocket
            # Do NOT call speaker.stop_audio() — the Recall.ai DELETE kills the output media pipeline
            try:
                await self.audio_ws.send_str(json.dumps({"type": "stop"}))
            except Exception:
                pass
        else:
            # Fallback mode: stop MP3 injection via Recall.ai API
            try:
                await self.speaker.stop_audio()
            except Exception:
                pass

    async def _stream_and_relay(self, text: str, my_gen: int) -> float:
        """Stream TTS via Cartesia WebSocket → relay PCM to audio page.
        Returns duration in seconds. Used in streaming mode."""
        total_bytes = 0
        t0 = time.time()
        try:
            async for pcm_chunk in self.speaker._stream_tts(text):
                if self.interrupt_event.is_set() or my_gen != self.generation:
                    return 0
                await self.audio_ws.send_bytes(pcm_chunk)
                total_bytes += len(pcm_chunk)
            # Send flush to let AudioWorklet know this utterance is done
            await self.audio_ws.send_str(json.dumps({"type": "flush"}))
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  Stream relay error: {e}")
            return 0

        duration = total_bytes / PCM_BYTES_PER_SEC
        self._current_audio_duration = duration
        print(
            f"[{ts()}] {self.tag} ⏱ Streamed {total_bytes} bytes ({duration:.1f}s) in {elapsed(t0)}"
        )
        return duration

    async def _wait_for_playback(self, duration_sec: float, my_gen: int) -> bool:
        """Wait for audio playback to finish, interruptible."""
        if duration_sec <= 0:
            return True
        self.audio_playing = True
        try:
            # Add 200ms for the AudioWorklet buffer delay
            await asyncio.wait_for(
                self.interrupt_event.wait(), timeout=duration_sec + 0.2
            )
            self.audio_playing = False
            return False  # interrupted
        except asyncio.TimeoutError:
            self.audio_playing = False
            return True  # completed

    async def _speak_streaming(self, text: str, my_gen: int) -> bool:
        """Stream TTS + wait for playback. Returns True if completed, False if interrupted."""
        duration = await self._stream_and_relay(text, my_gen)
        if duration <= 0:
            return False
        return await self._wait_for_playback(duration, my_gen)

    async def _speak_fallback(self, text: str, label: str, my_gen: int) -> bool:
        """Fallback: REST TTS + MP3 inject. Returns True if completed."""
        try:
            async with self.server._tts_semaphore:
                audio = await self.speaker._synthesise(text)
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  Fallback TTS error: {e}")
            return True

        if self.interrupt_event.is_set() or my_gen != self.generation:
            return False

        try:
            await self.speaker.stop_audio()
        except Exception:
            pass
        b64 = base64.b64encode(audio).decode("utf-8")
        await self.speaker._inject_into_meeting(b64)
        self.audio_playing = True

        play_dur = max(500, get_duration_ms(audio))
        try:
            await asyncio.wait_for(self.interrupt_event.wait(), timeout=play_dur / 1000)
            self.audio_playing = False
            return False
        except asyncio.TimeoutError:
            self.audio_playing = False
            return True

    async def _speak(self, text: str, label: str, my_gen: int) -> bool:
        """Speak text using best available method. Returns True if completed."""
        if self._streaming_mode:
            return await self._speak_streaming(text, my_gen)
        else:
            return await self._speak_fallback(text, label, my_gen)

    async def _stream_pipelined(
        self,
        queue: asyncio.Queue,
        my_gen: int,
        cancel_task=None,
        extra_duration: float = 0,
        relay_start_override: float = 0,
    ) -> tuple:
        """Read sentences from queue, relay PCM back-to-back (no gap), wait at end.
        extra_duration: audio already in ring buffer (e.g. filler) to account for in final wait.
        relay_start_override: when the first audio (filler) was relayed, for accurate wait calculation.
        Returns (all_sentences: list, interrupted: bool)."""
        all_sentences = []
        relay_start = relay_start_override if relay_start_override > 0 else time.time()
        total_duration = extra_duration  # Include filler audio already playing

        while True:
            if self.interrupt_event.is_set() or my_gen != self.generation:
                if cancel_task:
                    cancel_task.cancel()
                return all_sentences, True

            try:
                if not all_sentences and extra_duration > 0:
                    remaining_filler = extra_duration - (time.time() - relay_start)
                    if remaining_filler > 0:
                        try:
                            item = await asyncio.wait_for(
                                queue.get(), timeout=remaining_filler
                            )
                        except asyncio.TimeoutError:
                            print(
                                f"[{ts()}] {self.tag} 🌉 Injecting 'Hmm...' bridge (first sentence not ready before filler end)"
                            )
                            bridge_duration = await self._stream_and_relay(
                                "Hmm...", my_gen
                            )
                            if bridge_duration <= 0 or self.interrupt_event.is_set():
                                if cancel_task:
                                    cancel_task.cancel()
                                return all_sentences, True
                            total_duration += bridge_duration
                            item = await asyncio.wait_for(queue.get(), timeout=30.0)
                    else:
                        if queue.empty():
                            print(
                                f"[{ts()}] {self.tag} 🌉 Injecting 'Hmm...' bridge (filler already ended and queue empty)"
                            )
                            bridge_duration = await self._stream_and_relay(
                                "Hmm...", my_gen
                            )
                            if bridge_duration <= 0 or self.interrupt_event.is_set():
                                if cancel_task:
                                    cancel_task.cancel()
                                return all_sentences, True
                            total_duration += bridge_duration
                        item = await asyncio.wait_for(queue.get(), timeout=30.0)
                else:
                    item = await asyncio.wait_for(queue.get(), timeout=30.0)
            except asyncio.TimeoutError:
                break
            if item is None:
                break
            if item == "__FLUSH__":
                continue
            # F8: strip robotic opener from first sentence only
            if not all_sentences:
                item = self._strip_filler_opener(item)
            all_sentences.append(item)

            # Relay PCM to AudioWorklet — NO wait for playback (pipelined)
            duration = await self._stream_and_relay(item, my_gen)
            if duration <= 0:
                return all_sentences, True  # interrupted during relay
            total_duration += duration

        # Wait for remaining playback after all sentences relayed
        if total_duration > 0:
            elapsed_since_start = time.time() - relay_start
            remaining = (
                total_duration - elapsed_since_start + 0.2
            )  # 200ms AudioWorklet buffer
            if remaining > 0:
                self.audio_playing = True
                try:
                    await asyncio.wait_for(
                        self.interrupt_event.wait(), timeout=remaining
                    )
                    self.audio_playing = False
                    return all_sentences, True  # interrupted during final playback
                except asyncio.TimeoutError:
                    self.audio_playing = False

        return all_sentences, False  # completed normally

    def _check_name_change(self, text: str) -> str | None:
        """Return extracted preferred name if user is renaming themselves."""
        m = _NAME_CHANGE_RE.search(text or "")
        if not m:
            return None
        return _extract_first_name(m.group(1))

    async def _maybe_handle_name_change(self, text: str) -> bool:
        """Detect name change, confirm, and return True if handled."""
        new_name = self._check_name_change(text)
        if not new_name:
            return False
        await self._handle_name_change(new_name)
        return True

    async def _handle_name_change(self, new_name: str) -> None:
        first = _extract_first_name(new_name)
        if first.lower() in _CASUAL_NAME_WORDS:
            msg = "I'll need your actual first name — what should I call you?"
            print(f"[{ts()}] {self.tag} 📝 Name change rejected (casual): {first}")
            self._log_sam(msg)
            self.speaking = True
            try:
                await self._speak(msg, "name-change-reject", self.generation)
            finally:
                self.speaking = False
                self.audio_playing = False
            return

        previous = self._active_name
        self._active_name = first
        if self.standup_flow and not self.standup_flow.is_done:
            self.standup_flow.developer = first

        msg = random.choice(_NAME_CHANGE_CONFIRMATIONS).format(name=first)
        print(
            f"[{ts()}] {self.tag} 📝 Name change: {previous or '?'} → {first}"
        )
        self._log_sam(msg)
        try:
            from datetime import datetime as _dt

            self._utterance_log.append(
                {
                    "timestamp": _dt.utcnow().strftime("%Y-%m-%dT%H:%M:%SZ"),
                    "event": "name_change",
                    "previous_name": previous,
                    "session_name": first,
                    "changed_at": _dt.utcnow().strftime("%Y-%m-%dT%H:%M:%SZ"),
                }
            )
        except Exception:
            pass

        self.speaking = True
        try:
            await self._speak(msg, "name-change", self.generation)
        finally:
            self.speaking = False
            self.audio_playing = False

    def _build_greeting(self, name: str) -> str:
        """Phase 3.5: greeting that announces agenda if setup was provided.

        Falls back to the original greeting if no agenda is configured.
        """
        first = self._active_name or _extract_first_name(name)
        if not first or first == "Unknown":
            first = name.split()[0] if name and name not in ("", "Unknown") else "there"
        slot = _greeting_time_slot()
        openers = _CLIENT_GREETING_OPENERS[slot]
        self._last_greeting_variation = (
            self._last_greeting_variation + 1
        ) % len(openers)
        base = openers[self._last_greeting_variation].format(first=first)
        setup = self._meeting_setup or {}
        raw_agenda = setup.get("agenda") or []
        titles: list[str] = []
        for item in raw_agenda:
            if isinstance(item, dict):
                t = (item.get("title") or "").strip()
            elif isinstance(item, str):
                t = item.strip()
            else:
                t = ""
            if t:
                titles.append(t)
        if not titles:
            return base
        n = len(titles)
        if n == 1:
            return (
                f"{base} One thing on the agenda today — "
                f"{titles[0]}. Ready when you are."
            )
        if n == 2:
            return (
                f"{base} Two things today — "
                f"{titles[0]} and {titles[1]}. "
                f"Want to start with the first?"
            )
        # 3+ topics: Patch B1 — mention only the first topic to cut
        # greeting length from ~17s to ~6s. Remaining topics come up
        # naturally as the meeting flows.
        return (
            f"{base} {n} topics today — starting with {titles[0]}. "
            f"Ready when you are."
        )

    async def _greet(self, name, t0):
        await asyncio.sleep(1.0)
        if self.speaking:
            return
        greeting = self._build_greeting(name)
        self._log_sam(greeting)
        self.speaking = True
        try:
            await self._speak(greeting, "greeting", self.generation)
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  Greet error: {e}")
        finally:
            self.speaking = False
            self.audio_playing = False

        # Start silence reprompt timer after greeting (client mode only).
        # If user stays silent 20s, Sam will ask "What would you like to discuss today?"
        if self.mode != "standup" and not self._user_left:
            self._last_sam_intent = "greeting"
            self._start_client_silence_timer()

    async def _start_standup(self, developer_name: str):
        """Initialize and start the standup flow for a developer."""
        await asyncio.sleep(1.0)
        if self.speaking:
            return
        dev_first = self._active_name or _extract_first_name(developer_name)
        if not self._active_name:
            self._active_name = dev_first
        print(f"[{ts()}] {self.tag} 📋 Starting standup for {dev_first}")

        # Create standup flow with speaker function
        async def speak_fn(text, label, gen):
            self._log_sam(text)
            if (
                self._streaming_mode
                and getattr(self, "_standup_filler_duration", 0.0) > 0.0
            ):
                duration_filler = self._standup_filler_duration
                relay_start = self._standup_filler_relay_start
                self._standup_filler_duration = 0.0
                self._standup_filler_relay_start = 0.0

                print(f"[{ts()}] {self.tag} 🚀 Pipelining standup response with filler")
                dur_real = await self._stream_and_relay(text, gen)
                if dur_real <= 0 or self.interrupt_event.is_set():
                    return False

                total_duration = duration_filler + dur_real
                elapsed_since_start = time.time() - relay_start
                remaining = total_duration - elapsed_since_start + 0.2
                if remaining > 0:
                    self.audio_playing = True
                    try:
                        await asyncio.wait_for(
                            self.interrupt_event.wait(), timeout=remaining
                        )
                        self.audio_playing = False
                        return False
                    except asyncio.TimeoutError:
                        self.audio_playing = False
                return True
            else:
                return await self._speak(text, label, gen)

        self.standup_flow = StandupFlow(
            developer_name=dev_first,
            agent=self.agent,
            speaker_fn=speak_fn,
            jira_client=self.jira if self.jira.enabled else None,
            jira_context=self._jira_context,
            azure_extractor=self.azure_extractor
            if self.azure_extractor.enabled
            else None,
        )

        # Connect buffer check so re-prompt can detect if user started speaking
        self.standup_flow._check_buffer_fn = lambda: bool(
            self._standup_buffer or self.partial_text
        )

        self.generation += 1
        self.speaking = True
        try:
            await self.standup_flow.start(self.generation)
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  Standup start error: {e}")
        finally:
            self.speaking = False
            self.audio_playing = False

        # Start Flux STT if Deepgram key available
        if DEEPGRAM_API_KEY and not self._stt_task:
            await self._start_flux_stt(dev_first)

    # ── Flux STT (own Deepgram for standup) ──────────────────────────────────

    async def _start_flux_stt(self, developer_name: str):
        """Start Flux STT connection for standup. Receives audio_separate_raw for this developer.

        Flux params tuned for standup Q&A:
          eot_threshold=0.65      — fires EndOfTurn earlier on marginal-confidence turns
          eager_eot_threshold=0.35 — enables EagerEndOfTurn for speculative Groq pre-compute
          eot_timeout_ms=1500     — forces EndOfTurn after 1.5s silence (standup = short answers)
        """
        from stt import stream_deepgram

        self._stt_queue = asyncio.Queue()
        self._flux_enabled = True
        self._flux_developer = developer_name
        self._speculative_task = None
        self._speculative_text = ""
        self._flux_latest_sentiment = None
        print(f"[{ts()}] {self.tag} 🎯 Starting Flux STT for {developer_name}")

        async def _flux_transcript_callback(
            text, is_final, sentiment=None, sentiment_score=None
        ):
            """Called by Flux for every transcript update."""
            if not text or not text.strip():
                return
            if sentiment:
                self._flux_latest_sentiment = sentiment
            if sentiment_score is not None:
                self._last_sentiment_score = sentiment_score
            if is_final:
                # Cancel any pending backchannel — user finished speaking
                self._cancel_backchannel_task()
                if sentiment_score is not None:
                    self._update_empathy_state(sentiment_score)
                # EndOfTurn — Flux confirmed user is done speaking
                project_key = (
                    self.jira.project if self.jira and self.jira.enabled else "SCRUM"
                )
                clean_text = _convert_spoken_ticket_refs(text.strip(), project_key)
                print(
                    f'[{ts()}] {self.tag} 🎯 Flux FINAL: "{clean_text[:60]}" | Sentiment: {sentiment}'
                )
                # Clear Nova-3's stale partial_text so silence-timer skip check is accurate
                self.partial_text = ""
                self.partial_speaker = ""
                # Clear Flux interim — turn processed, speech_off debounce won't re-finalize
                self._flux_last_interim_text = ""
                # Cancel any pending speech_off debounce — Flux already delivered the FINAL
                if self._flux_speech_off_task and not self._flux_speech_off_task.done():
                    self._flux_speech_off_task.cancel()
                self._standup_buffer.append(clean_text)
                # Log per-utterance sentiment / emotion / intent insight
                developer = getattr(self, "_flux_developer", "Unknown")
                delay = _get_adaptive_delay(clean_text)
                self._log_utterance_insight(
                    speaker=developer,
                    text=clean_text,
                    sentiment=sentiment,
                    sentiment_score=sentiment_score,
                    filler_triggered=False,
                    pause_detected=delay > 0.4,
                    adaptive_endpointing_used="slow"
                    if delay >= 1.2
                    else ("medium" if delay >= 0.7 else "fast"),
                    active_listening_token_played=self._backchannel_last_token,
                )
                self._backchannel_last_token = None
                # Process — if speculative Groq result is cached, handle() uses it
                self._schedule_delayed_standup_processing(
                    self._flux_developer, clean_text
                )

            else:
                # Interim update — user still speaking
                print(f'[{ts()}] {self.tag} 🎯 Flux interim: "{text.strip()[:60]}"')
                if self._delayed_standup_task and not self._delayed_standup_task.done():
                    self._delayed_standup_task.cancel()
                # Track latest interim so silence monitor can decide whether to Finalize
                self._flux_last_interim_text = text.strip()

                # F8: pause-detection via debounce — cancel+restart on EVERY interim.
                # The 400ms sleep in _maybe_play_backchannel is the silence window:
                # continuous speech keeps restarting the timer so it never completes;
                # a real 400ms pause lets the sleep expire and plays the token.
                _bc_words = len(text.strip().split())
                _sf = self.standup_flow
                _early = (
                    _sf is not None
                    and hasattr(_sf, "state")
                    and _sf.state.name in ("GREETING", "WARM_UP")
                )
                if _bc_words > 5 and not self.speaking and not _early:
                    self._cancel_backchannel_task()
                    self._backchannel_task = asyncio.create_task(
                        self._maybe_play_backchannel(
                            self.generation,
                            speaker=getattr(self, "_flux_developer", ""),
                            word_count=_bc_words,
                        )
                    )

                # Fast interrupt: if re-prompt is playing and user has spoken 2+ words,
                # stop the re-prompt immediately (user is finally answering)
                if (
                    self.standup_flow
                    and getattr(self.standup_flow, "_playing_reprompt", False)
                    and self.speaking
                    and self.audio_playing
                    and not self._partial_interrupted
                    and len(text.strip().split()) >= 2
                ):
                    self._partial_interrupted = True
                    self._partial_interrupt_time = time.time()
                    print(
                        f'[{ts()}] {self.tag} ⚡ Re-prompt interrupted via Flux interim: "{text.strip()[:40]}" — stopping audio'
                    )
                    try:
                        await self._stop_all_audio()
                    except Exception as e:
                        print(
                            f"[{ts()}] {self.tag} ⚠️  Stop audio failed (non-fatal): {e}"
                        )
                    self.interrupt_event.set()
                    if self.current_task and not self.current_task.done():
                        self.current_task.cancel()
                    self.speaking = False
                    self.audio_playing = False

        async def _flux_eager_eot_callback(transcript, confidence):
            """EagerEndOfTurn — start speculative Groq classification.

            Flux fires this when confidence first crosses eager_eot_threshold.
            The transcript here will match the final EndOfTurn transcript (Flux guarantee).
            We pre-compute the Groq classify+ack so it's ready when EndOfTurn confirms.
            """
            if not self.standup_flow or self.standup_flow.is_done:
                return
            project_key = (
                self.jira.project if self.jira and self.jira.enabled else "SCRUM"
            )
            clean = _convert_spoken_ticket_refs(transcript.strip(), project_key)
            self._speculative_text = clean
            # Cancel any previous speculative task
            if self._speculative_task and not self._speculative_task.done():
                self._speculative_task.cancel()
            # Fire-and-forget: pre-compute Groq classification
            self._speculative_task = asyncio.create_task(
                self._run_speculative_classify(
                    clean, getattr(self, "_flux_latest_sentiment", None)
                )
            )
            print(
                f"[{ts()}] {self.tag} ⚡ EagerEOT (conf={confidence:.2f}) — speculative Groq started"
            )

        async def _flux_turn_resumed_callback():
            """TurnResumed — user kept speaking. Cancel speculative processing."""
            print(f"[{ts()}] {self.tag} 🔄 TurnResumed — cancelling speculative Groq")
            if self._speculative_task and not self._speculative_task.done():
                self._speculative_task.cancel()
            self._speculative_text = ""
            if self.standup_flow:
                self.standup_flow.clear_cached_result()

        async def _flux_end_of_turn_callback(confidence):
            """Called when Flux fires EndOfTurn with confidence score."""
            print(
                f"[{ts()}] {self.tag} 🎯 Flux EndOfTurn (confidence={confidence:.2f})"
            )

        # Build keyword list for Flux (fixes "Scrub" → "SCRUM" transcription)
        keywords = ["AnavClouds", "Salesforce", "Sam"]
        if self.jira and self.jira.enabled and self.jira.project:
            keywords.append(self.jira.project)

        async def _run_flux():
            try:
                # Stage R: lock one Deepgram key to this session for its lifetime
                try:
                    from key_rotator import key_for_session as _key_for_session

                    _dg_key = (
                        _key_for_session("DEEPGRAM", self.session_id)
                        or DEEPGRAM_API_KEY
                    )
                except Exception:
                    _dg_key = DEEPGRAM_API_KEY
                await stream_deepgram(
                    audio_queue=self._stt_queue,
                    transcript_callback=_flux_transcript_callback,
                    api_key=_dg_key,
                    model="nova-3",
                    sample_rate=16000,
                    keywords=keywords,
                    enable_sentiment=True,
                )
            except Exception as e:
                print(f"[{ts()}] {self.tag} ⚠️  Flux STT error: {e}")
            finally:
                self._flux_enabled = False
                print(f"[{ts()}] {self.tag} 🎯 Flux STT ended")

        self._stt_task = asyncio.create_task(_run_flux())

    async def _run_speculative_classify(
        self, text: str, sentiment: Optional[str] = None
    ):
        """Pre-compute Groq classify+ack during EagerEndOfTurn→EndOfTurn window.

        Called as fire-and-forget task. If completed before EndOfTurn fires,
        the cached result is used by standup_flow.handle() — saving ~200-300ms.
        If TurnResumed fires first, this task is cancelled and cache cleared.
        """
        try:
            if not self.standup_flow or self.standup_flow.is_done:
                return
            result = await self.standup_flow.pre_classify(text, sentiment=sentiment)
            # Only cache if the transcript still matches (not cancelled/replaced)
            if result and self._speculative_text == text:
                self.standup_flow.set_cached_result(result, text)
                print(
                    f'[{ts()}] {self.tag} ⚡ Speculative Groq cached: "{result[:50]}"'
                )
        except asyncio.CancelledError:
            pass
        except Exception as e:
            # Non-fatal — EndOfTurn will fall back to normal Groq call
            print(
                f"[{ts()}] {self.tag} ⚠️  Speculative classify failed (non-fatal): {e}"
            )

    async def _stop_flux_stt(self):
        """Stop Flux STT connection and clean up speculative state."""
        # Cancel speculative task
        if self._speculative_task and not self._speculative_task.done():
            self._speculative_task.cancel()
        self._speculative_task = None
        self._speculative_text = ""
        # Close Flux connection
        if self._stt_queue:
            await self._stt_queue.put(None)  # Sentinel to close Deepgram
        if self._stt_task and not self._stt_task.done():
            self._stt_task.cancel()
            try:
                await self._stt_task
            except (asyncio.CancelledError, Exception):
                pass
        # Cancel speech_off debounce timer if pending
        if self._flux_speech_off_task and not self._flux_speech_off_task.done():
            self._flux_speech_off_task.cancel()
        self._flux_speech_off_task = None
        self._stt_task = None
        self._stt_queue = None
        self._flux_enabled = False
        self._flux_audio_buf = b""
        self._flux_last_interim_text = ""
        self._flux_standup_audio_logged = False

    async def _flux_debounce_finalize(self):
        """Wait for debounce window, then convert Flux's pending interim text to FINAL.

        Called when Recall fires speech_off for the standup participant. If user resumes
        speaking within debounce window, speech_on cancels this task.

        This handles the case where Flux's native silence-based EOT won't fire because
        the user muted their mic (no audio = no silence detection). speech_off tells us
        the user stopped producing audio regardless of mute state.
        """
        try:
            debounce_s = self._FLUX_SPEECH_OFF_DEBOUNCE_MS / 1000.0
            await asyncio.sleep(debounce_s)

            # Debounce window passed — user genuinely stopped. Promote interim to FINAL.
            if (
                not self._flux_enabled
                or not self.standup_flow
                or self.standup_flow.is_done
            ):
                return
            interim = self._flux_last_interim_text
            if not interim:
                return  # no pending interim — nothing to finalize

            project_key = (
                self.jira.project if self.jira and self.jira.enabled else "SCRUM"
            )
            clean_text = _convert_spoken_ticket_refs(interim, project_key)
            print(
                f'[{ts()}] {self.tag} 🔇 speech_off debounce ({self._FLUX_SPEECH_OFF_DEBOUNCE_MS}ms) — promoting interim to FINAL: "{clean_text[:60]}"'
            )

            # Clear interim and any speculative state — same as Flux FINAL handler
            self._flux_last_interim_text = ""
            self.partial_text = ""
            self.partial_speaker = ""

            # Feed into the same processing path as Flux's own FINAL
            self._standup_buffer.append(clean_text)
            self._schedule_delayed_standup_processing(
                self.standup_flow.developer, clean_text
            )
        except asyncio.CancelledError:
            # speech_on fired within debounce — user resumed, no action needed
            pass
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  speech_off debounce error: {e}")

    def _schedule_delayed_standup_processing(self, speaker: str, text: str):
        """Schedule delayed standup processing with incomplete sentence detection."""
        if self._delayed_standup_task and not self._delayed_standup_task.done():
            self._delayed_standup_task.cancel()

        target_delay = _get_adaptive_delay(text)
        total_delay = max(0.0, target_delay - 0.4)

        print(
            f'[{ts()}] {self.tag} ⏱️ Standup response delay: {total_delay:.1f}s (target={target_delay:.1f}s, additional={total_delay:.1f}s) for text: "{text[:40]}"'
        )

        async def _run():
            try:
                await asyncio.sleep(total_delay)
                await self._process_standup_buffer(speaker)
            except asyncio.CancelledError:
                print(
                    f"[{ts()}] {self.tag} ⏱️ Standup response delay cancelled (user resumed speaking)"
                )

        self._delayed_standup_task = asyncio.create_task(_run())

    async def _process_standup_buffer(self, speaker: str):
        """Process standup buffer immediately (called by Flux EndOfTurn or timer fallback)."""
        if (
            not self._standup_buffer
            or not self.standup_flow
            or self.standup_flow.is_done
        ):
            return

        # Wait for Sam to finish speaking (max 2s)
        for _ in range(20):
            if not self.speaking:
                break
            await asyncio.sleep(0.1)

        # Wait for previous handle() to finish (max 15s)
        for _ in range(150):
            if not self.standup_flow._processing:
                break
            await asyncio.sleep(0.1)

        if not self._standup_buffer:
            return

        full_text = " ".join(self._standup_buffer)
        self._standup_buffer.clear()

        # Pre-convert spoken ticket references
        project_key = self.jira.project if self.jira and self.jira.enabled else "SCRUM"
        full_text = _convert_spoken_ticket_refs(full_text, project_key)

        print(f"[{ts()}] {self.tag} 📋 Standup input: {full_text[:80]}")

        changed_name = self._check_name_change(full_text)
        if changed_name:
            self.generation += 1
            self.speaking = True
            try:
                await self._handle_name_change(changed_name)
            finally:
                self.speaking = False
            return

        # Clear any stale interrupt
        self.interrupt_event.clear()

        self.generation += 1
        self.speaking = True
        try:
            sentiment = getattr(self, "_flux_latest_sentiment", None)
            self._flux_latest_sentiment = None

            # Determine if a standup filler is needed
            self._standup_filler_duration = 0.0
            self._standup_filler_relay_start = 0.0

            if self._needs_acknowledgement_filler(full_text, sentiment):
                chosen_filler = self._select_acknowledgement_filler(
                    full_text, sentiment
                )
                print(
                    f'[{ts()}] {self.tag} ⚡ Standup immediate low-latency filler: "{chosen_filler}"'
                )
                self._standup_filler_relay_start = time.time()
                if self._streaming_mode:
                    self._standup_filler_duration = await self._stream_and_relay(
                        chosen_filler, self.generation
                    )
                else:
                    await self._speak(
                        chosen_filler, "standup-immediate-filler", self.generation
                    )
                    self._standup_filler_duration = 0.0
                    self._standup_filler_relay_start = 0.0

                if self.interrupt_event.is_set():
                    return

            still_active = await self.standup_flow.handle(
                full_text, speaker, self.generation, sentiment=sentiment
            )
            if not still_active:
                await self._finish_standup()
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  Standup error: {e}")
        finally:
            self.speaking = False

    async def _finish_standup(self):
        """Save basic standup + leave immediately + background extract/Jira."""
        if self._standup_finished:
            return
        if not self.standup_flow:
            return
        self._standup_finished = True

        # Stop Flux STT
        await self._stop_flux_stt()

        # 1. Save basic standup data (raw answers, before extraction)
        result = self.standup_flow.get_result()
        result["session_id"] = self.session_id
        result["user"] = self.username
        result["mode"] = "standup"
        session_store.save_standup(result)
        print(f"[{ts()}] {self.tag} ✅ Standup saved (basic)")

        # 2. Leave meeting immediately (2 second pause for last audio)
        if self.standup_flow.is_done:
            asyncio.create_task(self._auto_leave_after_standup())

        # 3. Background: Azure extraction + Jira (fire and forget)
        if self.standup_flow.data.get("completed"):
            asyncio.create_task(self._background_standup_work())

    async def _auto_leave_after_standup(self):
        """Leave meeting 2 seconds after standup completes."""
        if self._auto_left:
            return
        self._auto_left = True
        try:
            await asyncio.sleep(2.0)
            print(f"[{ts()}] {self.tag} 🚪 Auto-leaving after standup")
            if self.bot_id:
                import httpx

                RECALL_REGION = os.environ.get("RECALLAI_REGION", "ap-northeast-1")
                RECALL_API_BASE = f"https://{RECALL_REGION}.recall.ai/api/v1"
                # Stage R: use the same Recall key that was locked to this
                # session when the bot was created (sticky per-session).
                try:
                    from key_rotator import key_for_session as _key_for_session

                    _recall_key = _key_for_session("RECALLAI", self.session_id)
                except Exception:
                    _recall_key = None
                if not _recall_key:
                    _recall_key = os.environ["RECALLAI_API_KEY"]
                headers = {
                    "Authorization": f"Token {_recall_key}",
                    "Content-Type": "application/json",
                }
                async with httpx.AsyncClient(timeout=10) as client:
                    await client.post(
                        f"{RECALL_API_BASE}/bot/{self.bot_id}/leave_call/",
                        headers=headers,
                    )
                print(f"[{ts()}] {self.tag} ✅ Bot left meeting")
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  Auto-leave failed: {e}")

    async def _background_standup_work(self):
        """Background: Azure extraction + Jira comments + transitions.
        Runs AFTER bot leaves. User is already gone."""
        try:
            # Wait a moment for bot to leave cleanly
            await asyncio.sleep(3.0)

            print(f"[{ts()}] {self.tag} 🔧 Background: processing standup data...")
            await self.standup_flow.background_finalize()

            # Re-save with enriched data (summaries, jira_ids, status_updates)
            result = self.standup_flow.get_result()
            result["session_id"] = self.session_id
            result["user"] = self.username
            result["mode"] = "standup"
            session_store.save_standup(result)
            print(f"[{ts()}] {self.tag} ✅ Standup re-saved (enriched)")

            # Write session-level insights summary for standup sessions
            if self._utterance_log:
                try:
                    developer = self.standup_flow.developer
                    session_store.save_session_insights(
                        session_id=self.session_id,
                        session_type="standup",
                        date=time.strftime("%Y-%m-%d", time.gmtime()),
                        participants=[developer, "Sam"],
                        summary=_compute_session_summary(self._utterance_log),
                    )
                except Exception as _ie:
                    print(
                        f"[{ts()}] {self.tag} ⚠️  Standup session insights save failed (non-fatal): {_ie}"
                    )

        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  Background standup work failed: {e}")

    async def _flush_standup_buffer(self, speaker: str):
        """Simple silence-based flush: 1.2s timer restarts on new text.
        Fast path for tickets/blockers/confirmations. No fillers, no EOT."""
        try:
            # ── Step 1: Wait for adaptive silence ──
            full_text = " ".join(self._standup_buffer)
            total_delay = _get_adaptive_delay(full_text)
            print(
                f'[{ts()}] {self.tag} ⏱️ Standup flush delay: {total_delay:.1f}s for text: "{full_text[:40]}"'
            )
            await asyncio.sleep(total_delay)

            if not self._standup_buffer:
                return

            # ── Step 2: Wait for Sam to finish speaking (max 2s) ──
            for _ in range(20):
                if not self.speaking:
                    break
                await asyncio.sleep(0.1)

            # ── Step 3: Wait for previous handle() to finish (max 15s) ──
            for _ in range(150):
                if not self.standup_flow._processing:
                    break
                await asyncio.sleep(0.1)

            if not self._standup_buffer:
                return

            # ── Step 4: Process entire buffer ──
            full_text = " ".join(self._standup_buffer)
            self._standup_buffer.clear()

            # Pre-convert spoken ticket references
            project_key = (
                self.jira.project if self.jira and self.jira.enabled else "SCRUM"
            )
            full_text = _convert_spoken_ticket_refs(full_text, project_key)

            print(f"[{ts()}] {self.tag} 📋 Standup input: {full_text[:80]}")

            changed_name = self._check_name_change(full_text)
            if changed_name:
                self.generation += 1
                self.speaking = True
                try:
                    await self._handle_name_change(changed_name)
                finally:
                    self.speaking = False
                return

            # Clear any stale interrupt
            self.interrupt_event.clear()

            self.generation += 1
            self.speaking = True
            try:
                still_active = await self.standup_flow.handle(
                    full_text, speaker, self.generation
                )
                if not still_active:
                    await self._finish_standup()
            except Exception as e:
                print(f"[{ts()}] {self.tag} ⚠️  Standup error: {e}")
            finally:
                self.speaking = False

            # After processing, check if more text arrived during processing
            if (
                self._standup_buffer
                and self.standup_flow
                and not self.standup_flow.is_done
            ):
                self._standup_timer = asyncio.create_task(
                    self._flush_standup_buffer(speaker)
                )

        except asyncio.CancelledError:
            pass

    def _append_transcript(self, role: str, text: str):
        """Append one turn to a per-session transcript .txt file.

        File path: transcripts/<session_id>_<launch_ts>.txt
        Format: "[YYYY-MM-DD HH:MM:SS]  <role>: <full_text>\n"

        Never raises — transcript logging must not break the main flow.
        """
        try:
            import os as _os
            from datetime import datetime as _dt

            if not hasattr(self, "_transcript_path"):
                _os.makedirs("transcripts", exist_ok=True)
                stamp = _dt.now().strftime("%Y%m%d-%H%M%S")
                # session_id may have dashes; keep as-is for traceability
                sid = getattr(self, "session_id", "unknown")
                self._transcript_path = _os.path.join(
                    "transcripts", f"{sid}_{stamp}.txt"
                )
                # Write a header on first append
                with open(self._transcript_path, "a", encoding="utf-8") as f:
                    f.write(f"=== Session {sid} | started {stamp} ===\n")
            ts_str = _dt.now().strftime("%Y-%m-%d %H:%M:%S")
            # Pad role to 6 chars so columns align (Sam vs Sahil etc.)
            role_padded = f"{role}:".ljust(7)
            line = f"[{ts_str}]  {role_padded} {text}\n"
            with open(self._transcript_path, "a", encoding="utf-8") as f:
                f.write(line)
        except Exception as e:
            # Defensive: never let transcript logging break main flow
            print(f"[{ts()}] {self.tag} ⚠️  transcript log failed (non-fatal): {e}")

    def _log_sam(self, text):
        self.convo_history.append(f"Sam: {text}")
        self.agent.log_exchange("Sam", text)
        # Track Sam's most recent response for AddresseeDecider context
        self._sam_last_response = text
        # Week 4 Phase 1: Tell DialogueManager what Sam said (for state tracking)
        if self._dialogue_manager is not None:
            try:
                self._dialogue_manager.record_sam_response(text)
            except Exception as e:
                print(
                    f"[{ts()}] {self.tag} ⚠️  DialogueManager record_sam_response "
                    f"failed (non-fatal): {e}"
                )
        print(f"[{ts()}] {self.tag} 🗣️ Sam: {text[:100]}")
        # Append FULL response to transcript file (console still shows preview)
        self._append_transcript("Sam", text)

    def _log_utterance_insight(
        self,
        speaker: str,
        text: str,
        sentiment: Optional[str],
        filler_triggered: bool,
        pause_detected: bool,
        sentiment_score: Optional[float] = None,
        adaptive_endpointing_used: Optional[str] = None,
        active_listening_token_played: Optional[str] = None,
        bridge_filler_played: Optional[str] = None,
        llm_used: Optional[str] = None,
        llm_model: Optional[str] = None,
        fallback_triggered: bool = False,
        groq_cooling: bool = False,
    ) -> None:
        """Build and persist one per-utterance insight record.

        Called synchronously (non-blocking) immediately after a user's final
        transcript is received. Derives emotion + intent locally (no LLM),
        then appends to self._utterance_log and calls storage.append_utterance_insight
        to write it to session_insights.json.

        Never raises — insight logging must not break the main pipeline.
        """
        try:
            from datetime import datetime as _dt

            sentiment_label = sentiment or "neutral"
            emotion_data = _derive_emotion(text, sentiment_label)
            intent_data = _derive_user_intent(text)

            record = {
                "timestamp": _dt.utcnow().strftime("%Y-%m-%dT%H:%M:%SZ"),
                "speaker": speaker,
                "utterance": text,
                "sentiment": {
                    "label": sentiment_label,
                    "score": sentiment_score,
                },
                "emotions": emotion_data,
                "intent": intent_data,
                "filler_triggered": filler_triggered,
                "pause_detected": pause_detected,
                "adaptive_endpointing_used": adaptive_endpointing_used,
                "active_listening_token_played": active_listening_token_played,
                "bridge_filler_played": bridge_filler_played,
                "llm_used": llm_used,
                "llm_model": llm_model,
                "fallback_triggered": fallback_triggered,
                "groq_cooling": groq_cooling,
            }

            self._utterance_log.append(record)
            session_store.append_utterance_insight(self.session_id, record)

            print(
                f"[{ts()}] {self.tag} 📊 Insight: [{speaker}] "
                f"sentiment={sentiment_label} score={sentiment_score} "
                f"emotion={emotion_data['dominant']} intent={intent_data['label']}"
            )
        except Exception as e:
            print(
                f"[{ts()}] {self.tag} ⚠️  _log_utterance_insight failed (non-fatal): {e}"
            )

    async def _play_interrupt_ack(self):
        if not self.server._interrupt_ack_audio:
            return
        self.interrupt_event.clear()
        self.generation += 1
        self.speaking = True
        self.playing_ack = True
        try:
            text, audio = random.choice(self.server._interrupt_ack_audio)
            # For acks, always use fallback (pre-baked MP3, instant)
            await asyncio.sleep(0.5)  # Wait for Recall to fully stop previous audio
            b64 = base64.b64encode(audio).decode("utf-8")
            await self.speaker._inject_into_meeting(b64)
            self.audio_playing = True
            play_dur = get_duration_ms(audio)
            try:
                await asyncio.wait_for(
                    self.interrupt_event.wait(), timeout=play_dur / 1000
                )
            except asyncio.TimeoutError:
                pass
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  Ack error: {e}")
        finally:
            self.speaking = False
            self.audio_playing = False
            self.playing_ack = False

    # ── Background search ─────────────────────────────────────────────────────

    async def _search_and_speak(self, text, context, my_gen):
        summary = await self.agent.search_and_summarize(text, context)
        sentences = self.agent._split_sentences(summary)
        for sent in sentences:
            if self.interrupt_event.is_set() or my_gen != self.generation:
                return ""
            await self._speak(sent, "search", my_gen)
        return " ".join(sentences)

    # ── Unified Research Flow (Feature 4) ─────────────────────────────────────

    async def _unified_research_flow(
        self,
        user_text: str,
        context: str,
        my_gen: int,
        filler_duration: float,
        filler_relay_start: float,
    ):
        """SerpAPI-direct OR Exa+Azure research path with unified LLM planning.

        Flow:
        1. Generate unified research plan (Groq 70b, ~600-900ms)
        2. Routing gate: internal_org → fall back to legacy
        3. Gather tickets (cached + fresh if needed)
        4. Build project context, agenda, client profile, ticket enrichment
        5. Branch on RESEARCH_PROVIDER:
            - "exa"   → Exa search + Azure streaming (NEW) → fall back to Brave on fail
            - "brave" → SerpAPI Brave AI Mode (existing path)
        6. Stream sentences to TTS via _stream_pipelined

        Returns:
        (all_sentences, interrupted) tuple if successful,
        None if any step failed (caller falls back to legacy synthesis).

        Safety: any failure at any step returns None → legacy fallback kicks in.
        """
        import time as _t

        # Step 1: Unified research planner (ONE Groq 70b call) — UNCHANGED
        plan = await self.agent.generate_unified_research_plan(
            user_text=user_text,
            context=context,
            ticket_cache=self._ticket_cache,
            memory_header=self._memory_header,
        )

        if not plan:
            return None

        # Step 2: ROUTING DECISION — UNCHANGED
        qtype = plan.get("question_type", "general")
        if qtype == "internal_org":
            print(
                f"[{ts()}] {self.tag} 🛡️  Unified plan: internal_org → "
                f"deferring to legacy (hallucination guard)"
            )
            return None

        cached_refs = plan.get("relevant_cached_tickets", [])
        needs_fresh = plan.get("needs_fresh_jira", False)
        features = plan.get("serpapi_context_features", [])
        print(
            f"[{ts()}] {self.tag} 🚪 Research path handling {qtype} "
            f"(provider={RESEARCH_PROVIDER}, cached_refs={len(cached_refs)}, "
            f"needs_fresh={needs_fresh}, features={len(features)})"
        )

        if self.interrupt_event.is_set() or my_gen != self.generation:
            return None

        # Step 3: Gather tickets — UNCHANGED
        relevant_tickets = []
        cached_keys = set(plan.get("relevant_cached_tickets", []))
        if cached_keys:
            for t in self._ticket_cache:
                if t.get("key") in cached_keys:
                    relevant_tickets.append(t)

        if plan.get("needs_fresh_jira") and plan.get("jira_search_terms"):
            if self.jira and self.jira.enabled:
                try:
                    fresh = await asyncio.wait_for(
                        self.jira.search_text(plan["jira_search_terms"], max_results=5),
                        timeout=2.5,
                    )
                    if fresh:
                        existing_keys = {t.get("key") for t in self._ticket_cache}
                        for ft in fresh:
                            if ft.get("key") and ft["key"] not in existing_keys:
                                self._ticket_cache.append(ft)
                                existing_keys.add(ft["key"])
                            if ft not in relevant_tickets:
                                relevant_tickets.append(ft)
                        self._rebuild_jira_context()
                        print(
                            f"[{ts()}] {self.tag} 🎯 Fresh Jira fetch: +{len(fresh)} ticket(s)"
                        )
                except asyncio.TimeoutError:
                    print(
                        f"[{ts()}] {self.tag} ⏱ Fresh Jira fetch timeout (>2.5s) — continuing without"
                    )
                except Exception as e:
                    print(f"[{ts()}] {self.tag} ⚠️  Fresh Jira fetch failed: {e}")

        if self.interrupt_event.is_set() or my_gen != self.generation:
            return None

        # Step 4: Build project context — UNCHANGED
        feature_descriptions = plan.get("serpapi_context_features", [])
        project_context = self.agent._build_project_context_from_tickets(
            tickets=relevant_tickets if relevant_tickets else self._ticket_cache[:10],
            feature_descriptions=feature_descriptions,
        )

        # Step 4b: PHASE 1 — Read-only ticket enrichment (sequential Jira fetch) — UNCHANGED
        enriched_ticket_block = ""
        try:
            ticket_keys_in_question = self._detect_ticket_keys(user_text)
            if ticket_keys_in_question and self.jira and self.jira.enabled:
                print(
                    f"[{ts()}] {self.tag} 🎯 Enrichment: detected "
                    f"{len(ticket_keys_in_question)} ticket key(s) in question: "
                    f"{ticket_keys_in_question}"
                )
                t_jira = time.time()
                fresh_tickets = await self.jira.get_tickets_batch(
                    ticket_keys_in_question
                )
                jira_ms = (time.time() - t_jira) * 1000
                if fresh_tickets:
                    enriched_ticket_block = self._format_fresh_tickets_for_prompt(
                        fresh_tickets
                    )
                    print(
                        f"[{ts()}] {self.tag} ✅ Enrichment: fetched "
                        f"{len(fresh_tickets)}/{len(ticket_keys_in_question)} ticket(s) "
                        f"from Jira ({jira_ms:.0f}ms)"
                    )
                else:
                    print(
                        f"[{ts()}] {self.tag} ⚠️  Enrichment: Jira returned "
                        f"0 tickets for {ticket_keys_in_question} ({jira_ms:.0f}ms) "
                        f"— prompt will rely on cached context"
                    )
        except Exception as _enrich_e:
            print(
                f"[{ts()}] {self.tag} ⚠️  Enrichment failed "
                f"({type(_enrich_e).__name__}: {_enrich_e}) — falling back to cached context"
            )

        if enriched_ticket_block:
            if project_context:
                project_context = enriched_ticket_block + "\n" + project_context
            else:
                project_context = enriched_ticket_block

        # Step 4c: Build agenda + client_profile blocks — UNCHANGED
        agenda_block = self._build_agenda_block_for_prompt()
        client_profile_block = self._build_client_profile_block_for_prompt()

        if self.interrupt_event.is_set() or my_gen != self.generation:
            return None

        length_hint = "70-90 words across 4-5 sentences"

        # ═════════════════════════════════════════════════════════════════════════
        # STEP 5: BRANCH ON RESEARCH_PROVIDER — this is the NEW logic
        # ═════════════════════════════════════════════════════════════════════════

        # Path: EXA + Azure streaming
        if RESEARCH_PROVIDER == "exa":
            exa_succeeded = await self._try_exa_research_path(
                user_text=user_text,
                project_context=project_context,
                agenda_block=agenda_block,
                client_profile_block=client_profile_block,
                context=context,
                plan=plan,
                length_hint=length_hint,
                my_gen=my_gen,
                filler_duration=filler_duration,
                filler_relay_start=filler_relay_start,
            )
            if exa_succeeded is not None:
                # Either succeeded (returns tuple) OR failed cleanly (returns None
                # to trigger Brave fallback below). When it returns a tuple we use it.
                return exa_succeeded
            # exa_succeeded is None → fall through to Brave path below
            print(
                f"[{ts()}] {self.tag} 🔄 Exa path returned None — falling back to Brave"
            )

        # Path: BRAVE AI Mode (default + Exa fallback) — EXISTING logic, unchanged
        response_text = await self.agent.serpapi_direct_research(
            user_text=user_text,
            project_context=project_context,
            conversation=context,
            length=length_hint,
            agenda_block=agenda_block,
            client_profile_block=client_profile_block,
        )

        if not response_text:
            return None

        if self.interrupt_event.is_set() or my_gen != self.generation:
            return None

        sentences = self.agent._split_sentences(response_text)
        if not sentences:
            return None

        research_queue: asyncio.Queue = asyncio.Queue()

        async def _fill_queue():
            try:
                for s in sentences:
                    if self.interrupt_event.is_set() or my_gen != self.generation:
                        break
                    await research_queue.put(s)
            finally:
                await research_queue.put(None)

        filler_stream_task = asyncio.create_task(_fill_queue())

        if self._streaming_mode:
            all_sentences, interrupted = await self._stream_pipelined(
                research_queue,
                my_gen,
                cancel_task=filler_stream_task,
                extra_duration=filler_duration,
                relay_start_override=filler_relay_start,
            )
            return (all_sentences, interrupted)
        else:
            spoken: list = []
            while True:
                try:
                    item = await asyncio.wait_for(research_queue.get(), timeout=30.0)
                except asyncio.TimeoutError:
                    break
                if item is None:
                    break
                spoken.append(item)
            for sent in spoken:
                if self.interrupt_event.is_set() or my_gen != self.generation:
                    return (spoken, True)
                await self._speak(sent, "research", my_gen)
            return (spoken, False)

    # ── ALSO ADD THIS HELPER METHOD ────────────────────────────────────────────
    # Paste this directly below _unified_research_flow (same indent — class method).

    async def _try_exa_research_path(
        self,
        user_text: str,
        project_context: str,
        agenda_block: str,
        client_profile_block: str,
        context: str,
        plan: dict,
        length_hint: str,
        my_gen: int,
        filler_duration: float,
        filler_relay_start: float,
    ):
        """Run the Exa + Azure streaming research path.

        Returns:
        (all_sentences, interrupted) tuple on success
        None on failure (caller should fall back to Brave)

        Failure modes that return None:
        - Exa returned no usable results
        - Exa client not configured (missing EXA_API_KEY)
        - Exa failed 3+ times in this session (circuit breaker)
        - Azure synthesis failed
        """
        import time as _t

        exa_search = self.agent._get_exa_search()

        # Bail out if Exa not configured — fall back to Brave
        if not exa_search.enabled:
            print(f"[{ts()}] {self.tag} ⚠️  EXA_API_KEY not set — falling back to Brave")
            return None

        # Circuit breaker — if Exa keeps failing, stop trying for this session
        if exa_search.consecutive_failures >= 3:
            print(
                f"[{ts()}] {self.tag} ⚠️  Exa circuit-broken "
                f"({exa_search.consecutive_failures} failures) — using Brave for rest of session"
            )
            return None

        # Build the Exa search query — prefer the planner's clean query,
        # fall back to user_text. Exa expects a search query, NOT a long persona prompt.
        exa_query = (plan.get("web_search_query") or "").strip()
        if not exa_query or exa_query.upper() == "SKIP":
            # Planner didn't produce a search query (e.g. for some Jira-status questions)
            # Fall back to the user's question, trimmed to a reasonable search query length
            exa_query = user_text.strip()
            if len(exa_query) > 200:
                exa_query = exa_query[:200]

        print(f'[{ts()}] {self.tag} 🔍 Exa query: "{exa_query[:80]}"')

        # Step 5.1: Exa search
        t_exa = _t.time()
        exa_results = await exa_search.search(exa_query, num_results=8)
        exa_ms = (_t.time() - t_exa) * 1000
        print(f"[{ts()}] {self.tag} ⏱ Exa search: {exa_ms:.0f}ms")

        if not exa_results:
            print(
                f"[{ts()}] {self.tag} ⚠️  Exa returned no results — falling back to Brave"
            )
            return None

        if self.interrupt_event.is_set() or my_gen != self.generation:
            return None

        # Step 5.2: Azure streaming synthesis with Exa results
        research_queue: asyncio.Queue = asyncio.Queue()

        synthesis_task = asyncio.create_task(
            self.agent.exa_stream_synthesis_to_queue(
                user_text=user_text,
                exa_results=exa_results,
                project_context=project_context,
                azure_extractor=self.azure_extractor,
                queue=research_queue,
                conversation=context,
                agenda_block=agenda_block,
                client_profile_block=client_profile_block,
                length=length_hint,
            )
        )

        # Step 5.3: Stream sentences to TTS via _stream_pipelined
        if self._streaming_mode:
            all_sentences, interrupted = await self._stream_pipelined(
                research_queue,
                my_gen,
                cancel_task=synthesis_task,
                extra_duration=filler_duration,
                relay_start_override=filler_relay_start,
            )

            # Sanity check: if synthesis produced nothing usable, treat as failure
            if not all_sentences and not interrupted:
                print(
                    f"[{ts()}] {self.tag} ⚠️  Exa+Azure produced no sentences — "
                    f"falling back to Brave"
                )
                return None

            return (all_sentences, interrupted)
        else:
            # Non-streaming fallback (used when audio page disconnected)
            spoken: list = []
            while True:
                try:
                    item = await asyncio.wait_for(research_queue.get(), timeout=30.0)
                except asyncio.TimeoutError:
                    break
                if item is None:
                    break
                spoken.append(item)

            if not spoken:
                print(
                    f"[{ts()}] {self.tag} ⚠️  Exa+Azure produced no sentences "
                    f"(non-streaming) — falling back to Brave"
                )
                return None

            for sent in spoken:
                if self.interrupt_event.is_set() or my_gen != self.generation:
                    return (spoken, True)
                await self._speak(sent, "research", my_gen)
            return (spoken, False)

    # ── Stage 2: unified research v2 ─────────────────────────────────────────

    async def _unified_research_v2(
        self,
        user_text: str,
        context: str,
        my_gen: int,
        filler_duration: float,
        filler_relay_start: float,
    ):
        """Stage 2: single research path with planner-driven conditional fetch.

        Replaces both _unified_research_flow AND the legacy fallback block.
        Behind RESEARCH_ARCHITECTURE=unified (default).

        Flow:
          1. Plan (Groq 70b, ~600-900ms)
          2. Build always-needed blocks (profile, agenda, memory)
          3. Conditional parallel fetch:
               - _handle_jira_read (handles transitions/creates/reads, ~1s)
                 fired when needs_fresh_jira=True OR question_type=="internal_org"
               - _search_with_fallback (Exa→Brave) fired when web_search_query
                 is set OR question_type=="internal_org"
          4. Build project_context from cached + freshly-fetched tickets
          5. Single synthesis via unified_synthesis_to_queue
          6. Stream sentences via existing _stream_pipelined

        For internal_org: legacy behavior — fetch both, let synthesis sort it
        out. Profile/agenda always injected so hallucinations stay impossible.

        Returns:
          (all_sentences, interrupted) tuple if successful
          None if any step failed (caller's safety-net legacy block runs)
        """
        import time as _t
        import json as _json
        import asyncio  # Stage 2.6 hotfix: needed for asyncio.wait_for/shield below

        # ─── Stage 2.6: journal retrieval with rewritten query ─────────────
        # Replaces Stage 2.5's heuristic single-slot cache. Now:
        #   1. Wait for the rewriter task that was fired in _handle_addressee
        #      (already running in parallel — usually done by now).
        #   2. Search the research journal by embedding similarity.
        #   3. If a match is found above min_score, fast PM with that entry.
        #   4. ESCALATE → fresh research path below.
        #
        # Kill switch: RESEARCH_JOURNAL_ENABLED=0 → falls back to Stage 2.5
        #              single-slot cache (which has known pollution issues but
        #              is preserved as a fallback).
        import os as _os

        use_journal = _os.environ.get("RESEARCH_JOURNAL_ENABLED", "1").strip() != "0"

        rewritten_query = user_text  # default if rewriter unavailable / disabled
        if use_journal:
            # Step 1: await the rewriter (fired in _handle_addressee_decision)
            if self._last_rewriter_task is not None:
                try:
                    rewritten_query = await asyncio.wait_for(
                        asyncio.shield(self._last_rewriter_task),
                        timeout=1.5,
                    )
                    self._last_rewritten_query = rewritten_query
                except (asyncio.TimeoutError, asyncio.CancelledError):
                    print(f"[{ts()}] {self.tag} ⚠️  Rewriter not ready — using raw")
                    rewritten_query = user_text
                except Exception as e:
                    print(f"[{ts()}] {self.tag} ⚠️  Rewriter await failed: {e}")
                    rewritten_query = user_text

            # Stage 2.10 Checkpoint 1: skip journal on live-fetch policy
            # If Policy demanded fresh data, don't let journal intercept.
            live_fetch, reason = self._policy_demanded_live_fetch()
            if live_fetch:
                print(
                    f"[{ts()}] {self.tag} 📔 Skipping journal lookup — "
                    f"{reason} (going straight to research)"
                )
            else:
                # Step 2: search journal
                try:
                    journal = getattr(self.agent, "journal", None)
                    if journal and journal.size > 0:
                        # Stage 2.10 Checkpoint 2: stricter journal hits.
                        # Raise threshold from 0.5 to 0.7. Below 0.7 we still
                        # peek (down to 0.5) but only accept if the entry has
                        # actual concrete data (tickets or web results).
                        import os as _os_thresh

                        try:
                            strict_thresh = float(
                                _os_thresh.environ.get("JOURNAL_MIN_SCORE", "0.7")
                            )
                        except ValueError:
                            strict_thresh = 0.7
                        peek_thresh = 0.5  # below 0.7 but above this requires data

                        matches = await journal.search(
                            rewritten_query, top_k=1, min_score=peek_thresh
                        )
                        if matches:
                            score, entry = matches[0]
                            n_tickets = len(entry.get("jira_tickets") or [])
                            n_web = len(entry.get("web_results") or [])
                            has_data = n_tickets > 0 or n_web > 0

                            # Stage 2.10 Checkpoint 2: accept hit only if
                            # (score is strict-high) OR (has concrete data)
                            if score >= strict_thresh or has_data:
                                # Stage 2.11: journal type-match required.
                                # Run planner now to get current question_type.
                                # Compare against entry's stored type. Reject
                                # cross-topic hits (e.g. capital-of-India entry
                                # firing on a ticket question).
                                #
                                # Kill switch: JOURNAL_TYPE_MATCH_ENABLED=0
                                import os as _os_tm

                                type_match_enabled = (
                                    _os_tm.environ.get(
                                        "JOURNAL_TYPE_MATCH_ENABLED", "1"
                                    ).strip()
                                    != "0"
                                )
                                entry_type = entry.get("question_type", "general")
                                type_check_passed = True

                                if type_match_enabled:
                                    try:
                                        type_plan = await self.agent.generate_unified_research_plan(
                                            user_text=user_text,
                                            context=context,
                                            ticket_cache=self._ticket_cache,
                                            memory_header=self._memory_header,
                                            rewritten_query=(
                                                rewritten_query
                                                if rewritten_query
                                                and rewritten_query != user_text
                                                else ""
                                            ),
                                        )
                                        if type_plan:
                                            current_type = type_plan.get(
                                                "question_type", "general"
                                            )
                                            if current_type != entry_type:
                                                print(
                                                    f"[{ts()}] {self.tag} 📔 Journal "
                                                    f"type-mismatch: entry={entry_type}, "
                                                    f"current={current_type} — rejecting "
                                                    f"hit, falling through to fresh research"
                                                )
                                                type_check_passed = False
                                                # Stash plan so the fresh-research
                                                # path doesn't re-run the planner.
                                                self._stashed_plan_for_v2 = type_plan
                                    except __import__("asyncio").CancelledError:
                                        raise
                                    except Exception as _tm_e:
                                        print(
                                            f"[{ts()}] {self.tag} ⚠️  Type-match "
                                            f"check failed (non-fatal): "
                                            f"{type(_tm_e).__name__}: {_tm_e}"
                                        )

                                if type_check_passed:
                                    print(
                                        f"[{ts()}] {self.tag} 📔 Journal HIT: "
                                        f"score={score:.3f}, type={entry_type}, "
                                        f"data=(t={n_tickets},w={n_web}), "
                                        f"q='{entry.get('question', '')[:50]}'"
                                    )

                                    # Step 3: fast PM with retrieved entry as context
                                    try:
                                        fast_result = await self._fast_pm_from_journal(
                                            user_text=user_text,
                                            rewritten_query=rewritten_query,
                                            journal_entry=entry,
                                            context=context,
                                            my_gen=my_gen,
                                            filler_duration=filler_duration,
                                            filler_relay_start=filler_relay_start,
                                        )
                                        if fast_result is not None:
                                            return fast_result
                                        print(
                                            f"[{ts()}] {self.tag} ↪ Fast PM ESCALATEd — "
                                            f"falling through to fresh research"
                                        )
                                    except __import__("asyncio").CancelledError:
                                        raise
                                    except Exception as e:
                                        print(
                                            f"[{ts()}] {self.tag} ⚠️  Fast PM error: "
                                            f"{type(e).__name__}: {e}"
                                        )
                                # else: type-mismatch path — fall through naturally
                                #       to the fresh-research code below.
                            else:
                                print(
                                    f"[{ts()}] {self.tag} 📔 Journal weak hit "
                                    f"(score={score:.3f} < {strict_thresh}, no data) — "
                                    f"treating as miss"
                                )
                        else:
                            print(
                                f"[{ts()}] {self.tag} 📔 Journal MISS for "
                                f"'{rewritten_query[:50]}' (size={journal.size})"
                            )
                    else:
                        print(f"[{ts()}] {self.tag} 📔 Journal empty — fresh research")
                except Exception as e:
                    print(
                        f"[{ts()}] {self.tag} ⚠️  Journal lookup error: "
                        f"{type(e).__name__}: {e}"
                    )

        else:
            # Fallback path: use Stage 2.5 single-slot cache
            hit, reason = self._check_cache_hit(user_text)
            print(
                f"[{ts()}] {self.tag} 💾 [LEGACY-2.5] Cache: "
                f"{'HIT' if hit else 'MISS'} — {reason}"
            )
            if hit:
                try:
                    fast_result = await self._fast_pm_with_research_cache(
                        user_text=user_text,
                        context=context,
                        my_gen=my_gen,
                        filler_duration=filler_duration,
                        filler_relay_start=filler_relay_start,
                    )
                    if fast_result is not None:
                        return fast_result
                except __import__("asyncio").CancelledError:
                    raise
                except Exception as e:
                    print(f"[{ts()}] {self.tag} ⚠️  Stage 2.5 fast PM error: {e}")

        if self.interrupt_event.is_set() or my_gen != self.generation:
            return None

        # Step 1: Plan ----------------------------------------------------------
        # Stage 2.11: reuse plan computed during type-match check above (if any).
        # Otherwise compute fresh. The stashed plan is the same query/context
        # we'd compute here anyway.
        stashed = getattr(self, "_stashed_plan_for_v2", None)
        if stashed is not None:
            plan = stashed
            self._stashed_plan_for_v2 = None  # consume
            print(f"[{ts()}] {self.tag} 🔁 Reusing plan from type-match check")
        else:
            plan = await self.agent.generate_unified_research_plan(
                user_text=user_text,
                context=context,
                ticket_cache=self._ticket_cache,
                memory_header=self._memory_header,
                rewritten_query=rewritten_query
                if rewritten_query and rewritten_query != user_text
                else "",
            )
        if not plan:
            return None

        qtype = plan.get("question_type", "general")
        cached_refs = plan.get("relevant_cached_tickets", [])
        needs_fresh = plan.get("needs_fresh_jira", False)
        web_query = plan.get("web_search_query", "").strip()

        # Stage 2.7: prefer rewritten_query over raw user_text for fallback.
        # Production bug: "What are your hourly rates" was sent raw to Exa,
        # which returned generic freelance pricing pages. Sam then synthesized
        # those as if they were AnavClouds rates. The rewriter resolves to
        # "AnavClouds Salesforce consulting hourly rates" — much better signal.
        fallback_query = (
            rewritten_query
            if rewritten_query and rewritten_query != user_text
            else user_text
        ).strip()[:200]

        # internal_org: fetch both anyway (per design decision — synthesis sorts
        # it out). Profile is always injected so this is safe.
        if qtype == "internal_org":
            needs_fresh = True
            if not web_query or web_query.upper() == "SKIP":
                web_query = fallback_query

        print(
            f"[{ts()}] {self.tag} 🚪 Unified-v2: type={qtype}, "
            f"cached_refs={len(cached_refs)}, fresh_jira={needs_fresh}, "
            f"web={'YES' if web_query and web_query.upper() != 'SKIP' else 'NO'}"
        )

        if self.interrupt_event.is_set() or my_gen != self.generation:
            return None

        # Step 2: Always-needed blocks ------------------------------------------
        agenda_block = self._build_agenda_block_for_prompt()
        client_profile_block = self._build_client_profile_block_for_prompt()
        memory_context = getattr(self, "_memory_full", "") or ""

        # Step 3: Conditional parallel fetch ------------------------------------
        # Jira: use _handle_jira_read (preserves transition/create/read intent)
        # Web:  use _search_with_fallback (Exa → Brave per-call)

        jira_task = None
        web_task = None

        # Stage 2.7: pass rewritten_query to Jira so "tell me about that
        # ticket" can be resolved to "tell me about SCRUM-244" (extracts key).
        effective_jira_text = (
            rewritten_query
            if rewritten_query and rewritten_query != user_text
            else user_text
        )

        if needs_fresh and self.jira and self.jira.enabled:

            async def _do_jira():
                t0 = _t.time()
                try:
                    result = await self._handle_jira_read(
                        effective_jira_text, context, my_gen
                    )
                    print(
                        f"[{ts()}] {self.tag} ⏱ [JIRA-v2] _handle_jira_read: "
                        f"{(_t.time() - t0) * 1000:.0f}ms"
                    )
                    return result
                except Exception as e:
                    print(
                        f"[{ts()}] {self.tag} ⚠️  [JIRA-v2] failed: "
                        f"{type(e).__name__}: {e}"
                    )
                    return None

            jira_task = __import__("asyncio").create_task(_do_jira())

        if web_query and web_query.upper() != "SKIP":

            async def _do_web():
                t0 = _t.time()
                try:
                    results = await self._search_with_fallback(web_query)
                    print(
                        f"[{ts()}] {self.tag} ⏱ [WEB-v2] {len(results)} results: "
                        f"{(_t.time() - t0) * 1000:.0f}ms"
                    )
                    return results
                except Exception as e:
                    print(
                        f"[{ts()}] {self.tag} ⚠️  [WEB-v2] failed: "
                        f"{type(e).__name__}: {e}"
                    )
                    return []

            web_task = __import__("asyncio").create_task(_do_web())

        # Gather fetches in parallel
        jira_action_result = None
        web_results = []
        if jira_task or web_task:
            t_parallel = _t.time()
            if jira_task:
                jira_action_result = await jira_task
            if web_task:
                web_results = await web_task or []
            print(
                f"[{ts()}] {self.tag} ⏱ [PARALLEL-v2] fetches done: "
                f"{(_t.time() - t_parallel) * 1000:.0f}ms"
            )

        if self.interrupt_event.is_set() or my_gen != self.generation:
            return None

        # Step 4: Build project_context ----------------------------------------
        # Update ticket cache with any fresh tickets from _handle_jira_read
        fresh_tickets = []
        if isinstance(jira_action_result, dict):
            action = jira_action_result.get("action", "")

            # Transition: update cache status in-place
            if action == "transition":
                tid = jira_action_result.get("ticket", "")
                new_status = jira_action_result.get("new_status", "")
                for t in self._ticket_cache:
                    if t.get("key") == tid:
                        t["status"] = new_status
                        break
                self._rebuild_jira_context()

            # New tickets returned: add to cache
            elif "tickets" in jira_action_result and isinstance(
                jira_action_result["tickets"], list
            ):
                fresh_tickets = jira_action_result["tickets"]
                existing_keys = {t.get("key") for t in self._ticket_cache}
                for ft in fresh_tickets:
                    if ft.get("key") and ft["key"] not in existing_keys:
                        self._ticket_cache.append(ft)
                        existing_keys.add(ft["key"])

            # Single ticket returned (no "tickets" wrapper)
            elif "key" in jira_action_result:
                fresh_tickets = [jira_action_result]
                if jira_action_result["key"] not in [
                    t.get("key") for t in self._ticket_cache
                ]:
                    self._update_ticket_cache(jira_action_result)

        # Build project_context: cached refs + fresh tickets
        relevant_tickets = []
        cached_keys_set = set(cached_refs)
        if cached_keys_set:
            for t in self._ticket_cache:
                if t.get("key") in cached_keys_set:
                    relevant_tickets.append(t)
        for ft in fresh_tickets:
            if ft.get("key") and ft.get("key") not in [
                rt.get("key") for rt in relevant_tickets
            ]:
                relevant_tickets.append(ft)

        if relevant_tickets:
            ctx_lines = []
            for t in relevant_tickets[:8]:
                key = t.get("key", "?")
                summary = (t.get("summary") or "").strip()[:120]
                status = t.get("status") or "?"
                ctx_lines.append(f"- {key} [{status}]: {summary}")
            project_context = "\n".join(ctx_lines)
        else:
            project_context = self._jira_context or ""

        # If a Jira action happened (transition / already_done / error), surface
        # it inside project_context so synthesis can acknowledge it
        if isinstance(jira_action_result, dict):
            act = jira_action_result.get("action", "")
            if act in ("transition", "already_done", "transition_error"):
                tid = jira_action_result.get("ticket", "?")
                if act == "transition":
                    note = (
                        f"\n\n[ACTION TAKEN] {tid} moved to "
                        f"'{jira_action_result.get('new_status', '?')}'"
                    )
                elif act == "already_done":
                    note = (
                        f"\n\n[ACTION] {tid} was already at "
                        f"'{jira_action_result.get('already_at', '?')}'"
                    )
                else:
                    note = (
                        f"\n\n[ACTION FAILED] {tid}: "
                        f"{jira_action_result.get('error', 'unknown')}"
                    )
                project_context = (project_context or "") + note

        # Step 5: Synthesis ----------------------------------------------------
        research_queue = __import__("asyncio").Queue()
        synth_task = __import__("asyncio").create_task(
            self.agent.unified_synthesis_to_queue(
                user_text=user_text,
                project_context=project_context,
                web_results=web_results,
                agenda_block=agenda_block,
                client_profile_block=client_profile_block,
                conversation=context,
                memory_context=memory_context,
                azure_extractor=self.azure_extractor,
                queue=research_queue,
                length="70-90 words across 4-5 sentences",
            )
        )

        # Step 6: Stream -------------------------------------------------------
        if self._streaming_mode:
            all_sentences, interrupted = await self._stream_pipelined(
                research_queue,
                my_gen,
                cancel_task=synth_task,
                extra_duration=filler_duration,
                relay_start_override=filler_relay_start,
            )
            # Sanity: if synthesis produced nothing usable, signal failure so
            # caller can fall through to legacy block
            if not all_sentences and not interrupted:
                print(
                    f"[{ts()}] {self.tag} ⚠️  Unified-v2 produced no sentences — "
                    f"falling back to legacy"
                )
                return None

            # Stage 2.6: append research to journal (RAG cache for follow-ups)
            # Stage 2.5 cache also updated as fallback if journal disabled.
            try:
                synthesis_text = " ".join(all_sentences) if all_sentences else ""

                # Stage 2.10 Bug B: include cached refs in journal
                # When planner used cached_refs without fresh_jira, fresh_tickets
                # is empty even though SCRUM-244 (etc.) was in the answer. Pull
                # those from self._ticket_cache so the journal entry has actual
                # data instead of being empty (which causes downstream stalls).
                relevant_tickets = []
                cached_refs = plan.get("relevant_cached_tickets", []) or []
                for key in cached_refs:
                    for t in self._ticket_cache or []:
                        if t.get("key") == key:
                            relevant_tickets.append(t)
                            break
                # Add fresh tickets, dedupe by key
                seen_keys = {t.get("key") for t in relevant_tickets if t.get("key")}
                for ft in fresh_tickets or []:
                    if ft.get("key") and ft.get("key") not in seen_keys:
                        relevant_tickets.append(ft)
                        seen_keys.add(ft.get("key"))

                # Stage 2.6: journal entry (now with cached refs included)
                journal = getattr(self.agent, "journal", None)
                if journal is not None:
                    entry = {
                        "question": rewritten_query
                        if "rewritten_query" in locals()
                        else user_text,
                        "raw_question": user_text,
                        "synthesis_output": synthesis_text[:1500],
                        "jira_tickets": relevant_tickets[:8],
                        "web_results": (web_results or [])[:4],
                        "question_type": plan.get("question_type", "general"),
                    }
                    await journal.add(entry)

                # Stage 2.5: also update single-slot for kill-switch fallback
                self._update_research_cache(
                    user_text=user_text,
                    plan=plan,
                    fresh_tickets=fresh_tickets,
                    web_results=web_results,
                    synthesis_output=synthesis_text,
                )
            except Exception as e:
                print(
                    f"[{ts()}] {self.tag} ⚠️  Journal/cache update failed (non-fatal): "
                    f"{type(e).__name__}: {e}"
                )

            return (all_sentences, interrupted)
        else:
            spoken: list = []
            asyncio = __import__("asyncio")
            while True:
                try:
                    item = await asyncio.wait_for(research_queue.get(), timeout=30.0)
                except asyncio.TimeoutError:
                    break
                if item is None:
                    break
                spoken.append(item)
            if not spoken:
                return None

            # Stage 2.6 + 2.10 Bug B: append research to journal (non-streaming)
            try:
                synthesis_text = " ".join(spoken) if spoken else ""

                # Stage 2.10 Bug B: include cached refs in journal
                relevant_tickets_ns = []
                cached_refs_ns = plan.get("relevant_cached_tickets", []) or []
                for key in cached_refs_ns:
                    for t in self._ticket_cache or []:
                        if t.get("key") == key:
                            relevant_tickets_ns.append(t)
                            break
                seen_keys_ns = {
                    t.get("key") for t in relevant_tickets_ns if t.get("key")
                }
                for ft in fresh_tickets or []:
                    if ft.get("key") and ft.get("key") not in seen_keys_ns:
                        relevant_tickets_ns.append(ft)
                        seen_keys_ns.add(ft.get("key"))

                journal = getattr(self.agent, "journal", None)
                if journal is not None:
                    entry = {
                        "question": rewritten_query
                        if "rewritten_query" in locals()
                        else user_text,
                        "raw_question": user_text,
                        "synthesis_output": synthesis_text[:1500],
                        "jira_tickets": relevant_tickets_ns[:8],
                        "web_results": (web_results or [])[:4],
                        "question_type": plan.get("question_type", "general"),
                    }
                    await journal.add(entry)

                # Stage 2.5 fallback
                self._update_research_cache(
                    user_text=user_text,
                    plan=plan,
                    fresh_tickets=fresh_tickets,
                    web_results=web_results,
                    synthesis_output=synthesis_text,
                )
            except Exception as e:
                print(
                    f"[{ts()}] {self.tag} ⚠️  Journal/cache update failed (non-fatal): "
                    f"{type(e).__name__}: {e}"
                )

            for sent in spoken:
                if self.interrupt_event.is_set() or my_gen != self.generation:
                    return (spoken, True)
                await self._speak(sent, "research", my_gen)
            return (spoken, False)

    async def _search_with_fallback(self, query: str) -> list:
        """Exa → Brave fallback for web search. Returns normalized list of dicts.

        Tries Exa first (when enabled and not circuit-broken). On empty/error,
        falls back to Brave. Output is always a list[dict] with keys
        {title, url, content, published_date} ready for unified synthesis.

        Respects RESEARCH_PROVIDER:
          - "exa"   (or anything but "brave") → try Exa, fall back to Brave
          - "brave"                            → Brave only

        Returns [] if both fail / both disabled.
        """
        import time as _t

        # If user pinned RESEARCH_PROVIDER=brave, skip Exa entirely
        try_exa = RESEARCH_PROVIDER != "brave"

        # ── Try Exa ──
        if try_exa:
            try:
                exa_search = self.agent._get_exa_search()
                if exa_search.enabled and exa_search.consecutive_failures < 3:
                    t0 = _t.time()
                    exa_results = await exa_search.search(query, num_results=5)
                    print(
                        f"[{ts()}] {self.tag} ⏱ Exa: "
                        f"{(_t.time() - t0) * 1000:.0f}ms "
                        f"({len(exa_results) if exa_results else 0} results)"
                    )
                    if exa_results:
                        return exa_results
                else:
                    print(
                        f"[{ts()}] {self.tag} ⚠️  Exa disabled or circuit-broken "
                        f"({exa_search.consecutive_failures} failures)"
                    )
            except Exception as e:
                print(
                    f"[{ts()}] {self.tag} ⚠️  Exa error, falling back to Brave: "
                    f"{type(e).__name__}: {e}"
                )

        # ── Fall back to Brave (returns string, wrap as single dict) ──
        try:
            web_search = self.agent._get_web_search()
            t0 = _t.time()
            brave_text = await web_search.search(query)
            print(
                f"[{ts()}] {self.tag} ⏱ Brave: "
                f"{(_t.time() - t0) * 1000:.0f}ms "
                f"({len(brave_text) if brave_text else 0} chars)"
            )
            if brave_text:
                return [
                    {
                        "title": "Web search results",
                        "url": "",
                        "content": brave_text,
                        "published_date": "",
                    }
                ]
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  Brave error: {type(e).__name__}: {e}")

        return []

    # ── Stage 2.5: research context cache ────────────────────────────────────

    @staticmethod
    def _make_empty_cache():
        """Initial cache state — populated after each successful research turn."""
        return {
            "fetched_at": 0.0,  # time.time() when populated
            "topic_keywords": set(),  # significant words from the question
            "jira_tickets": [],  # list[dict] — fresh tickets from research
            "web_results": [],  # list[dict] — Exa/Brave results
            "synthesis_output": "",  # what Sam said (for "as I mentioned")
            "last_question_type": "general",  # planner question_type — drives TTL
        }

    # TTL by question type — how long cached context stays fresh
    _CACHE_TTL_BY_TYPE = {
        "jira_status": 30,  # status changes — short TTL
        "general": 300,  # 5 min default
        "feasibility": 1800,  # 30 min — stable reasoning
        "tech_switch": 1800,
        "best_practices": 1800,
        "internal_org": 3600,  # 1 hr — company info is stable
    }

    @staticmethod
    def _extract_topic_keywords(text: str) -> set:
        """Pure-Python keyword extraction — no LLM call.

        Returns a set of significant words (3+ chars, not stop-words),
        plus any ticket keys (e.g. SCRUM-244) found in the text.
        """
        import re as _re

        STOP_WORDS = {
            "the",
            "and",
            "but",
            "for",
            "with",
            "this",
            "that",
            "have",
            "has",
            "had",
            "are",
            "was",
            "were",
            "been",
            "being",
            "what",
            "when",
            "where",
            "which",
            "who",
            "whom",
            "whose",
            "why",
            "how",
            "all",
            "any",
            "both",
            "each",
            "few",
            "more",
            "most",
            "other",
            "some",
            "such",
            "than",
            "too",
            "very",
            "can",
            "will",
            "just",
            "should",
            "would",
            "could",
            "may",
            "might",
            "must",
            "ought",
            "shall",
            "tell",
            "about",
            "give",
            "show",
            "make",
            "did",
            "does",
            "doing",
            "from",
            "into",
            "onto",
            "upon",
            "over",
            "under",
            "out",
            "off",
            "yes",
            "yeah",
            "okay",
            "actually",
            "really",
            "sure",
            "right",
            "you",
            "your",
            "yours",
            "his",
            "her",
            "hers",
            "its",
            "our",
            "ours",
            "their",
            "theirs",
            "they",
            "them",
            "him",
            "she",
            "we",
        }

        if not text:
            return set()

        # Extract ticket keys (preserve case)
        ticket_keys = set(_re.findall(r"\b[A-Z]+-\d+\b", text.upper()))

        # Extract regular words
        words = _re.findall(r"\b[a-zA-Z]{3,}\b", text.lower())
        keywords = {w for w in words if w not in STOP_WORDS}

        return keywords | ticket_keys

    def _check_cache_hit(self, user_text: str):
        """Heuristic cache hit/miss decision — no LLM call, ~1ms.

        Returns (hit: bool, reason: str) — reason is logged for visibility.

        Hit conditions (all must be true):
          - Cache is populated (fetched_at > 0)
          - Cache is fresh (age < TTL for last_question_type)
          - User's question doesn't reference a NEW ticket key
          - User's question doesn't shift to a new topic (3+ new keywords)

        Conservative: when in doubt, miss. ESCALATE handles the false positives.
        """
        import time as _t
        import re as _re
        import os as _os

        # Allow runtime opt-out for debugging / A/B testing
        if _os.environ.get("RESEARCH_CACHE_ENABLED", "1").strip() == "0":
            return (False, "cache disabled by env")

        cache = self._research_cache
        fetched_at = cache.get("fetched_at", 0.0)
        if fetched_at <= 0:
            return (False, "cache empty")

        age = _t.time() - fetched_at
        last_type = cache.get("last_question_type", "general")
        ttl = self._CACHE_TTL_BY_TYPE.get(last_type, 300)
        if age > ttl:
            return (False, f"stale (age={age:.0f}s > ttl={ttl}s for {last_type})")

        # New ticket key check
        question_keys = set(_re.findall(r"\b[A-Z]+-\d+\b", user_text.upper()))
        cached_keys = {
            t.get("key") for t in cache.get("jira_tickets", []) if t.get("key")
        }
        new_keys = question_keys - cached_keys
        if new_keys:
            return (False, f"new ticket key(s): {sorted(new_keys)}")

        # Topic shift check (lenient — short follow-ups have few new words)
        current_kws = self._extract_topic_keywords(user_text)
        cached_kws = cache.get("topic_keywords", set())
        new_kws = current_kws - cached_kws
        if len(new_kws) >= 3 and len(current_kws) >= 4:
            return (False, f"topic shift ({len(new_kws)} new keywords)")

        return (True, f"hit (age={age:.0f}s, type={last_type})")

    async def _fast_pm_from_journal(
        self,
        user_text: str,
        rewritten_query: str,
        journal_entry: dict,
        context: str,
        my_gen: int,
        filler_duration: float,
        filler_relay_start: float,
    ):
        """Stage 2.6: fast PM using a journal entry as cached context.

        Mirrors _fast_pm_with_research_cache but pulls data from a single
        retrieved journal entry instead of self._research_cache. The entry
        was selected by semantic search on the rewritten query.

        Returns:
          (all_sentences, interrupted) on success
          None on ESCALATE or error → caller does fresh research

        ESCALATE detection on first 15 chars (same as Stage 2.5).
        """
        import time as _t
        import re as _re
        import asyncio

        try:
            # Stage S: unified PM_PROMPT_V2 (base + cached-context suffix).
            # Same output as the old FAST_PM_CACHED_PROMPT alias.
            from Agent import PM_PROMPT_V2_BASE, PM_PROMPT_V2_CACHED_SUFFIX
        except ImportError as e:
            print(f"[{ts()}] {self.tag} ⚠️  PM_PROMPT_V2 import failed: {e}")
            return None

        cache_age = max(0, int(_t.time() - journal_entry.get("fetched_at", 0)))

        # Format cached tickets
        tickets = journal_entry.get("jira_tickets") or []
        cached_tickets_text = "(no cached tickets)"
        if tickets:
            lines = []
            for t in tickets[:8]:
                key = t.get("key", "?")
                summary = (t.get("summary") or "").strip()[:120]
                status = t.get("status") or "?"
                lines.append(f"- {key} [{status}]: {summary}")
            if lines:
                cached_tickets_text = "\n".join(lines)

        # Format cached web results
        web = journal_entry.get("web_results") or []
        cached_web_text = "(no cached web results)"
        if web:
            web_lines = []
            for i, r in enumerate(web[:4], 1):
                title = (r.get("title") or "").strip()
                content = (r.get("content") or "").strip()[:300]
                if not content:
                    continue
                line = f"[{i}]"
                if title:
                    line += f" {title}"
                line += f": {content}"
                web_lines.append(line)
            if web_lines:
                cached_web_text = "\n\n".join(web_lines)

        cached_synthesis = (journal_entry.get("synthesis_output") or "").strip()
        if not cached_synthesis:
            cached_synthesis = "(no prior response on this topic)"

        # Conversation block — last 3 turns
        if context:
            conv_lines = [l for l in context.strip().split("\n") if l.strip()][-3:]
            conversation_block = (
                "\n".join(conv_lines) if conv_lines else "(start of call)"
            )
        else:
            conversation_block = "(start of call)"

        # Always-injected blocks (Stage 1)
        agenda_block = (
            self._build_agenda_block_for_prompt() or "(no fixed agenda for today)"
        )
        client_profile_block = (
            self._build_client_profile_block_for_prompt()
            or "(no client profile loaded)"
        )

        system = (PM_PROMPT_V2_BASE + "\n\n" + PM_PROMPT_V2_CACHED_SUFFIX).format(
            client_profile_block=client_profile_block,
            agenda_block=agenda_block,
            cached_tickets=cached_tickets_text,
            cached_web=cached_web_text,
            cached_synthesis=cached_synthesis,
            conversation_block=conversation_block,
            question=user_text,
            cache_age_sec=cache_age,
        )

        print(
            f"[{ts()}] {self.tag} 🚀 Fast PM (journal): prompt={len(system)} chars, "
            f"age={cache_age}s, tickets={len(tickets)}, web={len(web)}, "
            f"rewritten='{rewritten_query[:50]}'"
        )

        if self.interrupt_event.is_set() or my_gen != self.generation:
            return None

        t0 = _t.time()
        _is_gemini = self.mode == "client_call" and _GEMINI_AVAILABLE
        print(
            f"[{ts()}] {self.tag} fast-PM-journal "
            f"llm_used={'gemini' if _is_gemini else 'groq'} session_type={self.mode}"
        )
        try:
            if _is_gemini:
                stream = self.agent._gemini_stream(
                    system, [{"role": "user", "content": user_text}], 200, 0.5
                )
            else:
                stream = await self.agent.client.chat.completions.create(
                    model="llama-3.3-70b-versatile",
                    messages=[
                        {"role": "system", "content": system},
                        {"role": "user", "content": user_text},
                    ],
                    temperature=0.5,
                    max_tokens=200,
                    stream=True,
                )
        except Exception as e:
            print(
                f"[{ts()}] {self.tag} ⚠️  Fast PM (journal) stream open failed: "
                f"{type(e).__name__}: {e}"
            )
            return None

        research_queue: asyncio.Queue = asyncio.Queue()
        escalated = {"flag": False}
        escalate_re = _re.compile(r"^ESCALATE[\s.!?]*$", _re.IGNORECASE)

        async def _consume_and_stream():
            sentence_buf = ""
            full = ""
            escalate_window = ""
            window_done = False
            first_token = False
            sentence_count = 0

            try:
                async for _raw in stream:
                    token = (
                        _raw
                        if _is_gemini
                        else (_raw.choices[0].delta.content if _raw.choices else None)
                    )
                    if not token:
                        continue
                    full += token

                    if not first_token:
                        first_token = True
                        print(
                            f"[{ts()}] {self.tag} ⏱ Fast PM (journal) first token: "
                            f"{(_t.time() - t0) * 1000:.0f}ms"
                        )

                    if not window_done:
                        escalate_window += token
                        # Stage 2.10 Checkpoint 3: extend window to 80 chars to
                        # also detect stall phrases like "let me check on Jira".
                        # ESCALATE check still uses the strict first-15-char rule.
                        if len(escalate_window) >= 80 or "\n" in escalate_window:
                            window_done = True
                            stripped = escalate_window.strip()
                            # Strict ESCALATE check (first 15 chars only)
                            if escalate_re.match(stripped[:30]):
                                escalated["flag"] = True
                                print(
                                    f"[{ts()}] {self.tag} 🔄 Fast PM ESCALATE "
                                    f"at {(_t.time() - t0) * 1000:.0f}ms"
                                )
                                return
                            # Stage 2.10 Checkpoint 3: stall-phrase check
                            is_stall, stall_phrase = BotSession._is_stall_response(
                                stripped
                            )
                            if is_stall:
                                escalated["flag"] = True
                                print(
                                    f"[{ts()}] {self.tag} 🛑 Fast PM stall "
                                    f"detected: '{stall_phrase}' — "
                                    f"falling through to fresh research"
                                )
                                return
                            sentence_buf = escalate_window
                        else:
                            continue
                    else:
                        sentence_buf += token

                    while (
                        ". " in sentence_buf
                        or "? " in sentence_buf
                        or "! " in sentence_buf
                    ):
                        for sep in [". ", "? ", "! "]:
                            idx = sentence_buf.find(sep)
                            if idx != -1:
                                sentence = sentence_buf[: idx + 1].strip()
                                sentence_buf = sentence_buf[idx + 2 :]
                                if sentence:
                                    sentence_count += 1
                                    print(
                                        f"[{ts()}] {self.tag} ⏱ Fast PM (journal) "
                                        f"sentence {sentence_count}: "
                                        f"{(_t.time() - t0) * 1000:.0f}ms"
                                    )
                                    await research_queue.put(sentence)
                                break

                if sentence_buf.strip() and not escalated["flag"]:
                    await research_queue.put(sentence_buf.strip())

                if full and not escalated["flag"]:
                    self.agent.history.append({"role": "user", "content": user_text})
                    self.agent.history.append({"role": "assistant", "content": full})
                    if len(self.agent.history) > 6:
                        self.agent.history = self.agent.history[-6:]

            except asyncio.CancelledError:
                raise
            except Exception as e:
                print(
                    f"[{ts()}] {self.tag} ⚠️  Fast PM (journal) consume error: "
                    f"{type(e).__name__}: {e}"
                )
            finally:
                await research_queue.put(None)

        consume_task = asyncio.create_task(_consume_and_stream())

        if self._streaming_mode:
            all_sentences, interrupted = await self._stream_pipelined(
                research_queue,
                my_gen,
                cancel_task=consume_task,
                extra_duration=filler_duration,
                relay_start_override=filler_relay_start,
            )
            if escalated["flag"]:
                return None
            if not all_sentences and not interrupted:
                return None
            return (all_sentences, interrupted)
        else:
            spoken: list = []
            while True:
                try:
                    item = await asyncio.wait_for(research_queue.get(), timeout=15.0)
                except asyncio.TimeoutError:
                    break
                if item is None:
                    break
                spoken.append(item)

            if escalated["flag"] or not spoken:
                return None

            for sent in spoken:
                if self.interrupt_event.is_set() or my_gen != self.generation:
                    return (spoken, True)
                await self._speak(sent, "research", my_gen)
            return (spoken, False)

    async def _fast_pm_with_research_cache(
        self,
        user_text: str,
        context: str,
        my_gen: int,
        filler_duration: float,
        filler_relay_start: float,
    ):
        """Cache-hit fast lane: PM-style response from cached context.

        Uses Groq llama-3.3-70b (faster + cheaper than Azure 4o-mini for the
        relatively-small reasoning task of "use cached data to answer follow-up").

        ESCALATE detection: buffers first 15 chars of model output. If the
        response starts with "ESCALATE" (followed by punctuation or end), the
        fast path returns None — caller falls through to fresh research.

        Returns:
          (all_sentences, interrupted) tuple on success
          None on ESCALATE or any error → caller does fresh research

        Always-injected blocks (Stage 1 fix carries through):
          - client_profile_block (real names only, no Tom/Rohan)
          - agenda_block
        """
        import time as _t
        import re as _re
        import asyncio
        import sys as _sys

        try:
            # Stage S: unified PM_PROMPT_V2 (base + cached-context suffix).
            # Same output as the old FAST_PM_CACHED_PROMPT alias.
            from Agent import PM_PROMPT_V2_BASE, PM_PROMPT_V2_CACHED_SUFFIX
        except ImportError as e:
            print(f"[{ts()}] {self.tag} ⚠️  PM_PROMPT_V2 import failed: {e}")
            return None

        cache = self._research_cache
        cache_age = max(0, int(_t.time() - cache.get("fetched_at", 0)))

        # Format cached tickets
        cached_tickets_text = "(no cached tickets)"
        if cache.get("jira_tickets"):
            lines = []
            for t in cache["jira_tickets"][:8]:
                key = t.get("key", "?")
                summary = (t.get("summary") or "").strip()[:120]
                status = t.get("status") or "?"
                lines.append(f"- {key} [{status}]: {summary}")
            if lines:
                cached_tickets_text = "\n".join(lines)

        # Format cached web results
        cached_web_text = "(no cached web results)"
        if cache.get("web_results"):
            web_lines = []
            for i, r in enumerate(cache["web_results"][:4], 1):
                title = (r.get("title") or "").strip()
                content = (r.get("content") or "").strip()[:300]
                if not content:
                    continue
                line = f"[{i}]"
                if title:
                    line += f" {title}"
                line += f": {content}"
                web_lines.append(line)
            if web_lines:
                cached_web_text = "\n\n".join(web_lines)

        cached_synthesis = (cache.get("synthesis_output") or "").strip()
        if not cached_synthesis:
            cached_synthesis = "(no prior response in this conversation)"

        # Conversation block
        if context:
            conv_lines = [l for l in context.strip().split("\n") if l.strip()][-3:]
            conversation_block = (
                "\n".join(conv_lines) if conv_lines else "(start of call)"
            )
        else:
            conversation_block = "(start of call)"

        # Always-injected blocks (Stage 1 carries through)
        agenda_block = (
            self._build_agenda_block_for_prompt() or "(no fixed agenda for today)"
        )
        client_profile_block = (
            self._build_client_profile_block_for_prompt()
            or "(no client profile loaded)"
        )

        system = (PM_PROMPT_V2_BASE + "\n\n" + PM_PROMPT_V2_CACHED_SUFFIX).format(
            client_profile_block=client_profile_block,
            agenda_block=agenda_block,
            cached_tickets=cached_tickets_text,
            cached_web=cached_web_text,
            cached_synthesis=cached_synthesis,
            conversation_block=conversation_block,
            question=user_text,
            cache_age_sec=cache_age,
        )

        print(
            f"[{ts()}] {self.tag} 🚀 Fast PM cache: prompt={len(system)} chars, "
            f"age={cache_age}s, tickets={len(cache.get('jira_tickets', []))}, "
            f"web={len(cache.get('web_results', []))}"
        )

        if self.interrupt_event.is_set() or my_gen != self.generation:
            return None

        # ── Open LLM stream (Gemini for client_call, Groq for standup) ──
        t0 = _t.time()
        _is_gemini = self.mode == "client_call" and _GEMINI_AVAILABLE
        print(
            f"[{ts()}] {self.tag} fast-PM-cache "
            f"llm_used={'gemini' if _is_gemini else 'groq'} session_type={self.mode}"
        )
        try:
            if _is_gemini:
                stream = self.agent._gemini_stream(
                    system, [{"role": "user", "content": user_text}], 200, 0.5
                )
            else:
                stream = await self.agent.client.chat.completions.create(
                    model="llama-3.3-70b-versatile",
                    messages=[
                        {"role": "system", "content": system},
                        {"role": "user", "content": user_text},
                    ],
                    temperature=0.5,
                    max_tokens=200,
                    stream=True,
                )
        except Exception as e:
            print(
                f"[{ts()}] {self.tag} ⚠️  Fast PM stream open failed: "
                f"{type(e).__name__}: {e}"
            )
            return None

        # ── Consume + ESCALATE detect + sentence stream ──
        research_queue: asyncio.Queue = asyncio.Queue()
        escalated = {"flag": False}  # mutable so closure can flip it

        # Regex matches "ESCALATE" alone, or with trailing punctuation
        escalate_re = _re.compile(r"^ESCALATE[\s.!?]*$", _re.IGNORECASE)

        async def _consume_and_stream():
            sentence_buf = ""
            full = ""
            escalate_window = ""
            window_done = False
            first_token = False
            sentence_count = 0

            try:
                async for _raw in stream:
                    token = (
                        _raw
                        if _is_gemini
                        else (_raw.choices[0].delta.content if _raw.choices else None)
                    )
                    if not token:
                        continue
                    full += token

                    if not first_token:
                        first_token = True
                        print(
                            f"[{ts()}] {self.tag} ⏱ Fast PM first token: "
                            f"{(_t.time() - t0) * 1000:.0f}ms"
                        )

                    # ── Phase 1: ESCALATE detection on first 15 chars ──
                    if not window_done:
                        escalate_window += token
                        # Window closes at 15 chars OR on newline
                        if len(escalate_window) >= 15 or "\n" in escalate_window:
                            window_done = True
                            stripped = escalate_window.strip()
                            if escalate_re.match(stripped):
                                escalated["flag"] = True
                                print(
                                    f"[{ts()}] {self.tag} 🔄 Fast PM ESCALATE "
                                    f"detected at {(_t.time() - t0) * 1000:.0f}ms — "
                                    f"falling through to research"
                                )
                                return  # finally clause puts None
                            # Not escalate — start streaming sentences
                            sentence_buf = escalate_window
                        else:
                            continue  # still buffering ESCALATE window

                    else:
                        sentence_buf += token

                    # ── Phase 2: sentence streaming ──
                    while (
                        ". " in sentence_buf
                        or "? " in sentence_buf
                        or "! " in sentence_buf
                    ):
                        for sep in [". ", "? ", "! "]:
                            idx = sentence_buf.find(sep)
                            if idx != -1:
                                sentence = sentence_buf[: idx + 1].strip()
                                sentence_buf = sentence_buf[idx + 2 :]
                                if sentence:
                                    sentence_count += 1
                                    print(
                                        f"[{ts()}] {self.tag} ⏱ Fast PM sentence "
                                        f"{sentence_count}: "
                                        f"{(_t.time() - t0) * 1000:.0f}ms"
                                    )
                                    await research_queue.put(sentence)
                                break

                # Stream finished — flush remainder
                if sentence_buf.strip() and not escalated["flag"]:
                    await research_queue.put(sentence_buf.strip())

                # Update cache + history with this PM response
                if full and not escalated["flag"]:
                    self._research_cache["synthesis_output"] = full
                    self.agent.history.append({"role": "user", "content": user_text})
                    self.agent.history.append({"role": "assistant", "content": full})
                    if len(self.agent.history) > 6:
                        self.agent.history = self.agent.history[-6:]
            except asyncio.CancelledError:
                raise
            except Exception as e:
                print(
                    f"[{ts()}] {self.tag} ⚠️  Fast PM consume error: "
                    f"{type(e).__name__}: {e}"
                )
            finally:
                await research_queue.put(None)

        consume_task = asyncio.create_task(_consume_and_stream())

        # ── Stream sentences to TTS ──
        if self._streaming_mode:
            all_sentences, interrupted = await self._stream_pipelined(
                research_queue,
                my_gen,
                cancel_task=consume_task,
                extra_duration=filler_duration,
                relay_start_override=filler_relay_start,
            )

            if escalated["flag"]:
                return None

            if not all_sentences and not interrupted:
                # Empty stream + no interrupt — treat as failure
                return None

            return (all_sentences, interrupted)
        else:
            spoken: list = []
            while True:
                try:
                    item = await asyncio.wait_for(research_queue.get(), timeout=15.0)
                except asyncio.TimeoutError:
                    break
                if item is None:
                    break
                spoken.append(item)

            if escalated["flag"] or not spoken:
                return None

            for sent in spoken:
                if self.interrupt_event.is_set() or my_gen != self.generation:
                    return (spoken, True)
                await self._speak(sent, "research", my_gen)
            return (spoken, False)

    def _update_research_cache(
        self,
        user_text: str,
        plan: dict,
        fresh_tickets: list,
        web_results: list,
        synthesis_output: str,
    ):
        """Populate the research cache after a successful research turn.

        Called from _unified_research_v2 after streaming completes. Replaces
        the cache wholesale (latest research wins) — multi-topic merging is
        future work.
        """
        import time as _t

        # Topic keywords from the question that triggered this research
        topic_kws = self._extract_topic_keywords(user_text)

        # Combine cached + fresh tickets, dedupe by key
        all_tickets_by_key = {}
        for t in self._ticket_cache or []:
            if t.get("key"):
                all_tickets_by_key[t["key"]] = t
        for ft in fresh_tickets or []:
            if ft.get("key"):
                all_tickets_by_key[ft["key"]] = ft

        # Keep only the most relevant — cap to avoid prompt bloat
        relevant = []
        cached_refs = set(plan.get("relevant_cached_tickets", []))
        for k, t in all_tickets_by_key.items():
            if k in cached_refs or t in (fresh_tickets or []):
                relevant.append(t)
        relevant = relevant[:8]

        self._research_cache = {
            "fetched_at": _t.time(),
            "topic_keywords": topic_kws,
            "jira_tickets": relevant,
            "web_results": (web_results or [])[:4],
            "synthesis_output": (synthesis_output or "").strip()[:1500],
            "last_question_type": plan.get("question_type", "general"),
        }

        print(
            f"[{ts()}] {self.tag} 💾 Cache updated: "
            f"tickets={len(self._research_cache['jira_tickets'])}, "
            f"web={len(self._research_cache['web_results'])}, "
            f"synthesis={len(self._research_cache['synthesis_output'])} chars, "
            f"type={self._research_cache['last_question_type']}, "
            f"keywords={len(topic_kws)}"
        )

    # ── Jira handler ──────────────────────────────────────────────────────────

    async def _handle_jira_read(self, text, context, my_gen):
        try:
            context_block = ""
            if context:
                lines = [l for l in context.strip().split("\n") if l.strip()][-3:]
                if lines:
                    context_block = "Recent conversation:\n" + "\n".join(lines) + "\n\n"

            t0 = time.time()
            response = await self.agent.client.chat.completions.create(
                model=self.agent.model,
                messages=[
                    {
                        "role": "system",
                        "content": JIRA_INTENT_PROMPT.format(
                            project_key=self.jira.project,
                            text=text,
                            context_block=context_block,
                        ),
                    },
                    {"role": "user", "content": text},
                ],
                temperature=0.0,
                max_tokens=30,
            )
            intent = response.choices[0].message.content.strip()
            print(
                f'[{ts()}] {self.tag} 🎫 Intent: "{intent}" ({(time.time() - t0) * 1000:.0f}ms)'
            )

            if intent == "MY_TICKETS":
                t_fetch = time.time()
                tickets = await self.jira.get_my_tickets()
                print(
                    f"[{ts()}] {self.tag} ⏱ [JIRA-API] get_my_tickets: {(time.time() - t_fetch) * 1000:.0f}ms ({len(tickets)} tickets)"
                )
                return {"tickets": tickets, "count": len(tickets)}
            elif intent == "SPRINT_STATUS":
                t_fetch = time.time()
                result = await self.jira.get_sprint_status()
                print(
                    f"[{ts()}] {self.tag} ⏱ [JIRA-API] get_sprint_status: {(time.time() - t_fetch) * 1000:.0f}ms"
                )
                return result
            elif intent.startswith("TICKET:"):
                ids = _re.findall(r"[A-Z]+-\d+", intent.split(":", 1)[1])
                if not ids:
                    t_fetch = time.time()
                    result = {"tickets": await self.jira.get_my_tickets(), "count": 0}
                    print(
                        f"[{ts()}] {self.tag} ⏱ [JIRA-API] get_my_tickets (fallback): {(time.time() - t_fetch) * 1000:.0f}ms"
                    )
                    return result
                if len(ids) == 1:
                    t_fetch = time.time()
                    result = await self.jira.get_ticket(ids[0])
                    print(
                        f"[{ts()}] {self.tag} ⏱ [JIRA-API] get_ticket({ids[0]}): {(time.time() - t_fetch) * 1000:.0f}ms"
                    )
                    return result
                t_fetch = time.time()
                results = []
                for tid in ids[:5]:
                    try:
                        results.append(await self.jira.get_ticket(tid))
                    except Exception:
                        pass
                print(
                    f"[{ts()}] {self.tag} ⏱ [JIRA-API] get_ticket × {len(ids[:5])}: {(time.time() - t_fetch) * 1000:.0f}ms"
                )
                return {"tickets": results, "count": len(results)}
            elif intent.startswith("TRANSITION:"):
                parts = intent.split(":")
                if len(parts) >= 3:
                    tid, status = parts[1].strip(), parts[2].strip()
                    if not _re.match(r"^[A-Z]+-\d+$", tid):
                        return {"error": f"Invalid ID: {tid}"}
                    try:
                        r = await self.jira.transition_ticket(tid, status)
                        if r.get("action") == "already_done":
                            return {
                                "action": "already_done",
                                "ticket": tid,
                                "message": f"{tid} already at '{r['already_at']}'.",
                            }
                        return {
                            "action": "transition",
                            "ticket": tid,
                            "new_status": r["new_status"],
                        }
                    except JiraTransitionError as e:
                        return {
                            "action": "transition_error",
                            "ticket": tid,
                            "error": str(e),
                        }
            elif intent.startswith("SEARCH:"):
                q = intent.split(":", 1)[1].strip()
                tickets = await self.jira.search_text(q, max_results=5)
                return (
                    {"tickets": tickets, "count": len(tickets)}
                    if tickets
                    else {"error": f"No tickets for '{q}'."}
                )
            elif intent.startswith("CREATE:"):
                # OPTION C: DEFERRED CREATION
                # Don't create the ticket now. Azure at meeting-end will create
                # high-quality tickets with full transcript context. We just
                # record the user's intent here and return an acknowledgment.
                #
                # Why: mid-meeting creation often produces garbage titles
                # ("Ticket Optimization" when user meant 4 specific tickets).
                # Azure sees full discussion and extracts proper titles + counts.
                summary_hint = intent.split(":", 1)[1].strip()
                if not summary_hint:
                    return {"error": "No summary hint provided"}

                try:
                    # Record the user's intent for Azure to process at meeting-end
                    self._pending_creation_intents.append(
                        {
                            "user_said": text,
                            "extracted_summary": summary_hint,
                            "at_time": time.strftime("%H:%M:%S", time.gmtime()),
                        }
                    )
                    count = len(self._pending_creation_intents)
                    print(
                        f"[{ts()}] {self.tag} 📝 Creation intent #{count} recorded: "
                        f'"{summary_hint}" (will be created post-meeting)'
                    )

                    # Return acknowledgment data that the research stream uses
                    # to craft a natural "I'll log that" response. The specific
                    # wording is in RESEARCH_PROMPT via Sam's natural-language LLM.
                    return {
                        "action": "creation_deferred",
                        "user_request": text,
                        "intent_summary": summary_hint,
                        "pending_count": count,
                        "note": (
                            "Ticket will be created after the meeting with full "
                            "context. Acknowledge naturally without inventing a "
                            "ticket ID. Say you'll log it post-meeting."
                        ),
                    }
                except Exception as e:
                    print(f"[{ts()}] {self.tag} ⚠️  Intent recording failed: {e}")
                    return {"action": "create_failed", "error": str(e)}
            else:
                return {"tickets": await self.jira.get_my_tickets(), "count": 0}
        except Exception as e:
            print(f"[{ts()}] {self.tag} ⚠️  Jira error: {e}")
            return {"error": str(e)}

    # ── Main pipeline ─────────────────────────────────────────────────────────

    async def _process(self, text, speaker, t0, generation=0):
        if self.speaking:
            return
        self.speaking = True
        self.interrupt_event.clear()
        my_gen = generation
        is_direct = self._is_direct_address(text)

        try:
            context = "\n".join(self.convo_history)
            t1 = time.time()
            mode = "streaming" if self._streaming_mode else "fallback"
            print(f"[{ts()}] {self.tag} 🔊 Mode: {mode}")

            # ── Trigger: skip for direct address ──────────────────────
            if is_direct:
                print(f"  ⚡ Direct address — trigger skipped")
                should = True
            else:
                trigger_task = asyncio.create_task(
                    self.trigger.should_respond(
                        text,
                        speaker,
                        context,
                        [e["text"] for e in self.agent.rag._entries[-20:]],
                    )
                )
                should = await trigger_task

            if not should:
                return

            # Determine if immediate filler is needed
            filler_duration = 0.0
            filler_relay_start = 0.0
            filler_played = False

            if self._needs_acknowledgement_filler(text, self._flux_latest_sentiment):
                chosen_filler = self._select_acknowledgement_filler(
                    text, self._flux_latest_sentiment
                )
                print(
                    f'[{ts()}] {self.tag} ⚡ Immediate low-latency acknowledgement filler: "{chosen_filler}"'
                )

                # Cancel the pre-fired filler task since we are playing the low-latency filler now
                if self._pending_filler_task and not self._pending_filler_task.done():
                    self._pending_filler_task.cancel()
                    try:
                        await self._pending_filler_task
                    except (asyncio.CancelledError, Exception):
                        pass
                    self._pending_filler_task = None
                    print(
                        f"[{ts()}] {self.tag} 🚫 Cancelled pre-fired filler task (using immediate low-latency filler)"
                    )

                filler_relay_start = time.time()
                if self._streaming_mode:
                    filler_duration = await self._stream_and_relay(
                        chosen_filler, my_gen
                    )
                    if filler_duration > 0:
                        filler_played = True
                else:
                    await self._speak(chosen_filler, "immediate-filler", my_gen)
                    filler_duration = 0.0
                    filler_relay_start = 0.0
                    filler_played = True

                if self.interrupt_event.is_set():
                    return

            # ── Speculative execution: start router + PM LLM + dynamic filler in parallel ──
            router_task = asyncio.create_task(self.agent._route(text, context))

            # Speculatively start PM LLM (80% of queries go to PM)
            speculative_queue = asyncio.Queue()
            # F2: prepend empathy instruction when session mood is negative
            _mem = self._memory_full
            if self._empathy_mode:
                _mem = (
                    "[EMPATHY_MODE ACTIVE] Acknowledge the user's difficulty in one short "
                    "sentence before answering.\n\n" + _mem
                )
            speculative_llm = asyncio.create_task(
                self.agent.stream_sentences_to_queue(
                    text,
                    context,
                    speculative_queue,
                    memory_context=_mem,
                )
            )

            # Ship 4: Dynamic filler is now PRE-FIRED at EOT-decides-RESPOND
            # (in self._pending_filler_task), running in parallel with NLU,
            # Policy, Router. We just consume it here. By router time, the
            # task has been running ~1.5-2s — almost always ready.
            #
            # Pull it from session state and clear the slot so subsequent
            # turns don't see stale data.
            filler_task = self._pending_filler_task
            self._pending_filler_task = None

            route = await router_task
            print(f"[{ts()}] {self.tag} Route: [{route}] ({elapsed(t1)})")

            # ── [RESEARCH] — cancel speculative LLM, parallel research, Azure stream ──
            if route == "RESEARCH":
                speculative_llm.cancel()
                try:
                    await speculative_llm
                except (asyncio.CancelledError, Exception):
                    pass

                # ── Dynamic filler: use if pre-fired task is ready + valid ──
                # Wait briefly (up to 800ms) if task is still running. Combined
                # with the head start from EOT-RESPOND, total budget is ~2-3s
                # which fits well within Groq's typical 600-1500ms latency.
                self.searching = True
                if not filler_played:
                    dynamic_filler_text = None
                    if filler_task is not None:
                        if filler_task.done():
                            # Task finished while pipeline was running — best case
                            try:
                                result = filler_task.result()
                                if result:  # None = generation failed/invalid
                                    dynamic_filler_text = result
                            except (asyncio.CancelledError, Exception):
                                pass
                        else:
                            # Still running — wait briefly to give it a chance
                            try:
                                result = await asyncio.wait_for(
                                    filler_task, timeout=0.8
                                )
                                if result:
                                    dynamic_filler_text = result
                            except asyncio.TimeoutError:
                                # Took too long — kill it, fall back to hardcoded
                                filler_task.cancel()
                                try:
                                    await filler_task
                                except (asyncio.CancelledError, Exception):
                                    pass
                            except (asyncio.CancelledError, Exception):
                                pass

                    filler = (
                        dynamic_filler_text
                        if dynamic_filler_text
                        else random.choice(FILLERS)
                    )
                    if dynamic_filler_text:
                        print(f"[{ts()}] {self.tag} 🎨 Dynamic filler")
                    else:
                        print(f"[{ts()}] {self.tag} 📋 Hardcoded filler")

                    filler_relay_start = time.time()
                    if self._streaming_mode:
                        filler_duration = await self._stream_and_relay(filler, my_gen)
                        if filler_duration <= 0 or self.interrupt_event.is_set():
                            return
                    else:
                        await self._speak(filler, "research-filler", my_gen)
                        filler_duration = 0
                        filler_relay_start = 0
                        if self.interrupt_event.is_set():
                            return
                else:
                    print(
                        f"[{ts()}] {self.tag} 🚀 Bypassing legacy research filler (low-latency filler already played)"
                    )

                # Research starts NOW — while filler is still playing
                import time as _time

                t_research = _time.time()

                # ═══════════════════════════════════════════════════════════════
                # UNIFIED RESEARCH FLOW (Feature 4 + Stage 2)
                # Three-tier fallback chain:
                #   1. Stage 2: unified-v2 research path (RESEARCH_ARCHITECTURE)
                #   2. Feature 4: unified research flow (USE_UNIFIED_RESEARCH)
                #   3. Legacy: parallel Jira+web+Azure (always available)
                # Each tier returns None on failure → next tier runs.
                # ═══════════════════════════════════════════════════════════════
                used_unified = False
                all_sentences: list = []
                interrupted = False

                # ── Tier 1: Stage 2 unified-v2 research path ──
                if RESEARCH_ARCHITECTURE == "unified":
                    try:
                        v2_response = await self._unified_research_v2(
                            user_text=text,
                            context=context,
                            my_gen=my_gen,
                            filler_duration=filler_duration,
                            filler_relay_start=filler_relay_start,
                        )
                        if v2_response is not None:
                            all_sentences, interrupted = v2_response
                            used_unified = True
                            research_ms = (_time.time() - t_research) * 1000
                            print(
                                f"[{ts()}] {self.tag} 🔬 Unified-v2 research: "
                                f"{research_ms:.0f}ms"
                            )
                    except __import__("asyncio").CancelledError:
                        raise
                    except Exception as e:
                        print(
                            f"[{ts()}] {self.tag} ⚠️  Unified-v2 failed, "
                            f"falling back: {e}"
                        )

                # ── Tier 2: existing USE_UNIFIED_RESEARCH path (Feature 4) ──
                if not used_unified and USE_UNIFIED_RESEARCH:
                    try:
                        unified_response = await self._unified_research_flow(
                            user_text=text,
                            context=context,
                            my_gen=my_gen,
                            filler_duration=filler_duration,
                            filler_relay_start=filler_relay_start,
                        )
                        if unified_response is not None:
                            all_sentences, interrupted = unified_response
                            used_unified = True
                            research_ms = (_time.time() - t_research) * 1000
                            print(
                                f"[{ts()}] {self.tag} 🔬 Unified research: {research_ms:.0f}ms"
                            )
                    except asyncio.CancelledError:
                        raise
                    except Exception as e:
                        print(
                            f"[{ts()}] {self.tag} ⚠️  Unified research failed, falling back: {e}"
                        )

                # ── Legacy path: Jira action + web search + Azure synthesis ──
                if not used_unified:

                    async def _jira_action():
                        """Detect and execute Jira operations. Updates cache after writes."""
                        t_jira_start = _time.time()
                        print(f"[{ts()}] {self.tag} ⏱ [JIRA] task started")
                        if not self.jira or not self.jira.enabled:
                            print(
                                f"[{ts()}] {self.tag} ⏱ [JIRA] skipped (not enabled): {(_time.time() - t_jira_start) * 1000:.0f}ms"
                            )
                            return "(no Jira)"
                        try:
                            t_intent = _time.time()
                            result = await self._handle_jira_read(text, context, my_gen)
                            print(
                                f"[{ts()}] {self.tag} ⏱ [JIRA] _handle_jira_read: {(_time.time() - t_intent) * 1000:.0f}ms"
                            )
                            if not result:
                                print(
                                    f"[{ts()}] {self.tag} ⏱ [JIRA] total (no action): {(_time.time() - t_jira_start) * 1000:.0f}ms"
                                )
                                return "(no action needed)"

                            t_post = _time.time()
                            if isinstance(result, dict):
                                action = result.get("action", "")
                                if action == "transition":
                                    tid = result.get("ticket", "")
                                    new_status = result.get("new_status", "")
                                    for t in self._ticket_cache:
                                        if t["key"] == tid:
                                            t["status"] = new_status
                                            break
                                    self._rebuild_jira_context()
                                elif "key" in result and result["key"] not in [
                                    t["key"] for t in self._ticket_cache
                                ]:
                                    self._update_ticket_cache(result)
                            print(
                                f"[{ts()}] {self.tag} ⏱ [JIRA] post-processing: {(_time.time() - t_post) * 1000:.0f}ms"
                            )

                            t_serial = _time.time()
                            out = json.dumps(result, indent=2, default=str)[:800]
                            print(
                                f"[{ts()}] {self.tag} ⏱ [JIRA] JSON serialize: {(_time.time() - t_serial) * 1000:.0f}ms"
                            )
                            print(
                                f"[{ts()}] {self.tag} ⏱ [JIRA] TOTAL: {(_time.time() - t_jira_start) * 1000:.0f}ms"
                            )
                            return out
                        except Exception as e:
                            print(f"[{ts()}] {self.tag} ⚠️  Jira action: {e}")
                            print(
                                f"[{ts()}] {self.tag} ⏱ [JIRA] failed after: {(_time.time() - t_jira_start) * 1000:.0f}ms"
                            )
                            return "(Jira action failed)"

                    async def _web_search():
                        t_web_start = _time.time()
                        print(f"[{ts()}] {self.tag} ⏱ [WEB] task started")
                        try:
                            t_hint = _time.time()
                            ticket_hint = self._get_ticket_context_for_search()
                            print(
                                f"[{ts()}] {self.tag} ⏱ [WEB] ticket_hint built: {(_time.time() - t_hint) * 1000:.0f}ms"
                            )

                            t_query = _time.time()
                            query = await self.agent._to_english_search_query(
                                text, context, ticket_hint
                            )
                            print(
                                f'[{ts()}] {self.tag} ⏱ [WEB] query optimizer LLM: {(_time.time() - t_query) * 1000:.0f}ms → "{query[:50]}"'
                            )

                            if query.upper().strip() == "SKIP":
                                print(
                                    f"[{ts()}] {self.tag} 🔍 Web search: SKIPPED (not needed)"
                                )
                                print(
                                    f"[{ts()}] {self.tag} ⏱ [WEB] TOTAL (skipped): {(_time.time() - t_web_start) * 1000:.0f}ms"
                                )
                                return (
                                    "(web search skipped — not relevant for this query)"
                                )

                            t_serp = _time.time()
                            results = await self.agent._get_web_search().search(query)
                            print(
                                f"[{ts()}] {self.tag} ⏱ [WEB] SerpAPI call: {(_time.time() - t_serp) * 1000:.0f}ms ({len(results) if results else 0} chars)"
                            )
                            print(
                                f"[{ts()}] {self.tag} ⏱ [WEB] TOTAL: {(_time.time() - t_web_start) * 1000:.0f}ms"
                            )
                            return results[:800] if results else "(no web results)"
                        except Exception as e:
                            print(
                                f"[{ts()}] {self.tag} ⏱ [WEB] failed after: {(_time.time() - t_web_start) * 1000:.0f}ms — {type(e).__name__}: {e}"
                            )
                            return "(web search failed)"

                    t_parallel_start = _time.time()
                    action_task = asyncio.create_task(_jira_action())
                    web_task = asyncio.create_task(_web_search())
                    print(
                        f"[{ts()}] {self.tag} ⏱ [PARALLEL] tasks scheduled — waiting for both..."
                    )

                    t_await_jira = _time.time()
                    jira_action = await action_task
                    print(
                        f"[{ts()}] {self.tag} ⏱ [PARALLEL] jira_action awaited (completed): {(_time.time() - t_await_jira) * 1000:.0f}ms wait"
                    )

                    t_await_web = _time.time()
                    web_results = await web_task
                    print(
                        f"[{ts()}] {self.tag} ⏱ [PARALLEL] web_results awaited (completed): {(_time.time() - t_await_web) * 1000:.0f}ms wait"
                    )

                    research_ms = (_time.time() - t_research) * 1000
                    parallel_ms = (_time.time() - t_parallel_start) * 1000
                    print(
                        f"[{ts()}] {self.tag} ⏱ [PARALLEL] both tasks done: {parallel_ms:.0f}ms total"
                    )
                    print(
                        f"[{ts()}] {self.tag} 🔬 Legacy research: {research_ms:.0f}ms"
                    )

                    if self.interrupt_event.is_set() or my_gen != self.generation:
                        return

                    # Stream from Azure 4o-mini (pipelined — no gap between sentences)
                    research_queue = asyncio.Queue()
                    research_stream = asyncio.create_task(
                        self.agent.stream_research_to_queue(
                            user_text=text,
                            jira_context=self._jira_context,
                            related_tickets="(all tickets included in project context above)",
                            web_results=web_results,
                            jira_action=jira_action,
                            conversation=context,
                            azure_extractor=self.azure_extractor,
                            queue=research_queue,
                            memory_context=self._memory_full,
                        )
                    )

                    if self._streaming_mode:
                        all_sentences, interrupted = await self._stream_pipelined(
                            research_queue,
                            my_gen,
                            cancel_task=research_stream,
                            extra_duration=filler_duration,
                            relay_start_override=filler_relay_start,
                        )
                    else:
                        all_sentences = []
                        while True:
                            try:
                                item = await asyncio.wait_for(
                                    research_queue.get(), timeout=30.0
                                )
                            except asyncio.TimeoutError:
                                break
                            if item is None:
                                break
                            all_sentences.append(item)
                        for sent in all_sentences:
                            await self._speak(sent, "research", my_gen)

                # ── Post-response handling (both paths) ──
                if interrupted and all_sentences:
                    self._log_sam(" ".join(all_sentences) + " [interrupted]")
                    self.trigger.mark_responded()
                    return

                full_text = " ".join(all_sentences)
                if full_text:
                    self._log_sam(full_text)
                    self.trigger.mark_responded()

            # ── [PM] — use speculative LLM (already running!) ──
            else:
                # Cancel pre-fired dynamic filler task (not used in PM path).
                # This costs ~1 wasted Groq call per PM turn, accepted as
                # trade-off for contextual fillers on RESEARCH turns.
                if filler_task is not None and not filler_task.done():
                    filler_task.cancel()
                    try:
                        await filler_task
                    except (asyncio.CancelledError, Exception):
                        pass
                    print(
                        f"[{ts()}] {self.tag} 🚫 Discarded pre-fired filler "
                        f"(PM route — not needed)"
                    )
                # LLM has been running since before router finished
                # Sentences may already be in the queue

                if self._streaming_mode:
                    all_sentences, interrupted = await self._stream_pipelined(
                        speculative_queue,
                        my_gen,
                        cancel_task=speculative_llm,
                        extra_duration=filler_duration,
                        relay_start_override=filler_relay_start,
                    )
                    if interrupted and all_sentences:
                        self._log_sam(" ".join(all_sentences) + " [interrupted]")
                        self.trigger.mark_responded()
                        return
                else:
                    # Fallback mode: collect all then speak
                    all_sentences = []
                    while True:
                        if self.interrupt_event.is_set() or my_gen != self.generation:
                            speculative_llm.cancel()
                            return
                        try:
                            item = await asyncio.wait_for(
                                speculative_queue.get(), timeout=15.0
                            )
                        except asyncio.TimeoutError:
                            break
                        if item is None:
                            break
                        if item == "__FLUSH__":
                            continue
                        all_sentences.append(item)

                    if all_sentences:
                        if len(all_sentences) == 1:
                            await self._speak(all_sentences[0], "single", my_gen)
                        else:
                            from pydub import AudioSegment as _AS

                            parts = []
                            for s in all_sentences:
                                try:
                                    async with self.server._tts_semaphore:
                                        parts.append(await self.speaker._synthesise(s))
                                except Exception:
                                    pass
                            if parts:
                                combined = (
                                    parts[0]
                                    if len(parts) == 1
                                    else self._combine_audio(parts)
                                )
                                b64 = base64.b64encode(combined).decode("utf-8")
                                try:
                                    await self.speaker.stop_audio()
                                except Exception:
                                    pass
                                await self.speaker._inject_into_meeting(b64)
                                self.audio_playing = True
                                dur = get_duration_ms(combined)
                                try:
                                    await asyncio.wait_for(
                                        self.interrupt_event.wait(), timeout=dur / 1000
                                    )
                                except asyncio.TimeoutError:
                                    pass
                                self.audio_playing = False

                if all_sentences:
                    print(f"[{ts()}] {self.tag} 📊 TOTAL: {elapsed(t0)}")
                    self._log_sam(" ".join(all_sentences))
                    self.trigger.mark_responded()

                    # Client mode contextual reprompt: classify Sam's intent
                    # based on his response, then start the 20s silence timer.
                    # If user speaks before then, timer cancels (see transcript handlers).
                    if (
                        self.mode != "standup"
                        and not self._user_left
                        and not self.was_interrupted
                    ):
                        sam_final = " ".join(all_sentences)
                        self._last_sam_intent = self._classify_sam_intent(sam_final)
                        self._start_client_silence_timer()

        except asyncio.CancelledError:
            pass
        except Exception as e:
            import traceback

            print(f"[{ts()}] {self.tag} ❌ Error: {e}")
            traceback.print_exc()
        finally:
            self.audio_playing = False
            self.speaking = False
            self.searching = False

    def _combine_audio(self, audio_list):
        from pydub import AudioSegment
        import io

        combined = AudioSegment.empty()
        for ab in audio_list:
            combined += AudioSegment.from_file(io.BytesIO(ab), format="mp3")
        output = io.BytesIO()
        combined.export(output, format="mp3", bitrate="192k")
        return output.getvalue()


# ══════════════════════════════════════════════════════════════════════════════
# WebSocketServer
# ══════════════════════════════════════════════════════════════════════════════


class WebSocketServer:
    def __init__(self, port=8000):
        self.port = port
        self.sessions = {}
        self._tts_semaphore = asyncio.Semaphore(4)
        self._interrupt_ack_audio = []
        self.on_session_removed = (
            None  # Callback: fn(session) — called when session is cleaned up
        )
        self.debug_save_audio = os.environ.get("DEBUG_SAVE_AUDIO", "").lower() in (
            "1",
            "true",
            "yes",
        )
        self.app = web.Application()
        self.app.router.add_get("/ws/{session_id}", self.handle_websocket)
        self.app.router.add_get("/audio/{session_id}", self.handle_audio_ws)
        self.app.router.add_get("/health", self.handle_health)

    async def handle_health(self, request):
        return web.json_response({"status": "ok", "sessions": len(self.sessions)})

    async def handle_websocket(self, request):
        """Recall.ai transcript/events WebSocket."""
        session_id = request.match_info.get("session_id", "")
        session = self.sessions.get(session_id)
        if not session:
            return web.Response(status=404)
        ws = web.WebSocketResponse(heartbeat=30)
        await ws.prepare(request)
        print(f"[{ts()}] {session.tag} ✅ Recall.ai WebSocket connected")
        try:
            async for msg in ws:
                if msg.type == aiohttp.WSMsgType.TEXT:
                    try:
                        await session.handle_event(msg.data)
                    except Exception as e:
                        print(f"[{ts()}] {session.tag} ⚠️  Event error: {e}")
                elif msg.type in (
                    aiohttp.WSMsgType.ERROR,
                    aiohttp.WSMsgType.CLOSE,
                    aiohttp.WSMsgType.CLOSING,
                ):
                    break
        except Exception as e:
            print(f"[{ts()}] {session.tag} WS error: {e}")
        finally:
            print(f"[{ts()}] {session.tag} WebSocket disconnected")
            await self.remove_session(session_id)
        return ws

    async def handle_audio_ws(self, request):
        """Output Media audio page WebSocket — receives PCM chunks to play."""
        session_id = request.match_info.get("session_id", "")
        session = self.sessions.get(session_id)
        if not session:
            return web.Response(status=404, text="Session not found")
        ws = web.WebSocketResponse(heartbeat=20)
        await ws.prepare(request)
        session.audio_ws = ws
        print(f"[{ts()}] {session.tag} 🔊 Audio page connected (streaming mode ON)")
        try:
            async for msg in ws:
                pass  # Audio page doesn't send us data
        except Exception:
            pass
        finally:
            session.audio_ws = None
            print(f"[{ts()}] {session.tag} 🔇 Audio page disconnected (fallback mode)")
        return ws

    def create_session(self, session_id, bot_id):
        session = BotSession(session_id, bot_id, self)
        self.sessions[session_id] = session
        print(f"[{ts()}] 📦 Session created: {session_id[:12]}")
        return session

    async def remove_session(self, session_id):
        session = self.sessions.pop(session_id, None)
        if session:
            await session.cleanup()
            # Notify server.py to clean up active_bots
            if self.on_session_removed and session.username:
                try:
                    self.on_session_removed(session)
                except Exception as e:
                    print(f"[{ts()}] ⚠️  on_session_removed callback failed: {e}")
            print(f"[{ts()}] 🗑️  Session removed: {session_id[:12]}")

    async def start(self):
        print(f"[{ts()}] Pre-baking interrupt ack audio...")
        temp = CartesiaSpeaker(bot_id=None)
        await temp.warmup()
        for phrase in _INTERRUPT_ACKS:
            try:
                async with self._tts_semaphore:
                    audio = await temp._synthesise(phrase)
                self._interrupt_ack_audio.append((phrase, audio))
            except Exception as e:
                print(f"[{ts()}] ⚠️  Pre-bake failed: {e}")

        await temp.close()
        print(f"[{ts()}] ✅ {len(self._interrupt_ack_audio)} acks pre-baked")

        runner = web.AppRunner(self.app)
        await runner.setup()
        site = web.TCPSite(runner, "0.0.0.0", self.port)
        await site.start()
        print(f"[{ts()}] WebSocket ready on ws://0.0.0.0:{self.port}/ws/{{session_id}}")
        print(f"[{ts()}] Audio relay on ws://0.0.0.0:{self.port}/audio/{{session_id}}")
        print(f"[{ts()}] Health: http://localhost:{self.port}/health\n")
