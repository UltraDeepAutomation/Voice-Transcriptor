"""Deepgram Nova-3 live WebSocket streaming — single source of truth.

Proxies raw PCM16 mono audio from the app's own WebSocket into Deepgram's
real streaming API (wss://api.deepgram.com/v1/listen) and normalizes the
Deepgram ``Results`` events into the app's canonical live protocol:

    {"type": "segments", "segments": [...], "is_final": bool}
    {"type": "interim",  "segment": {...}}
    {"type": "final",    "text": str, "segments": [...], "durationSec": float}
    {"type": "error",    "error": str, "fatal": bool}

Lifecycle is session-scoped: ``connect()`` opens the upstream socket and
starts a background task that drains Deepgram events into an internal
queue. ``send_pcm()`` forwards audio; ``events()`` is the async iterator
consumers iterate to receive normalized events; ``finalize()`` tells
Deepgram to flush and returns the accumulated final transcript.

Production-grade features:

* **KeepAlive frames** — a background task emits ``{"type":"KeepAlive"}``
  on the upstream every ``keepalive_interval_sec`` seconds as long as the
  socket is idle (no audio has been sent recently). This prevents
  Deepgram from auto-closing the connection during prolonged silence.
  Deepgram's documented idle timeout is ~10 s, so we default to 7 s.

* **Structured error classification** — connect failures, send failures,
  recv errors, abnormal closes, and finalize timeouts all go through
  ``_report_error`` so callers see consistent ``{"type":"error","fatal":
  bool}`` events and can decide whether to fall back.

* **Telemetry** — ``stats`` returns ``{bytes_sent, chunks_sent,
  segments_final, segments_interim, connect_ms, finalize_ms}`` so the
  caller can log upstream latency and debug stalls.

* **Single-use safety** — the class is explicitly not reentrant. All
  operations after ``close()`` are no-ops so late cleanup cannot crash
  the event loop.

This module is the ONLY place in the codebase that talks to Deepgram's
live API. Callers should never construct the URL, set headers, or parse
Results messages directly.
"""

from __future__ import annotations

import asyncio
import json
import logging
import time
from collections import deque
from dataclasses import dataclass
from typing import AsyncIterator, Callable, Iterable, Optional
from urllib.parse import urlencode

import websockets
from websockets.asyncio.client import ClientConnection, connect as ws_connect
from websockets.exceptions import ConnectionClosed, InvalidStatus, WebSocketException

logger = logging.getLogger(__name__)


DEEPGRAM_LIVE_OPEN_TIMEOUT_SEC = 8.0
DEEPGRAM_LIVE_RETRY_TIMEOUT_SEC = 4.0
# How long ``close()`` waits, after sending ``Finalize``, for Deepgram to
# return the transcript that Finalize flushed — before sending
# ``CloseStream``. The wait ends the moment the transcript arrives, so
# this is a ceiling, not a cost. Observed post-Finalize round trips in
# main.log land between 0.26 s and 0.73 s.
#
# 1.5 → 3.0 s (tail-truncation fix): main.log 2026-08-24 07:35 shows a
# session where the post-Finalize transcript did NOT arrive within 1.5 s
# ("no post-Finalize transcript within 1.5s; closing") and the finalize
# delta was 0 — the user's trailing clause never reached any final
# segment and the tail was lost. The ceiling only bites on exactly such
# slow/cross-region sessions; healthy ones end the wait at first
# transcript and pay nothing extra.
FINALIZE_FLUSH_WAIT_SEC = 3.0

# Tail guard: if the streamed audio runs this many seconds past the last
# finalized segment, the trailing words are still unflushed upstream. One
# extra Finalize round-trip is cheaper than silently dropping everything
# the user said after the last periodic flush (2026-08-24 log: 19
# sessions exited on the first timeout; all benign by luck — every one
# had a flush landing exactly at Stop. This guard removes the "by luck").
TAIL_GUARD_MIN_SEC = 0.75

# Wait budget when the streamed audio is ALREADY fully covered by
# finalized segments at Finalize time — i.e. Finalize has nothing left to
# flush and, in the overwhelming majority of such sessions, Deepgram
# answers with nothing at all.
#
# Measured over 410 real stops in main.log: 267 (65 %) ended in exactly
# this state, each having first burned the full FINALIZE_FLUSH_WAIT_SEC
# ceiling waiting for a message that was never coming — 608 s of stop
# latency in total, almost all of it here. The coverage that proves
# nothing is missing used to be computed only INSIDE the timeout
# handler, so the answer arrived strictly after the cost had been paid.
#
# Sized from the round trips of sessions that DID receive a post-Finalize
# transcript (411 of them: median 0.26 s, p90 0.36 s, p95 0.49 s). It sits
# above p95 with margin, so a tail whose final IS coming still gets it,
# while a tail with nothing behind it does not pay the full ceiling.
#
# An UNCOVERED tail keeps the full ceiling and the retry — that is the
# case where a truncated wait would cost the user real words.
FINALIZE_COVERED_WAIT_SEC = 0.75

# Nothing at all past the last finalized segment — a boundary sliver, not a
# tail. This is the ONE population where waiting has never once produced
# anything: 9 of 9 such stops in the log waited out their whole window and
# Deepgram sent nothing, at 962-1011 ms per finalize. Their measured gaps
# were 0.06-0.24 s, which is exactly what COVERAGE_GAP_MIN_SEC calls
# segment-boundary jitter.
#
# Applying this window to the whole "no retry needed" band was a mistake,
# and it cost a user real words. ``_tail_needs_flush`` tolerates up to
# TAIL_GUARD_MIN_SEC (0.75 s) of uncovered audio before it asks for a
# RETRY — which is a different question from whether anything is left to
# flush at all. Production, 2026-08-25 14:33:16: ``gap=0.50s
# speech_in_gap=0.00``, the stream closed 0.25 s after Finalize, and the
# sentence arrived ending "…чтобы никуда не не". Half a second of audio past
# the last final that no interim had decoded either — which is precisely
# what Finalize exists to force, and the answer takes a round trip this
# window is too short to receive.
#
# Scoped to the population it was measured on, and no wider.
FINALIZE_EMPTY_TAIL_WAIT_SEC = 0.25

# C3 (audit §2.5): the announced budget used to describe only the flush
# wait, leaving out everything drain_transcript() still does after the
# wait resolves — the tail-guard re-measure, the interim-word splice,
# building the merged transcript. That work is CPU-bound and small, but
# a budget that omits it is not an honest upper bound on "time until the
# envelope is sent", which is the promise made to the renderer. Sized
# generously above what splice + seam-merge + dict-building take on a
# session with a few hundred segments (single-digit milliseconds) so it
# never needs revisiting for a slow machine.
FINALIZE_ASSEMBLY_ALLOWANCE_SEC = 0.15

# Seam repair: Deepgram's periodic forced flushes may cut a word in half
# across two consecutive finals ("…четыре, пя" | "ть. Далее"). When two
# finals touch within SEAM_MERGE_MAX_GAP seconds and neither side ends
# the sentence, the provider's OWN word lists decide whether the touching
# tokens are one spoken word split by the flush boundary — see
# ``_provider_split_token``. The morphological heuristic below is only
# the fallback for segments that arrived without word timings.
SEAM_MERGE_MAX_GAP_SEC = 0.05
# Splice guard (audit A/B, three real artifacts on the trilingual evidence
# recording): the number of leading alpha-core letters compared to decide
# a spliced word would sit beside a re-spelling of itself in the
# assembled text ("слушаю"/"слушай" share these five letters; "WAV"/"WAB"
# are shorter than this and so compared in full).
_SPLICE_STEM_LETTERS = 5
# Same A/B: a final that RE-TIMED a word instead of re-spelling it still
# owns that time. Requiring only 25% overlap of either word's own
# duration (not majority of the shorter one) is what stops an orphan
# interim from being spliced back in next to the final's own take on the
# same audio.
SPLICE_COVERAGE_OVERLAP_FRACTION = 0.25
# A spliced word may only land where there is room for it: the gap it
# would occupy — inside a final's own word list, or at the seam between
# two finals/fallback segments — must be at least the word's own
# duration, less this tolerance for re-decode boundary jitter.
SPLICE_GAP_SLACK_SEC = 0.05
_SEAM_VOWELS = set("аеёиоуыэюяaeiouy")
# Russian words that are a single vowel-less letter. The fallback
# heuristic ("exactly one side has no vowel ⇒ it is half a word") reads
# every one of these as a severed fragment and glues it to its
# neighbour, which is how "мы живём в" | "доме на горе" became "мы живём
# вдоме" (audit §3.3, reproduced by running the function). They are
# complete words — a preposition, a conjunction or a particle — and no
# amount of vowel counting can tell them apart from a fragment, so the
# heuristic is simply not allowed to touch them.
_SEAM_WHOLE_WORDS = frozenset(
    ("в", "с", "к", "ж", "б", "и", "у", "о", "а", "я")
)
# Interim hypotheses kept for the finalize-time hole report (§3.9). Only
# the text and the span are retained, and only the newest N, so a long
# dictation cannot grow this without bound. 40 covers several seconds of
# rolling re-decodes at the observed ~15 Hz interim rate — enough to show
# what the service was hearing around a hole.
INTERIM_HYPOTHESIS_RING_SIZE = 40
# Per-line truncation for that report: enough to recognise the clause,
# short enough that a block of them stays readable in main.log.
_HOLE_REPORT_TEXT_CHARS = 120
# At most this many interim hypotheses are printed per hole.
_HOLE_REPORT_MAX_INTERIMS = 6
# At most this many OVERRULED words (an interim word whose audio a
# differently-spelled final word claimed) are printed. A stop with a
# handful is a diagnosis; a stop with fifty is a rule that needs
# rethinking, and the count on the header line says so without printing
# all of them. "Overruled" is deliberately not "displaced": a displaced
# word was superseded by a newer HYPOTHESIS and lives on in the orphan
# pool, an overruled one was dropped for good.
_HOLE_REPORT_MAX_OVERRULED = 12
# How many displacements are retained for that report. Bounded so a long
# dictation cannot grow the diagnostic without limit; the total is
# counted separately, so the header stays truthful when the ring wraps.
OVERRULED_WORD_RING_SIZE = 50


def _word_speech_spans(words: Iterable[dict]) -> list[tuple[float, float]]:
    """Speech spans covering ``words``, with inter-word silence bridged.

    Consecutive words closer together than ``COVERAGE_GAP_MIN_SEC`` belong
    to one run of speech; the breath between them is not a hole and must
    not be measured as one. Anything wider starts a new span, so a real
    pause inside a re-decode window stays outside the measurement.
    """
    spans: list[tuple[float, float]] = []
    for word in sorted(words, key=lambda w: (float(w["start"]), float(w["end"]))):
        start = float(word["start"])
        end = float(word["end"])
        if end <= start:
            continue
        if spans and start - spans[-1][1] <= COVERAGE_GAP_MIN_SEC:
            spans[-1] = (spans[-1][0], max(spans[-1][1], end))
        else:
            spans.append((start, end))
    return spans


def _token_alpha_core(token: str) -> str:
    return "".join(ch for ch in token if ch.isalpha())


def _has_vowel(core: str) -> bool:
    return any(ch.lower() in _SEAM_VOWELS for ch in core)


def _as_float(value: object, default: float = 0.0) -> float:
    """Numeric coercion that never raises.

    A malformed upstream message (non-numeric ``start``/``duration``)
    must not crash the receive loop, because that would terminate the
    whole recording over one stray frame.
    """
    try:
        return float(value) if value is not None else default  # type: ignore[arg-type]
    except (TypeError, ValueError):
        return default


def normalize_words(raw: object) -> list[dict]:
    """Parse ``alternatives[0].words`` into ``{word, start, end}`` dicts.

    The ONE place a Deepgram word list becomes internal word records —
    used for interim hypotheses and for finals alike (audit §3.1). The
    display spelling comes from ``deepgram_word_text`` so the live path
    cannot disagree with the REST path about ``punctuated_word`` vs
    ``word``. Tokens without text or without a positive duration are
    dropped: they carry no evidence.
    """
    if not isinstance(raw, list):
        return []
    out: list[dict] = []
    for item in raw:
        if not isinstance(item, dict):
            continue
        token = deepgram_word_text(item)
        if not token:
            continue
        start = _as_float(item.get("start"))
        end = _as_float(item.get("end"))
        if end <= start:
            continue
        out.append({"word": token, "start": round(start, 3), "end": round(end, 3)})
    return out


def _word_core(word: dict) -> str:
    """Case-folded alphabetic core of a word record.

    Punctuation and capitalisation are formatting — ``punctuated_word``
    adds both — so they must not decide whether two records are the same
    spoken word ("Субагента," and "субагента" are one word).
    """
    return _token_alpha_core(str(word.get("word") or "")).casefold()


def _word_stem(word: dict) -> str:
    """First ``_SPLICE_STEM_LETTERS`` letters of a word's alpha core.

    Used only to decide whether a word about to be spliced in would sit
    beside a near-duplicate of itself in the assembled text — a stem
    match survives the kind of respelling a re-decode produces
    ("слушаю" next to "слушай", "WAV" next to "WAB") without matching
    unrelated words that merely share a prefix. Full-core equality
    (``_word_core(a) == _word_core(b)``) is a special case of this, so
    nothing that used to be caught stops being caught.
    """
    return _word_core(word)[:_SPLICE_STEM_LETTERS]


def _time_overlap(a: dict, b: dict) -> float:
    return min(_as_float(a.get("end")), _as_float(b.get("end"))) - max(
        _as_float(a.get("start")), _as_float(b.get("start"))
    )


def _word_duration(word: dict) -> float:
    return max(_as_float(word.get("end")) - _as_float(word.get("start")), 1e-6)


def _same_spoken_word(a: dict, b: dict) -> bool:
    """Are these two word records the same spoken word?

    Identity is the alpha core plus MAJORITY temporal overlap: a rolling
    re-decode moves word boundaries by a few tens of milliseconds, so
    requiring identical times would treat every shift as a new word,
    while requiring only *some* overlap would let any neighbouring word
    stand in for this one. The rule was written once for the splice's
    orphan dedupe and is now the single definition used everywhere
    (audit §3.1/§3.2).
    """
    core = _word_core(a)
    if not core or core != _word_core(b):
        return False
    shortest = min(_word_duration(a), _word_duration(b))
    return _time_overlap(a, b) > 0.5 * shortest


def word_accounted_for(word: dict, others: Iterable[dict]) -> bool:
    """Does any record in ``others`` account for ``word``?

    One predicate, three callers, because they are all asking the same
    question:

    * a final's own words vs a retained interim word — "did this final
      actually contain that word?" (the eviction, audit §3.1);
    * the newest interim's words vs an orphan — "does the newer
      hypothesis already account for this?" (the purge, audit §3.2);
    * the current interim words vs an orphan at splice time — the same
      question one last time, so a shifted re-decode is not spliced
      twice (BUG-78).

    Answering it by TIME WINDOW instead — "the final's span contains the
    word's centre" — is what deleted the word "субагента" from a
    recording whose final said "три на или если это": the span covered
    it, the transcript did not.
    """
    return any(_same_spoken_word(word, other) for other in others)


def covering_final_word(word: dict, final_words: Iterable[dict]) -> Optional[dict]:
    """Which final word answers for ``word`` — or ``None`` if none does.

    The implementation behind ``final_words_cover``: the predicate is
    "did anything cover it", this is "what covered it", and they must
    never be able to disagree, so there is one rule and the predicate
    delegates to it.

    Naming the covering word is what makes a displacement visible. An
    interim word judged covered by a final word with a DIFFERENT
    letter core is not a recovered word and not a hole — it is the
    coverage rule deciding that the final owns that audio and spelled
    it otherwise. That decision is right for "слушаю" vs "слушай" and
    wrong for "трёх" vs "в", and telling the two apart after the fact
    needs both words and both time spans, which only this function
    knows (audit §3.4, defect "трёх").

    Two ways, and both are needed:

    * the final carries the SAME word, its boundaries shifted by the
      re-decode (``word_accounted_for``); or
    * the final's own WORDS occupy a substantial share of this word's
      time — the final heard that audio and wrote something else for
      it, whatever it spelled.

    The second clause is what a pure identity test misses, and the miss
    is visible in the output: an interim that heard "слушаю" where the
    final committed "слушай" is not a lost word, it is a disagreement,
    and splicing the loser back in ships "слушаю слушай" to the user.
    The final is the authoritative transcript for the time its words
    occupy; it is authoritative for nothing else, which is exactly why
    the gaps BETWEEN its words — where "субагента" was spoken — stay
    recoverable.

    "Substantial" is ``SPLICE_COVERAGE_OVERLAP_FRACTION`` (25%) of
    EITHER word's own duration, not a majority of the shorter one: a
    final that re-times a word — moves its boundaries enough that a
    strict majority no longer overlaps, as happened with "слушаю" vs
    "слушай" on the trilingual evidence recording — still re-decoded
    that audio and still owns it. A 0.1 s filler in the middle of a
    0.6 s word still does not amount to having transcribed it either
    way, so the fraction is checked both ways rather than dropped.
    """
    duration = _word_duration(word)
    for other in final_words:
        if _same_spoken_word(word, other):
            return other
        overlap = _time_overlap(word, other)
        if overlap <= 0:
            continue
        if overlap >= SPLICE_COVERAGE_OVERLAP_FRACTION * duration:
            return other
        if overlap >= SPLICE_COVERAGE_OVERLAP_FRACTION * _word_duration(other):
            return other
    return None


def final_words_cover(word: dict, final_words: Iterable[dict]) -> bool:
    """Is this interim word's ground already transcribed by a final?

    See ``covering_final_word`` for the rule; this is that answer read
    as a yes/no.
    """
    return covering_final_word(word, final_words) is not None


def _segment_words(segment: dict) -> list[dict]:
    words = segment.get("words")
    if not isinstance(words, list):
        return []
    return [w for w in words if isinstance(w, dict)]


def _provider_split_token(prev: dict, nxt: dict) -> Optional[bool]:
    """Did Deepgram itself cut one spoken word across this seam?

    Returns ``None`` when either side arrived without a word list — the
    caller then falls back to the morphological heuristic, which is all
    that is knowable about a segment carrying only text.

    With both word lists in hand the question is answerable instead of
    guessable (audit §3.3). Two conditions must hold:

    * the two touching WORDS are contiguous in time (a real inter-word
      boundary inside one flush window is not a severed token), and
    * at least one of the touching text tokens is not a whole entry in
      its own segment's word list — i.e. the provider's transcript and
      its word list disagree about where that token ends, which is
      exactly what a flush cutting through a token produces.

    When both tokens ARE whole words in the provider's own list, the
    provider is telling us they are two words. Believing it is the point:
    the heuristic that did not read "в" as a word glued it to the next
    one.
    """
    p_words = _segment_words(prev)
    n_words = _segment_words(nxt)
    if not p_words or not n_words:
        return None
    last = p_words[-1]
    first = n_words[0]
    gap = _as_float(first.get("start")) - _as_float(last.get("end"))
    if abs(gap) > SEAM_MERGE_MAX_GAP_SEC:
        return False
    p_tokens = str(prev.get("text") or "").split()
    n_tokens = str(nxt.get("text") or "").split()
    if not p_tokens or not n_tokens:
        return False
    prev_whole = _token_alpha_core(p_tokens[-1]).casefold() == _word_core(last)
    next_whole = _token_alpha_core(n_tokens[0]).casefold() == _word_core(first)
    return not (prev_whole and next_whole)


def _looks_like_severed_pair(core_a: str, core_b: str) -> bool:
    """Fallback for segments with no word list: is this pair one word?

    Exactly one side vowel-less, both sides short, and NEITHER side a
    complete single-letter word (``_SEAM_WHOLE_WORDS``). The last clause
    is the fix: without it the rule merged "живём"+"в" → "живём в" ...
    "вдоме", i.e. it corrupted three of the most common Russian
    prepositions on every seam they happened to land on.
    """
    if not core_a or not core_b:
        return False
    if core_a.casefold() in _SEAM_WHOLE_WORDS or core_b.casefold() in _SEAM_WHOLE_WORDS:
        return False
    if max(len(core_a), len(core_b)) > 4:
        return False
    return _has_vowel(core_a) != _has_vowel(core_b)


def merge_seam_fragments(
    segments: list[dict],
) -> list[dict]:
    """Return ``segments`` with word fragments severed at final boundaries rejoined.

    Pure function over ``{"start", "end", "text"}`` dicts (the canonical
    finalized-segment shape), which may also carry ``words`` — the
    provider's own word list for that segment. Two adjacent segments are
    merged at the text level only when every guard below holds —
    otherwise the pair is left untouched:

    * temporal: ``next.start - prev.end <= SEAM_MERGE_MAX_GAP_SEC``
      (a real pause between utterances is never bridged);
    * prosody: ``prev.text`` does not end with sentence punctuation;
    * casing: ``next.text`` begins with a lowercase letter (a mid-sentence
      continuation, not a new sentence);
    * evidence: with word lists on both sides, ``_provider_split_token``
      decides — the provider says whether it cut a token. Without them,
      ``_looks_like_severed_pair`` falls back to morphology (exactly one
      vowel-less core, both short, neither a complete one-letter word).

    When a merge fires, the two touching WORD records are fused as well,
    so a segment's ``words`` never contradicts its own ``text``.
    """
    if len(segments) < 2:
        return segments
    out = [dict(segments[0])]
    for nxt in segments[1:]:
        prev = out[-1]
        gap = float(nxt.get("start", 0.0)) - float(prev.get("end", 0.0))
        p_text = str(prev.get("text") or "").strip()
        n_text = str(nxt.get("text") or "").strip()
        if not p_text or not n_text or gap > SEAM_MERGE_MAX_GAP_SEC:
            out.append(dict(nxt))
            continue
        if p_text[-1] in ".!?…":
            out.append(dict(nxt))
            continue
        if n_text[:1].isupper():
            out.append(dict(nxt))
            continue
        p_tokens = p_text.split()
        n_tokens = n_text.split()
        ta = _token_alpha_core(p_tokens[-1]) if p_tokens else ""
        tb = _token_alpha_core(n_tokens[0]) if n_tokens else ""
        evidence = _provider_split_token(prev, nxt)
        severed = _looks_like_severed_pair(ta, tb) if evidence is None else evidence
        if not severed:
            out.append(dict(nxt))
            continue
        # Guards passed: the two touching tokens are one spoken word.
        # Pure-function contract: edits land on the copies in ``out`` —
        # mutating ``nxt`` directly leaked changes into the caller's
        # segment list (BUG-67). The word lists are rebuilt rather than
        # mutated for the same reason: ``dict(segment)`` is shallow, so
        # the list object is still the caller's.
        prev["text"] = " ".join(p_tokens[:-1] + [p_tokens[-1] + n_tokens[0]])
        p_words = _segment_words(prev)
        n_words = _segment_words(nxt)
        if p_words and n_words:
            fused = {
                "word": str(p_words[-1].get("word") or "")
                + str(n_words[0].get("word") or ""),
                "start": p_words[-1].get("start"),
                "end": n_words[0].get("end"),
            }
            prev["words"] = [*p_words[:-1], fused]
            n_words = n_words[1:]
        nxt_rest = " ".join(n_tokens[1:])
        if nxt_rest:
            merged_nxt = dict(nxt)
            merged_nxt["text"] = nxt_rest
            if _segment_words(nxt):
                merged_nxt["words"] = n_words
            out.append(merged_nxt)
        # else: next contributed only the fragment tail — fully absorbed.
    return out


# Cross-final duplicate guard: Deepgram's own endpointing documentation
# shows a word straddling an ``is_final`` boundary can be transcribed on
# BOTH sides of it ("two two" | "two two three three…"), independently
# of anything this module splices in. At most this many trailing/leading
# words are compared per seam...
CROSS_FINAL_NGRAM_MAX_WORDS = 5
# ...and only when the seam is no wider than this — a real pause means a
# genuine repeat ("да, да"), not the same word transcribed twice.
CROSS_FINAL_NGRAM_MAX_GAP_SEC = 1.0


def _token_stem(token: str) -> str:
    """Same rule as ``_word_stem``, for a raw text token with no word
    record (a segment that arrived with ``text`` but no ``words``)."""
    return _token_alpha_core(token).casefold()[:_SPLICE_STEM_LETTERS]


def drop_repeated_seam_ngrams(segments: list[dict]) -> list[dict]:
    """Drop a run of words Deepgram emitted on BOTH sides of a final
    boundary.

    Nothing else in this module de-duplicates across two ALREADY-FINAL
    segments: ``merge_seam_fragments`` only rejoins one word a flush cut
    in half, and the splice guard (``_insert_word_into_segment`` /
    ``_fits_beside``) only stops a newly RECOVERED word from duplicating
    a final's word — neither touches two native finals that both
    transcribed the same boundary word on their own.

    Pure function over the same ``{"start", "end", "text"}`` (+ optional
    ``words``) segment shape as ``merge_seam_fragments``, meant to run
    right after it and before either ``text`` or ``segments`` is derived
    from the result — the one shared, merged list both envelope fields
    come from (audit §3.8's SSOT).

    For each consecutive pair, the LARGEST ``i`` from 1 to
    ``CROSS_FINAL_NGRAM_MAX_WORDS`` is found such that the last ``i``
    words of ``prev`` and the first ``i`` words of ``next`` match by
    STEM (``_word_stem``/``_token_stem`` — the same rule the splice
    guard uses, so a re-spelling like "слушаю"/"слушай" is caught, not
    only an exact repeat). That leading run is then dropped from
    ``next``.

    A stem match alone is not enough to call it a duplicate: the same
    words spoken twice in a row are two utterances, not one straddling a
    boundary, and dropping the second occurrence would delete real
    content — measured on the trilingual evidence recording, where an
    isolated re-decode of the 57-62 s span confirmed "sub agents, sub
    agents" was said twice. So when both sides carry word timings, a
    match counts as the SAME utterance — and is dropped — only when
    EVERY matched pair of words also overlaps in TIME (by at least 25%
    of either word's own duration, the same fraction the splice guard's
    coverage rule uses): two disjoint-time occurrences of the same words
    are kept, both. Only when neither side has word timings to check
    does this fall back to the segment-level rule this function shipped
    with — the seam is no wider than ``CROSS_FINAL_NGRAM_MAX_GAP_SEC``
    — because time overlap is not answerable per word without them.
    """
    if len(segments) < 2:
        return segments
    out = [dict(segments[0])]
    for raw_nxt in segments[1:]:
        prev = out[-1]
        nxt = dict(raw_nxt)
        p_tokens = str(prev.get("text") or "").split()
        n_tokens = str(nxt.get("text") or "").split()
        p_words = _segment_words(prev)
        n_words = _segment_words(nxt)
        drop = 0
        if p_tokens and n_tokens:
            max_n = min(CROSS_FINAL_NGRAM_MAX_WORDS, len(p_tokens), len(n_tokens))
            if p_words and n_words:
                for i in range(max_n, 0, -1):
                    tail = [_token_stem(t) for t in p_tokens[-i:]]
                    head = [_token_stem(t) for t in n_tokens[:i]]
                    if not (all(tail) and tail == head):
                        continue
                    same_moment = all(
                        _time_overlap(pw, nw)
                        >= SPLICE_COVERAGE_OVERLAP_FRACTION * _word_duration(pw)
                        or _time_overlap(pw, nw)
                        >= SPLICE_COVERAGE_OVERLAP_FRACTION * _word_duration(nw)
                        for pw, nw in zip(p_words[-i:], n_words[:i])
                    )
                    if same_moment:
                        drop = i
                        break
            else:
                gap = _as_float(nxt.get("start")) - _as_float(prev.get("end"))
                if gap <= CROSS_FINAL_NGRAM_MAX_GAP_SEC:
                    for i in range(max_n, 0, -1):
                        tail = [_token_stem(t) for t in p_tokens[-i:]]
                        head = [_token_stem(t) for t in n_tokens[:i]]
                        if all(tail) and tail == head:
                            drop = i
                            break
        if drop:
            n_tokens = n_tokens[drop:]
            nxt["text"] = " ".join(n_tokens)
            if n_words:
                nxt["words"] = n_words[drop:]
        out.append(nxt)
    return out
# An interim must carry at least this much text before its span counts as
# "the service heard words here". Deepgram emits 1-2 character noise
# hypotheses during silence; those must not be mistaken for speech.
INTERIM_SPEECH_MIN_CHARS = 8
# Gaps shorter than this between consecutive finals are normal segment
# boundaries, not holes.
COVERAGE_GAP_MIN_SEC = 0.25
# When grouping retained interim words into fallback segments, a silence
# gap longer than this between two consecutive words starts a new group.
# Matches a natural inter-clause pause; smaller values would fuse words
# the user spoke several sentences apart into one run-on blob.
INTERIM_WORD_GAP_SPLIT_SEC = 1.0


# 1.1.25 SSOT: imported from ``backend.deepgram_endpoints``. Same
# centralised host as the REST module so a regional override sets
# both at once via TRANSCRIPTOR_DEEPGRAM_HOST.
from backend.audio_constants import LIVE_SAMPLE_RATE_HZ  # noqa: E402
from backend.deepgram_endpoints import DEEPGRAM_LIVE_URL
from backend.deepgram_format import shared_format_params  # noqa: E402
from backend.deepgram_keyterms import keyterm_query_pairs  # noqa: E402
from backend.deepgram_words import deepgram_word_text  # noqa: E402
from backend.model_catalog import DEFAULT_DEEPGRAM_AUDIO_MODEL  # noqa: E402


@dataclass
class DeepgramLiveConfig:
    """Typed configuration for a Deepgram live streaming session.

    Parameter set is restricted to what Nova-3's ``/v1/listen`` live
    endpoint actually accepts. ``detect_language`` is a pre-recorded
    endpoint feature — the live endpoint uses ``language=multi`` for
    multilingual auto-detection instead. ``numerals`` is pre-recorded
    only; the shared formatting pass covers number formatting at live
    time.

    Formatting options are not configured here — see
    ``backend.deepgram_format``, which both Deepgram paths read so the
    same recording cannot come back formatted differently depending on
    which one served it.

    Keyterm Prompting (``keyterms``) similarly comes from one shared
    parser — ``backend.deepgram_keyterms`` — for the same reason:
    both Deepgram paths must bias toward the same vocabulary.
    """

    model: str = DEFAULT_DEEPGRAM_AUDIO_MODEL
    language: str = "auto"
    # Constrained to ``LIVE_SAMPLE_RATE_HZ`` — the WS announces this
    # rate to Deepgram and the frontend downsampler targets it; any
    # override here MUST come with a matching frontend change.
    sample_rate: int = LIVE_SAMPLE_RATE_HZ
    channels: int = 1
    interim_results: bool = True
    # ``smart_format``, ``punctuate`` and ``filler_words`` are NOT fields
    # here. They are formatting, both Deepgram paths must format the same
    # way, and a per-session copy is how the two paths came to disagree.
    # ``backend.deepgram_format`` owns them; ``to_query_string`` reads
    # them from there.
    # Endpointing is the silence threshold (in ms) Deepgram uses to
    # decide a chunk is "complete enough" to seal as is_final=true.
    #
    # 1.1.18 — reverted 700 → 300 ms.
    #
    # The 700 ms bump (from the "грамматически-неточные фрагменты"
    # report) made segments grammatically richer, but the user's
    # 1.1.17 main.log showed Nova-3 multilingual on a Russian uplink
    # returning interim text continuously and NEVER emitting
    # ``is_final`` during a 14-second recording (``segments_final=0``
    # at stop time). The post-CloseStream finalize also failed to
    # arrive in time (envelope timed out at 4 s). Result: every Stop
    # fell through to the on-disk REST recovery path — a 3+ second
    # tax on every recording that the streaming path was supposed to
    # avoid.
    #
    # 300 ms matches typical conversational pause length (250–500 ms),
    # so utterance breaks reliably seal ``is_final`` segments DURING
    # streaming. The "broken fragments" concern is unrelated to this
    # window — ``punctuate`` handles sentence assembly and punctuation
    # regardless of how often individual segments are sealed. (This used
    # to credit ``smart_format``; a same-audio A/B over 280 s of Russian
    # returned byte-identical text with the flag on and off, so the
    # credit belonged to ``punctuate`` all along. See
    # ``backend.deepgram_format``.) The 700 ms bump was solving the wrong
    # axis.
    endpointing_ms: int = 300
    # Utterance end is the silence threshold that triggers
    # ``speech_final=true`` (end-of-utterance signal used downstream
    # to decide when to emit a period). 1200 ms was too aggressive
    # for conversational pauses (natural "um" breaks). 2000 ms is
    # Deepgram's recommended long-form value and prevents a thought
    # from splitting across two "final" events.
    utterance_end_ms: int = 2000
    diarize: bool = False
    # Nova-3 Keyterm Prompting terms, already normalised (see
    # ``backend.deepgram_keyterms.normalize_keyterms`` — this field
    # holds the parsed tuple, never the user's raw config string).
    # Emitted as repeated ``keyterm=`` query parameters by
    # ``to_query_string``; silently dropped for a non-Nova-3 model via
    # ``keyterm_query_pairs``.
    keyterms: tuple[str, ...] = ()

    def to_query_string(self) -> str:
        model = self.model or DEFAULT_DEEPGRAM_AUDIO_MODEL
        # A list of pairs, not a dict: ``keyterm`` must be repeated once
        # per term (Deepgram's documented shape for Keyterm Prompting),
        # and a dict can hold only one value per key. ``urlencode``
        # accepts a sequence of 2-tuples directly and preserves order,
        # so every existing key stays exactly where it was.
        params: list[tuple[str, str]] = [
            ("model", model),
            ("encoding", "linear16"),
            ("sample_rate", str(int(self.sample_rate))),
            ("channels", str(int(self.channels))),
            ("interim_results", _bool(self.interim_results)),
            *shared_format_params().items(),
            ("endpointing", str(int(self.endpointing_ms))),
            ("utterance_end_ms", str(int(self.utterance_end_ms))),
        ]
        if self.diarize:
            params.append(("diarize", "true"))
        lang = (self.language or "").strip().lower()
        if not lang or lang in ("auto", "multi"):
            # Nova-3 multilingual mode — the model auto-detects the
            # active language per utterance across 10 supported
            # languages including Russian, Spanish, French, German,
            # Hindi, Portuguese, Italian, Dutch, Japanese, English.
            #
            # 2026-09-03 measurement (BUGS_AUDIT_2026-09-03.md §1;
            # reproducible with ``backend/tools/deepgram_live_ab.py``):
            # on this app's own saved Russian recordings, ``multi``
            # dropped ~35% of a 99 s dictation and whole clauses in two
            # short ones (8.6 s, 12 s), and was non-deterministic
            # between repeat runs on the SAME audio. ``language=ru`` on
            # the identical files kept every clause, byte-identical
            # across repeats. Lowering the level by 14 dB to match the
            # clean June recording did not change the result. A 173 s
            # June recording, made without clipping, showed no
            # difference between the two modes — the failure
            # is specific to this kind of content, not universal. This
            # does NOT change what "auto" maps to here — that mapping
            # is a UI-level choice (see ``frontend``) — it only records
            # the measured fact where the mapping lives, and points at
            # Keyterm Prompting (``keyterms`` above) as the mitigation
            # for the transliteration cost of choosing a monolingual
            # language instead.
            params.append(("language", "multi"))
        else:
            params.append(("language", lang))
        params.extend(keyterm_query_pairs(self.keyterms, model))
        return urlencode(params)


def _bool(value: bool) -> str:
    return "true" if value else "false"


class DeepgramLiveError(Exception):
    """Raised for unrecoverable Deepgram live session failures."""


@dataclass
class DeepgramLiveStats:
    """Telemetry for a single live session."""

    bytes_sent: int = 0
    # Bytes handed to send_pcm() for this connection, whether or not the
    # send actually reached Deepgram. ``bytes_sent`` only counts what
    # succeeded, so a mid-stream send timeout (BUG audit §3.6) silently
    # shrank it — and with it ``_tail_coverage``'s streamed_sec, which
    # made a genuinely unflushed tail look shorter than it was. This
    # field is the honest total; see ``_tail_coverage``.
    bytes_offered: int = 0
    chunks_sent: int = 0
    segments_final: int = 0
    segments_interim: int = 0
    keepalives_sent: int = 0
    connect_ms: Optional[float] = None
    finalize_ms: Optional[float] = None
    last_send_at: Optional[float] = None
    last_recv_at: Optional[float] = None
    # ``time.monotonic()`` of the last KeepAlive frame that actually
    # reached the wire. A socket held open with nothing but KeepAlives
    # (``backend.deepgram_warm``) has no other evidence that its send
    # path still works: a half-open TCP connection accepts writes into a
    # black hole, and Deepgram never answers a KeepAlive. This is the age
    # the warm pool reads before adopting a socket. Deliberately NOT in
    # ``as_dict`` — that dict is the ``stats`` field of the renderer's
    # final envelope, and this is backend liveness bookkeeping.
    last_keepalive_at: Optional[float] = None

    def as_dict(self) -> dict:
        return {
            "bytes_sent": self.bytes_sent,
            "bytes_offered": self.bytes_offered,
            "chunks_sent": self.chunks_sent,
            "segments_final": self.segments_final,
            "segments_interim": self.segments_interim,
            "keepalives_sent": self.keepalives_sent,
            "connect_ms": self.connect_ms,
            "finalize_ms": self.finalize_ms,
        }


class DeepgramLiveSession:
    """A single-use Deepgram streaming session.

    Not reentrant. Create one per recording, call ``connect()`` once,
    then ``send_pcm()`` for each audio chunk and iterate ``events()`` from
    a single consumer. Call ``finalize()`` at stop to drain remaining
    results and return the canonical transcript. Always ``close()`` in
    ``finally`` (``finalize()`` closes implicitly on success).
    """

    _QUEUE_SENTINEL = object()

    def __init__(
        self,
        api_key: str,
        config: Optional[DeepgramLiveConfig] = None,
        *,
        keepalive_interval_sec: float = 7.0,
        keepalive_idle_threshold_sec: float = 3.5,
    ):
        if not api_key:
            raise DeepgramLiveError("Deepgram API key is required")
        self._api_key = api_key
        self._cfg = config or DeepgramLiveConfig()
        self._keepalive_interval_sec = max(1.0, float(keepalive_interval_sec))
        self._keepalive_idle_threshold_sec = max(
            0.5, float(keepalive_idle_threshold_sec)
        )
        self._ws: Optional[ClientConnection] = None
        self._recv_task: Optional[asyncio.Task[None]] = None
        self._keepalive_task: Optional[asyncio.Task[None]] = None
        # Bounded queue: a pathological slow consumer (browser throttled,
        # renderer hung) must not be allowed to accumulate interim segments
        # unboundedly at ~15 Hz. On QueueFull, the put path drops the
        # oldest interim entry and re-enqueues; finals and errors are never
        # dropped.  See _enqueue_event below.
        self._event_queue: asyncio.Queue[object] = asyncio.Queue(maxsize=1024)
        self._queue_overflow_warned: bool = False
        self._finalized_segments: list[dict] = []
        # Spans where an interim carried real text. Deepgram can emit a
        # final that stops short of what its own interim already heard
        # and then resume the next final past the difference, leaving a
        # hole no final ever covers — words the user definitely spoke and
        # the service definitely recognised, missing from the committed
        # transcript. Keeping the interim spans lets ``finalize()``
        # measure exactly that, instead of the transcript being trusted
        # blind. Silence produces no interims, so ordinary pauses do not
        # register here.
        self._interim_speech_spans: list[tuple[float, float]] = []
        # Retained word-level hypotheses from interims: {word, start, end}.
        #
        # Deepgram can emit a final that stops short of what its own
        # interim already heard and resume the next final past the
        # difference, leaving a hole no final ever covers (see the
        # ``_interim_speech_spans`` docstring above for a measured
        # example). The interim words are real recognitions of real
        # audio — discarding them throws away the only transcript that
        # exists for that ground. We retain them so ``finalize()`` can
        # splice exactly the words NO final covers back into the
        # committed transcript.
        #
        # Bounded by construction: each new interim supersedes prior
        # hypotheses over its own time range, and every arriving final
        # prunes the words it covers, so steady-state size tracks only
        # the currently-uncovered speech — typically near zero.
        self._interim_words: list[dict] = []
        # Orphan pool: words DISPLACED by a newer rolling hypothesis are
        # unconfirmed-but-heard speech. Deepgram occasionally never
        # re-emits such regions as finals (observed live: a 10.5 s window
        # vanished between two finals while every interim that had first
        # decoded it was itself superseded). Displaced words move here
        # instead of dying, stay subject to newer-evidence pruning, and
        # join the finalize-time hole splice.
        self._orphan_interim_words: list[dict] = []
        # Ring of the newest interim hypotheses (audit §3.9): the 1-in-5
        # sampling line records a LENGTH, so when a hole was found in a
        # shipped recording the log could not say whether the missing
        # words had ever been heard. Bounded by construction — see
        # ``INTERIM_HYPOTHESIS_RING_SIZE`` — and read only at finalize,
        # when a hole is actually being reported.
        self._interim_ring: "deque[tuple[float, float, str]]" = deque(
            maxlen=INTERIM_HYPOTHESIS_RING_SIZE
        )
        # Ring of ``(interim_word, covering_final_word)`` pairs where the
        # two are spelled differently — the drop that leaves no hole
        # behind it (see ``_note_overruled_word``). Bounded like the
        # hypothesis ring; ``_overruled_total`` keeps the count honest
        # when the ring wraps, because a report that silently caps its
        # own count is how a rule looks fine while misfiring hundreds of
        # times.
        self._overruled_words: "deque[tuple[dict, dict]]" = deque(
            maxlen=OVERRULED_WORD_RING_SIZE
        )
        self._overruled_total = 0
        self._closed = False
        # Separate "consumer-visible closed" (self._closed, flipped by
        # recv_loop.finally as soon as the upstream drops so events()
        # consumers see termination) from "close() has been called"
        # (self._close_ran, used as the idempotency guard inside close()).
        # Without this split, when recv_loop sets _closed=True on its
        # exit path and THEN a caller invokes close(), the early-return
        # at the top of close() fired, leaking the upstream WebSocket
        # socket (never sent the WS close frame) and the keepalive task
        # (never cancelled). TCP FIN-WAITs piled up until OS reclaim.
        self._close_ran = False
        # Set by ``discard()``: this socket is being replaced on purpose,
        # so its teardown must not reach the consumer as an error event.
        self._discarded = False
        self._finalize_sent = False
        # Set once drain_transcript() actually enters the Finalize dance
        # (ws present, Finalize not already sent). shutdown() reads this
        # to decide whether CloseStream is its job to send — it must
        # mirror the entry condition exactly, not re-derive it from
        # ``_finalize_sent`` alone, because a Finalize send that timed
        # out leaves that flag False even though CloseStream still needs
        # to go out (see drain_transcript()/shutdown()).
        self._needs_close_stream = False
        # Set by the receive loop whenever an ``is_final`` arrives. The
        # finalize path waits on it after sending ``Finalize`` so the
        # flushed trailing transcript has a chance to come back before
        # the stream is closed. See ``FINALIZE_FLUSH_WAIT_SEC``.
        self._final_arrived = asyncio.Event()
        # ``last_word_end`` from the most recent Deepgram ``UtteranceEnd``
        # message (C7, audit §3.5) — an affirmative "the utterance ended
        # here" signal, fed into ``_tail_coverage`` as evidence distinct
        # from (and stronger than) mere interim silence.
        self._last_utterance_end: Optional[float] = None
        self._last_error: Optional[str] = None
        self._last_fatal: bool = False
        self.stats = DeepgramLiveStats()

    # ----- Lifecycle --------------------------------------------------------

    async def connect(self, open_timeout: float = DEEPGRAM_LIVE_OPEN_TIMEOUT_SEC) -> None:
        """Open the upstream Deepgram WebSocket and start the receive loop.

        Raises ``DeepgramLiveError`` on authentication / network failure.
        The session is unusable after a failed connect; construct a new
        one to retry.

        Default ``open_timeout`` is 8s with one 4s retry. Live capture
        cannot benefit from a 20+ second handshake: if Deepgram is not
        reachable quickly, the recording is still saved locally and the
        stop-time recovery path can decide what to do with the durable
        audio.

        On ``asyncio.TimeoutError`` we perform ONE silent retry:
          - DNS miss on attempt 1 → attempt 2 hits a warm cache.
          - Momentary TCP stall → new connection bypasses the stuck
            half-open socket.
          - Permanently dead network → attempt 2 also fails quickly,
            worst-case total 12s.
          - ``InvalidStatus`` (4xx) is NEVER retried: 401 = bad key,
            403 = no streaming entitlement, 429 = rate-limit, all
            permanent within the retry window.
          - Transport errors (OSError / WebSocketException) also not
            retried — the original error message is more actionable
            than a second identical attempt.
        """
        if self._ws is not None:
            raise DeepgramLiveError("session already connected")
        if self._closed:
            raise DeepgramLiveError("session is closed")
        url = f"{DEEPGRAM_LIVE_URL}?{self._cfg.to_query_string()}"
        headers = [("Authorization", f"Token {self._api_key}")]
        # The full query string, not a summary: endpointing,
        # utterance_end_ms, smart_format and punctuate all change what the
        # transcript looks like, and a session whose parameters are not in
        # the log cannot be compared against one recorded before they were
        # changed. No secret is involved — the key travels in a header.
        logger.info(
            "deepgram-live: params %s keyterms=%d",
            self._cfg.to_query_string(),
            len(self._cfg.keyterms),
        )
        logger.info(
            "deepgram-live: connecting model=%s language=%s sr=%s timeout=%.1fs",
            self._cfg.model,
            self._cfg.language,
            self._cfg.sample_rate,
            open_timeout,
        )
        started = time.perf_counter()

        async def _attempt(budget: float):
            return await ws_connect(
                url,
                additional_headers=headers,
                open_timeout=budget,
                close_timeout=2.0,
                max_size=2 * 1024 * 1024,
                ping_interval=None,  # we manage liveness via KeepAlive frames
                ping_timeout=None,
            )

        retry_budget = DEEPGRAM_LIVE_RETRY_TIMEOUT_SEC
        try:
            try:
                self._ws = await _attempt(open_timeout)
            except asyncio.TimeoutError:
                logger.warning(
                    "deepgram-live: connect timeout attempt=1 budget=%.1fs — retrying once with budget=%.1fs",
                    open_timeout,
                    retry_budget,
                )
                self._ws = await _attempt(retry_budget)
                logger.info(
                    "deepgram-live: connected on retry after total_ms=%.0f",
                    (time.perf_counter() - started) * 1000.0,
                )
            except OSError as os_err:
                # 1.1.25: docstring above promised retry on "DNS miss
                # on attempt 1 -> attempt 2 hits a warm cache" but the
                # original code only retried on TimeoutError. A real
                # DNS miss raises OSError (gaierror), and TCP-RST
                # during connect raises ConnectionRefusedError (also
                # OSError). Both are transient on the post-sleep wake
                # / mobile-network-flap paths. Retry once with the
                # budget the docstring already documents.
                logger.warning(
                    "deepgram-live: connect %s on attempt 1 (%s) — retrying once with budget=%.1fs",
                    type(os_err).__name__, os_err, retry_budget,
                )
                self._ws = await _attempt(retry_budget)
                logger.info(
                    "deepgram-live: connected on retry after total_ms=%.0f",
                    (time.perf_counter() - started) * 1000.0,
                )
        except InvalidStatus as e:
            status = getattr(e.response, "status_code", None)
            body_text = ""
            detail = ""
            try:
                body_text = (e.response.body or b"").decode("utf-8", errors="replace")[:600]
            except Exception as body_err:
                logger.debug("deepgram-live: failed to read error body: %s", body_err)
            # Deepgram returns structured JSON on 400: {"err_code": ...,
            # "err_msg": ..., "request_id": ...}. Parse it so the user
            # sees an actionable message instead of raw JSON.
            if body_text:
                try:
                    parsed = json.loads(body_text)
                    if isinstance(parsed, dict):
                        detail = str(
                            parsed.get("err_msg")
                            or parsed.get("message")
                            or parsed.get("reason")
                            or ""
                        ).strip()
                        if not detail and parsed.get("err_code"):
                            detail = f"code={parsed.get('err_code')}"
                        req_id = str(parsed.get("request_id") or "")
                        if req_id:
                            detail = f"{detail} (request_id={req_id[:12]})" if detail else f"request_id={req_id[:12]}"
                except (ValueError, TypeError):
                    detail = body_text
            if status == 400:
                msg = (
                    f"Deepgram rejected the live streaming parameters (HTTP 400): {detail}"
                    if detail
                    else "Deepgram rejected the live streaming parameters (HTTP 400)"
                )
            elif status == 401:
                msg = "Deepgram rejected the API key (HTTP 401)"
            elif status == 402:
                msg = "Deepgram account has insufficient credits (HTTP 402)"
            elif status == 403:
                msg = "Deepgram account does not have access to live streaming (HTTP 403)"
            elif status == 429:
                msg = "Deepgram rate limit exceeded (HTTP 429). Try again in a moment."
            elif status:
                msg = f"Deepgram handshake failed (HTTP {status}): {detail}" if detail else f"Deepgram handshake failed (HTTP {status})"
            else:
                msg = f"Deepgram handshake failed: {e}"
            logger.error("deepgram-live: %s (raw body=%s)", msg, body_text[:200])
            raise DeepgramLiveError(msg) from e
        except asyncio.TimeoutError as e:
            # This branch fires only if BOTH the initial attempt AND the
            # retry timed out. Report the full budget we actually spent
            # so the user knows the network is genuinely unreachable,
            # not just slow.
            total_budget = open_timeout + retry_budget
            elapsed_ms = (time.perf_counter() - started) * 1000.0
            msg = (
                f"Deepgram connect timed out after {total_budget:.1f}s "
                f"(2 attempts, elapsed={elapsed_ms:.0f}ms)"
            )
            logger.error("deepgram-live: %s", msg)
            raise DeepgramLiveError(msg) from e
        except (WebSocketException, OSError) as e:
            msg = f"Deepgram connect failed: {e}"
            logger.error("deepgram-live: %s", msg)
            raise DeepgramLiveError(msg) from e

        self.stats.connect_ms = (time.perf_counter() - started) * 1000.0
        # 1.1.25: socket-open + task-launch is wrapped so a
        # CancelledError fired between the two doesn't leak the open
        # WebSocket. The window is small (synchronous create_task
        # calls) but real — under heavy event-loop pressure or
        # cooperative cancellation from the caller, an open socket
        # with no recv task to drain it accumulates server-side and
        # burns the user's quota.
        try:
            self._recv_task = asyncio.create_task(
                self._recv_loop(), name="deepgram-live-recv"
            )
            self._keepalive_task = asyncio.create_task(
                self._keepalive_loop(), name="deepgram-live-keepalive"
            )
        except BaseException:
            # Cancellation or OOM between socket-open and task-launch:
            # close the orphan socket so the connection doesn't leak.
            try:
                if self._ws is not None:
                    await self._ws.close()
            except Exception:
                pass
            self._ws = None
            raise
        logger.info(
            "deepgram-live: connected in %.0f ms", self.stats.connect_ms
        )

    def report_fatal(self, message: str) -> None:
        """Report a fatal condition the CALLER detected.

        The send pipeline lives in the caller (audit §3.6: a queue and a
        dedicated sender task, so the renderer's receive loop never
        waits on Deepgram), which means the caller is the only place
        that can notice a wedged upstream — but errors must still reach
        the consumer through the one path every other error takes, or
        the ``events()`` stream and ``last_error``/``last_fatal`` would
        disagree with what the user is told.
        """
        self._report_error(message, fatal=True)

    def note_undelivered_audio(self, nbytes: int) -> None:
        """Account for captured audio that never reached ``send_pcm``.

        ``bytes_offered`` means "audio the mic captured and the pipeline
        was asked to deliver", and coverage math reads it as the length
        of the recording (``_tail_coverage``). Bytes the caller's send
        queue had to drop — the upstream was wedged and the queue hit
        its bound — are exactly that: captured, never delivered. Without
        this they would vanish from both counters and shrink the
        measured tail, hiding a real hole behind a smaller number.
        """
        if nbytes > 0:
            self.stats.bytes_offered += int(nbytes)

    async def send_pcm(self, chunk: bytes) -> None:
        """Forward a PCM16LE mono chunk to Deepgram.

        Silently no-ops when the session is already closed so callers can
        keep draining the mic until the consumer notices the close.
        Mid-stream send failures are only treated as fatal when NO final
        segments have been received yet — if we already have committed
        text, the caller will use it and a send failure just means we
        stop pushing new audio to an already-dead connection.

        The send is NEVER cancelled once started. ``websockets``
        documents that cancelling a ``send()`` mid-frame leaves the
        connection in an undefined state, and the 5-second
        ``wait_for`` that used to wrap this call did exactly that —
        which is the most plausible explanation for the observed runs of
        four consecutive hangs inside a single session (audit §3.6).
        A wedged upstream is detected by the caller instead, from the
        AGE of the audio waiting in its send queue, and answered by
        closing the socket — which makes this await raise rather than
        leaving a half-written frame behind.
        """
        if self._closed or self._ws is None:
            return
        if not chunk:
            return
        # Counted BEFORE the send is attempted (B1, audit §3.6): this is
        # audio the caller captured and offered to Deepgram, regardless
        # of whether the send below succeeds. ``bytes_sent`` below stays
        # "actually delivered" for the connect/telemetry logs; coverage
        # math needs the honest total captured, not just what got
        # through — see ``_tail_coverage``.
        self.stats.bytes_offered += len(chunk)
        try:
            await self._ws.send(chunk)
        except asyncio.TimeoutError:
            # Not ours to raise any more (see the docstring) — this is
            # the transport's own timeout surfacing as a failed send.
            # The chunk is counted as offered, never as sent.
            fatal = self.stats.segments_final == 0
            self._report_error(
                "Deepgram send timed out at the transport", fatal=fatal,
            )
            return
        except OSError as e:
            # A wedged/reset socket below the websockets layer. Same
            # policy as a protocol-level failure: fatal only while no
            # transcript has been committed.
            fatal = self.stats.segments_final == 0
            self._report_error(f"Deepgram send failed: {e}", fatal=fatal)
            return
        except ConnectionClosed as e:
            fatal = self.stats.segments_final == 0
            self._report_error(
                f"Deepgram upstream closed while sending: {e}", fatal=fatal
            )
            if not fatal:
                logger.info(
                    "deepgram-live: send after close, degrading gracefully (%d committed segs)",
                    self.stats.segments_final,
                )
            return
        except WebSocketException as e:
            fatal = self.stats.segments_final == 0
            self._report_error(f"Deepgram send failed: {e}", fatal=fatal)
            return
        self.stats.bytes_sent += len(chunk)
        self.stats.chunks_sent += 1
        self.stats.last_send_at = time.monotonic()

    async def events(self) -> AsyncIterator[dict]:
        """Yield normalized events until the session terminates.

        The generator completes when the upstream socket closes or
        ``close()`` is called. Exactly one consumer per session.
        """
        while True:
            item = await self._event_queue.get()
            if item is self._QUEUE_SENTINEL:
                return
            assert isinstance(item, dict)
            yield item

    async def drain_transcript(
        self,
        on_budget: "Optional[Callable[[float, bool], None]]" = None,
    ) -> dict:
        """Flush Deepgram and return the final transcript — nothing else.

        This is the half of the old ``finalize()`` that produces the
        transcript: send ``Finalize``, decide and announce the wait
        budget, wait for the flush — for as many finals as it takes to
        cover the streamed tail, inside that one budget, then the
        tail-guard retry — splice uncovered interim words, merge seams
        once. It deliberately stops
        the moment the transcript is known complete — CloseStream,
        keepalive teardown and the recv-loop drain are ``shutdown()``'s
        job (C4, audit §2.4/§2.5).

        Splitting this out matters because those belong to DIFFERENT
        deadlines. Median post-Finalize round trip is a few hundred ms;
        median time from CloseStream to the socket actually closing was
        270 ms but ran as long as 5 s, spent waiting for Deepgram to tear
        down a connection whose transcript was already sitting in memory.
        A caller can now send the ``final`` envelope right after this
        returns and let ``shutdown()`` run after — the user stops paying
        for teardown, because the last thing that reaches the frontend no
        longer depends on it.

        ``on_budget`` is called once, the moment the wait budget is
        chosen and before the waiting starts, with ``(budget_sec,
        expects_more)``. The caller forwards it to the client so both
        sides of the stop share ONE deadline: the coverage analysis that
        decides how long this may take happens here, where the data is,
        and the consumer stops guessing. ``budget_sec`` is an honest upper
        bound on the time until THIS method returns (C3) — it is what the
        client should wait, not an optimistic estimate.

        Sets ``stats.finalize_ms`` to this method's own duration — the
        cost the budget promises to bound.

        Returns a dict with ``text``, ``segments``, ``durationSec``,
        ``stats``, ``uncoveredSpeechSec``, ``streamedSec`` and
        ``coveredEndSec``.
        """
        started = time.perf_counter()
        logger.info(
            "deepgram-live: finalize ENTER segments_final=%d segments_interim=%d bytes_sent=%d",
            self.stats.segments_final, self.stats.segments_interim, self.stats.bytes_sent,
        )
        if self._ws is not None and not self._finalize_sent:
            # CloseStream is shutdown()'s responsibility, but whether it
            # is owed at all is decided by THIS entry condition — record
            # it now so shutdown() (which may run well after this method
            # returns, or not know if Finalize send itself failed) does
            # not have to re-derive it. See ``_needs_close_stream``.
            self._needs_close_stream = True
            # 1.1.25: idempotency flag is set AFTER the Finalize send
            # succeeds, NOT before. Previously a CancelledError fired
            # between the flag-set and the actual ``ws.send`` would
            # leave ``_finalize_sent=True`` even though Deepgram never
            # got the Finalize signal — a follow-up finalize() call
            # then early-returned and the trailing is_final was never
            # flushed. Moving the flag below the send-success makes
            # the flag a faithful witness of "Finalize was actually
            # delivered to Deepgram".
            # ── 1.1.19: send Finalize BEFORE CloseStream ─────────────
            #
            # Deepgram's streaming protocol supports two control msgs:
            #   • Finalize:    flushes buffered audio and emits a
            #                  final ``is_final=true`` Result message
            #                  WITHOUT closing the connection. Designed
            #                  exactly for "user pressed Stop, give me
            #                  the trailing transcript now".
            #   • CloseStream: graceful shutdown — server processes
            #                  remaining audio and closes.
            #
            # In the 1.1.18 user logs, the post-CloseStream is_final
            # was empty for EVERY long recording (env.wordCount=0)
            # despite Deepgram clearly receiving the audio (it had
            # emitted is_final segments mid-stream). Some Deepgram
            # regions appear to skip the trailing-buffer flush on
            # CloseStream alone and only emit it on an explicit
            # Finalize. Sending Finalize first guarantees that flush;
            # CloseStream then closes cleanly with the buffer already
            # emptied.
            #
            # The event is armed BEFORE the send (BUG-68): a final that
            # lands while the Finalize frame is still in flight (network
            # RTT, up to the 5 s send timeout) used to be erased by the
            # post-send clear(), forcing the full flush wait below even
            # though the answer was already in hand.
            self._final_arrived.clear()
            try:
                await asyncio.wait_for(
                    self._ws.send(json.dumps({"type": "Finalize"})),
                    timeout=5.0,
                )
                self._finalize_sent = True
                logger.info("deepgram-live: Finalize sent (forces trailing is_final flush)")
            except asyncio.TimeoutError:
                logger.warning("deepgram-live: Finalize send timed out (>5s)")
            except ConnectionClosed:
                # Connection was already closed — treat as "Finalize
                # need not happen", flag accordingly so a second call
                # doesn't try again.
                self._finalize_sent = True
                logger.info("deepgram-live: Finalize skipped (already closed)")
            except WebSocketException as e:
                logger.warning("deepgram-live: Finalize send failed: %s", e)

            # Give Deepgram a moment to return the transcript that
            # ``Finalize`` just flushed, BEFORE closing the stream.
            #
            # These two frames used to go out in the same millisecond, so
            # the close raced the flush. Measured across 14 sessions in
            # one main.log: sessions whose last segment arrived naturally
            # (``speech_final=true``) left 0.25 s of audio undecoded on
            # average, while sessions still mid-utterance at Stop
            # (``speech_final=false``) left 1.86 s — the trailing clause
            # the user had just spoken. That is the difference between
            # "it ended exactly where I stopped" and "the last sentence
            # is missing".
            #
            # Bounded, and short-circuited the instant the flush covers
            # the tail, so a well-behaved stream pays only its actual
            # round trip. (The clear moved ABOVE the send — BUG-68.)
            # Decide the wait budget BEFORE waiting, from what we already
            # know. Coverage is a property of state we hold locally — how
            # much audio we streamed versus how much is represented in
            # finalized segments — so there is no reason to learn it only
            # after a timeout has elapsed. Measuring it first is what
            # turns "wait 3 s, then discover nothing was missing" into
            # "notice nothing is missing, wait 0.75 s to confirm".
            streamed_sec, covered_end, tail_gap, tail_speech = self._tail_coverage()
            # Three cases, not two. "Needs a retry" and "has nothing left to
            # flush" are different questions, and collapsing them applied a
            # window measured on empty tails to tails that were merely small.
            needs_flush = self._tail_needs_flush(tail_gap, tail_speech)
            if needs_flush:
                flush_wait = FINALIZE_FLUSH_WAIT_SEC
            elif tail_gap <= COVERAGE_GAP_MIN_SEC:
                flush_wait = FINALIZE_EMPTY_TAIL_WAIT_SEC
            else:
                flush_wait = FINALIZE_COVERED_WAIT_SEC
            if on_budget is not None:
                # Worst case, not the expected case: an uncovered tail may
                # also pay a retry of the same ceiling. The consumer needs
                # the bound it must respect, not an optimistic estimate.
                # C3: the budget must bound the time to the ENVELOPE being
                # sent, not just the flush wait — add the fixed cost of
                # what still runs after the wait resolves (tail-guard
                # re-measure, splice, seam-merge) so the number the
                # renderer is told to trust actually covers what this
                # method obeys.
                worst_case = (
                    flush_wait * (2.0 if needs_flush else 1.0)
                    + FINALIZE_ASSEMBLY_ALLOWANCE_SEC
                )
                try:
                    on_budget(worst_case, needs_flush)
                except Exception as e:  # never let telemetry break a stop
                    logger.warning("deepgram-live: finalize budget callback failed: %s", e)
            # ONE final is not the flush. Deepgram answers a Finalize with
            # as many ``is_final`` messages as the buffered audio needs,
            # and the first of them can cover a fraction of the tail:
            # 2026-09-03T21:42:09Z, session 62115e77 — 14.26 s streamed,
            # the first final arrived 130 ms after Finalize covering
            # 0.00-10.85 s, the wait ended there, and the second final
            # (10.85-14.26 s, "Напиши, на чем кто вас поверил.") landed
            # 2.7 s later into a transcript that had already been sent.
            #
            # So the wait ends on COVERAGE, not on arrival: after each
            # final, re-measure and keep waiting while the tail is still
            # unflushed — inside the SAME deadline computed above, which
            # is what ``on_budget`` already announced. No second Finalize
            # (the flush is in progress; another one buys nothing) and no
            # extension of the budget: the renderer was told a number and
            # this side must obey it. Exhausting it drops through to the
            # tail guard exactly as before.
            wait_started = time.perf_counter()
            deadline = wait_started + flush_wait
            finals_seen = 0
            flush_covered_tail = False
            while True:
                remaining = deadline - time.perf_counter()
                if remaining <= 0:
                    break
                try:
                    await asyncio.wait_for(
                        self._final_arrived.wait(),
                        timeout=remaining,
                    )
                except asyncio.TimeoutError:
                    break
                # Re-armed BEFORE the measurement, never after it: a
                # final landing while we measure must leave the event
                # set for the next iteration rather than be erased by a
                # clear that runs after it (the BUG-68 shape, one level
                # down).
                self._final_arrived.clear()
                finals_seen += 1
                streamed_sec, covered_end, tail_gap, tail_speech = self._tail_coverage()
                if not self._tail_awaits_more_finals(tail_gap, tail_speech):
                    flush_covered_tail = True
                    break
            waited_ms = (time.perf_counter() - wait_started) * 1000.0
            if flush_covered_tail:
                logger.info(
                    "deepgram-live: post-Finalize finals=%d covered=%.2fs gap=%.2fs "
                    "waited=%.0fms (budget=%.2fs streamed=%.2fs speech_in_gap=%.2fs)",
                    finals_seen,
                    covered_end,
                    tail_gap,
                    waited_ms,
                    flush_wait,
                    streamed_sec,
                    tail_speech,
                )
            else:
                # The budget ran out with the tail still unflushed —
                # either nothing came at all, or the finals that came
                # did not reach the end of the streamed audio.
                # Re-measure: the reader task may have finalized more
                # segments while we were on our way here, which can
                # close a gap that was open a moment ago.
                streamed_sec, covered_end, tail_gap, tail_speech = self._tail_coverage()
                if self._tail_needs_flush(tail_gap, tail_speech):
                    logger.warning(
                        "deepgram-live: tail guard: %.2fs of audio past last final "
                        "(%.2fs of it recognised speech) after %d post-Finalize "
                        "final(s) in %.0fms; retrying Finalize once",
                        tail_gap,
                        tail_speech,
                        finals_seen,
                        waited_ms,
                    )
                    # Armed BEFORE the retry send (BUG-68): a final
                    # landing while the frame is in flight must be seen
                    # by the wait below, not erased by a post-send clear.
                    self._final_arrived.clear()
                    try:
                        await asyncio.wait_for(
                            self._ws.send(json.dumps({"type": "Finalize"})),
                            timeout=5.0,
                        )
                    except (asyncio.TimeoutError, ConnectionClosed, WebSocketException) as e:
                        logger.warning("deepgram-live: tail-guard Finalize failed: %s", e)
                    else:
                        try:
                            await asyncio.wait_for(
                                self._final_arrived.wait(),
                                timeout=FINALIZE_FLUSH_WAIT_SEC,
                            )
                            logger.info("deepgram-live: tail guard: transcript arrived on retry")
                        except asyncio.TimeoutError:
                            logger.warning(
                                "deepgram-live: tail guard: still silent after retry "
                                "(%.2fs uncovered, %.2fs of it speech); closing",
                                tail_gap,
                                tail_speech,
                            )
                else:
                    # State the measurement, not a conclusion. "Nothing was
                    # unflushed" was printed for any tail below the retry
                    # threshold, including half a second of real audio, and
                    # it read as proof that the tail was complete when it
                    # was nothing of the kind.
                    verdict = (
                        "nothing past the last final"
                        if tail_gap <= COVERAGE_GAP_MIN_SEC
                        else "below the retry threshold, but not empty"
                    )
                    # And say how many finals the wait actually saw:
                    # "no post-Finalize transcript" was the honest
                    # phrasing when the wait ended on the first arrival,
                    # but it now ends on coverage, so a budget can
                    # expire after several finals have landed.
                    logger.info(
                        "deepgram-live: post-Finalize finals=%d covered=%.2fs "
                        "gap=%.2fs waited=%.0fms (budget=%.2fs streamed=%.2fs "
                        "speech_in_gap=%.2fs — %s); closing",
                        finals_seen,
                        covered_end,
                        tail_gap,
                        waited_ms,
                        flush_wait,
                        streamed_sec,
                        tail_speech,
                        verdict,
                    )
            # CloseStream, keepalive teardown, the recv-loop drain and
            # close() no longer happen here — they are shutdown()'s job,
            # run by the caller AFTER the envelope below has been sent.
            # See this method's docstring and C4.

        # Measured BEFORE the splice consumes the hypotheses: this is
        # the record of what was missing and of what was heard there
        # (audit §3.9). After the splice the words are in the
        # transcript and the evidence is gone.
        holes_before_splice = self._coverage_hole_spans()
        spliced_words = self._splice_uncovered_interim_words()
        # C6 (audit §3.8): merge seams exactly once and derive BOTH
        # ``text`` and ``segments`` from the same merged list. Previously
        # ``text`` went through ``final_text()`` (which merges) while
        # ``segments`` was the raw, unmerged list — the two fields
        # described different transcripts.
        merged_segments = merge_seam_fragments(list(self._finalized_segments))
        # Deepgram can transcribe a boundary word on both sides of an
        # is_final split ("two two" | "two two three three…") with no
        # splice involved at all; this is the one place both envelope
        # fields are derived from the merged list, so it runs before
        # either is built.
        merged_segments = drop_repeated_seam_ngrams(merged_segments)
        final_text = self._join_segment_texts(merged_segments)
        duration_sec = 0.0
        if merged_segments:
            duration_sec = float(
                max(s.get("end", 0.0) for s in merged_segments)
            )
        self.stats.finalize_ms = (time.perf_counter() - started) * 1000.0
        # 1.1.19: explicit DELTA logging — segments_final at ENTER vs
        # EXIT shows whether the Finalize sequence actually produced
        # trailing is_final segments. If segments_final didn't increase
        # between ENTER and EXIT, we know the flush is ineffective for
        # this session (likely region/network) and recovery is the only
        # path to the trailing words. "EXIT" now marks the transcript
        # being complete and ready to send, not the socket being closed
        # (C4) — that is logged separately by shutdown().
        logger.info(
            "deepgram-live: finalize EXIT %.0f ms text_len=%d segments_final=%d (delta from ENTER) duration_sec=%.2f bytes_sent=%d",
            self.stats.finalize_ms,
            len(final_text),
            self.stats.segments_final,
            duration_sec,
            self.stats.bytes_sent,
        )
        uncovered_speech_sec = self._uncovered_speech_sec()
        if uncovered_speech_sec > 0:
            logger.warning(
                "deepgram-live: %.2fs of recognised speech is not covered by any "
                "final segment — the committed transcript has holes",
                uncovered_speech_sec,
            )
        # Displacements trigger the block on their own: they are the one
        # loss shape that produces neither a splice nor uncovered
        # seconds, so gating the report on those two would have kept it
        # silent for exactly the defect it was extended to explain.
        # Read after the splice, which is the second place a hypothesis
        # can be discarded for being covered.
        if spliced_words or uncovered_speech_sec > 0 or self._overruled_total:
            self._log_coverage_holes(
                holes_before_splice, spliced_words, uncovered_speech_sec
            )
        streamed_sec = self.stats.bytes_sent / float(
            2 * max(1, int(self._cfg.sample_rate))
        )
        return {
            "text": final_text,
            "segments": merged_segments,
            "durationSec": round(duration_sec, 3),
            "stats": self.stats.as_dict(),
            # Seconds where Deepgram's own interims recognised words that
            # no final segment ever covered — see the WS handler's field
            # documentation next to this envelope key.
            "uncoveredSpeechSec": round(uncovered_speech_sec, 3),
            # C5: bytes actually delivered to Deepgram (not merely
            # captured — see ``bytes_offered``/``_tail_coverage`` for
            # that distinction), so the renderer can tell "the mic
            # captured N seconds" from "Deepgram actually processed N
            # seconds" without guessing from ``durationSec`` alone.
            "streamedSec": round(streamed_sec, 3),
            # End of the last finalized segment (post seam-merge) — the
            # point up to which the transcript is a committed final, as
            # opposed to spliced interim fallback or nothing at all.
            "coveredEndSec": round(duration_sec, 3),
        }

    async def shutdown(self, wait_timeout: float = 3.0) -> None:
        """Release the upstream connection after drain_transcript().

        Sends ``CloseStream`` (if drain_transcript() actually entered the
        Finalize dance — see ``_needs_close_stream``), cancels the
        keepalive task, waits up to ``wait_timeout`` for the recv loop to
        drain, then calls ``close()``. Every step is best-effort and
        independently guarded (matching ``close()``'s own idempotency),
        so this is safe to call even if drain_transcript() raised, or
        was never called at all.

        Deliberately does not touch anything drain_transcript() already
        produced — the transcript is done and, by the time a caller
        invokes this, likely already on the wire to the client (C4).
        """
        if self._ws is not None and self._needs_close_stream:
            try:
                # Same 5-second bound as send_pcm — a wedged TCP socket
                # mustn't hang shutdown indefinitely. The CloseStream
                # frame is tiny so the timeout only fires when the
                # underlying socket is genuinely stuck.
                await asyncio.wait_for(
                    self._ws.send(json.dumps({"type": "CloseStream"})),
                    timeout=5.0,
                )
                logger.info("deepgram-live: CloseStream sent")
            except asyncio.TimeoutError:
                logger.warning("deepgram-live: CloseStream send timed out (>5s)")
            except ConnectionClosed:
                logger.info("deepgram-live: CloseStream skipped (already closed)")
            except WebSocketException as e:
                logger.warning("deepgram-live: CloseStream send failed: %s", e)

        if self._keepalive_task is not None and not self._keepalive_task.done():
            self._keepalive_task.cancel()
            try:
                await self._keepalive_task
            except (asyncio.CancelledError, Exception):
                pass

        if self._recv_task is not None:
            try:
                await asyncio.wait_for(self._recv_task, timeout=wait_timeout)
            except asyncio.TimeoutError:
                logger.warning(
                    "deepgram-live: recv drain timeout (%.2fs)", wait_timeout
                )
                self._recv_task.cancel()
                try:
                    await self._recv_task
                except (asyncio.CancelledError, Exception):
                    pass

        await self.close()

    async def finalize(
        self,
        wait_timeout: float = 3.0,
        on_budget: "Optional[Callable[[float, bool], None]]" = None,
    ) -> dict:
        """Back-compat convenience: ``drain_transcript()`` then ``shutdown()``.

        Existing callers that want "give me the transcript and clean
        everything up, in one call" still get exactly that behaviour.
        The WS handler calls the two halves separately so it can send the
        ``final`` envelope in between — see ``drain_transcript()``'s
        docstring and C4.
        """
        result = await self.drain_transcript(on_budget=on_budget)
        await self.shutdown(wait_timeout=wait_timeout)
        return result

    def _word_covered_by_finals(self, word: dict) -> bool:
        """Is this interim word already in the committed transcript?

        Coverage is a property of WORDS, not of message windows (audit
        §3.1). A final answers for the words it carries; only a final
        that arrived without a word list falls back to its span, because
        then the span is the sole thing knowable about it.
        """
        return (
            self._covering_final_word_for(word) is not None
            or self._word_covered_by_spanless_final(word)
        )

    def _covering_final_word_for(self, word: dict) -> Optional[dict]:
        """The final WORD that answers for ``word``, across all finals.

        The first half of ``_word_covered_by_finals``, separated because
        the splice needs to NAME the word that overruled a hypothesis
        it is about to discard, not merely know that one exists.
        """
        for seg in self._finalized_segments:
            seg_words = _segment_words(seg)
            if not seg_words:
                continue
            owner = covering_final_word(word, seg_words)
            if owner is not None:
                return owner
        return None

    def _word_covered_by_spanless_final(self, word: dict) -> bool:
        """The other half: finals that arrived without a word list.

        They are merged into one span first — two adjacent finals
        meeting at 10.0 s cover a word centred exactly on the boundary,
        which neither of them covers on its own. There is no covering
        WORD to name in this case, only a span.
        """
        center = (_as_float(word.get("start")) + _as_float(word.get("end"))) / 2.0
        return any(
            c_start < center < c_end for c_start, c_end in self._spanless_coverage()
        )

    def _note_overruled_word(self, word: dict, owner: dict) -> None:
        """Record an interim word a DIFFERENTLY-SPELLED final answered for.

        The coverage rule's second clause: the final overlapped that
        audio by at least ``SPLICE_COVERAGE_OVERLAP_FRACTION`` of either
        word and wrote something whose letter core differs, so the
        interim word is dropped as a disagreement the final wins.

        That is right for "слушаю" vs "слушай" (one word, two
        spellings) and wrong for "трёх" vs "в" (two words, one of them
        gone) — 2026-09-03, session a9fd3fd9, where "трёх" lived only
        in an interim and never reached the user. Nothing in the log
        told the two shapes apart, so the rule could not be fixed from
        evidence. This IS that evidence and only that: the rule is
        unchanged.

        It has to be recorded at the moment of the drop, because that
        is the only moment both words exist together — the eviction
        deletes the interim word, and by finalize there is nothing left
        to notice. Copies are stored so a later splice into the host
        segment cannot rewrite the record.
        """
        core = _word_core(word)
        # An owner found by identity shares the core by construction
        # (``_same_spoken_word``), so this keeps exactly the
        # overlap-clause cases — the ones where a word went missing.
        if not core or core == _word_core(owner):
            return
        self._overruled_total += 1
        self._overruled_words.append((dict(word), dict(owner)))

    def _evict_words_covered_by(
        self, words: list[dict], final_words: list[dict]
    ) -> list[dict]:
        """Drop the retained words this final answers for, and say which.

        The eviction itself is unchanged (``covering_final_word`` is the
        same rule ``final_words_cover`` asks); it now names the covering
        word on its way past so a displacement leaves a trace.
        """
        kept: list[dict] = []
        for word in words:
            owner = covering_final_word(word, final_words)
            if owner is None:
                kept.append(word)
            else:
                self._note_overruled_word(word, owner)
        return kept

    def _spanless_coverage(self) -> list[tuple[float, float]]:
        """Merged spans of the finals that carry no word list.

        Their span is the only thing knowable about what they contain,
        so it stays the coverage test for them — and only for them.
        """
        return self._union(
            (_as_float(s.get("start")), _as_float(s.get("end")))
            for s in self._finalized_segments
            if not _segment_words(s)
        )

    def _host_final_for(self, word: dict) -> Optional[dict]:
        """The final segment a recovered word belongs INSIDE, if any.

        Word-level coverage makes holes possible in the middle of a
        final's span: "субагента" was spoken at 5.5-6.1 s inside a final
        covering 4.91-9.70 s whose text omitted it. Appending such a
        word as a separate trailing segment would put it after the whole
        clause it belongs in the middle of, so it is inserted into the
        host segment at its time position instead.
        """
        center = (_as_float(word.get("start")) + _as_float(word.get("end"))) / 2.0
        for seg in self._finalized_segments:
            if not _segment_words(seg):
                continue
            if _as_float(seg.get("start")) < center < _as_float(seg.get("end")):
                return seg
        return None

    def _nearest_final_word(self, time: float, before: bool) -> Optional[dict]:
        """The final word closest to ``time`` on the requested side.

        Feeds the splice's seam guard (rule 2/3 of the A/B fix): before a
        recovered word is allowed to become — or extend — a fallback
        segment at the edge of the assembled text, this is what sits on
        the other side of the seam it would create.
        """
        best: Optional[dict] = None
        for seg in self._finalized_segments:
            for w in _segment_words(seg):
                if before:
                    if _as_float(w.get("end")) <= time and (
                        best is None or _as_float(w.get("end")) > _as_float(best.get("end"))
                    ):
                        best = w
                else:
                    if _as_float(w.get("start")) >= time and (
                        best is None or _as_float(w.get("start")) < _as_float(best.get("start"))
                    ):
                        best = w
        return best

    @staticmethod
    def _fits_beside(word: dict, neighbour: Optional[dict], neighbour_before: bool) -> bool:
        """Same test as ``_insert_word_into_segment``'s guard, for a
        seam between segments instead of a position inside one word
        list: no stem match with the word on the other side of the
        seam, and enough room for this word's own duration.
        """
        if neighbour is None:
            return True
        stem = _word_stem(word)
        if stem and stem == _word_stem(neighbour):
            return False
        gap = (
            _as_float(word.get("start")) - _as_float(neighbour.get("end"))
            if neighbour_before
            else _as_float(neighbour.get("start")) - _as_float(word.get("end"))
        )
        return gap >= _word_duration(word) - SPLICE_GAP_SLACK_SEC

    @staticmethod
    def _insert_word_into_segment(segment: dict, word: dict) -> bool:
        """Put ``word`` into ``segment`` at its time position.

        The segment's own word list gives the position: the index is how
        many of its words start before this one. The text is edited at
        the same index so ``text`` and ``words`` keep describing one
        transcript; when the two do not have the same token count (the
        provider's transcript is not always a plain join of its words)
        the index is clamped rather than guessed at.

        Returns False, changing nothing, in two cases (audit A/B on the
        trilingual evidence recording, rules 2 and 3 of the splice
        guard):

        * the word would land immediately beside a word sharing its stem
          (``_word_stem`` — first ``_SPLICE_STEM_LETTERS`` letters of the
          alpha core). Such a pair is one spoken word whose boundary the
          re-decode moved, or that the two decodes spelled differently —
          "тебе тебе нужно", "посмотреть в в WAV" and "слушаю"/"слушай"
          are all this same failure. A recovery that reads as a stutter
          is not a recovery;
        * there is not enough room: the gap between this final's own
          neighbouring words (or the segment's own start/end, at an
          edge) is shorter than the word's duration less
          ``SPLICE_GAP_SLACK_SEC``. A final that already accounts for
          that time in a shape the coverage test did not recognise must
          not be overwritten by force-fitting a word into a slot too
          small for it.
        """
        seg_words = _segment_words(segment)
        index = sum(
            1 for w in seg_words if _as_float(w.get("start")) <= _as_float(word.get("start"))
        )
        stem = _word_stem(word)
        neighbours = seg_words[max(0, index - 1):index + 1]
        if stem and any(_word_stem(n) == stem for n in neighbours):
            return False
        prev_word = seg_words[index - 1] if index > 0 else None
        next_word = seg_words[index] if index < len(seg_words) else None
        before_bound = (
            _as_float(prev_word.get("end")) if prev_word else _as_float(segment.get("start"))
        )
        after_bound = (
            _as_float(next_word.get("start")) if next_word else _as_float(segment.get("end"))
        )
        if after_bound - before_bound < _word_duration(word) - SPLICE_GAP_SLACK_SEC:
            return False
        tokens = str(segment.get("text") or "").split()
        tokens.insert(min(index, len(tokens)), str(word.get("word") or ""))
        segment["text"] = " ".join(tokens)
        seg_words.insert(
            index,
            {
                "word": word.get("word"),
                "start": word.get("start"),
                "end": word.get("end"),
            },
        )
        segment["words"] = seg_words
        # Diagnostic only (like ``source`` on the fallback segments
        # below): says this final was repaired, and by how much.
        segment["splicedWords"] = int(segment.get("splicedWords") or 0) + 1
        return True

    def _splice_uncovered_interim_words(self) -> int:
        """Fold interim-recognised words no final ever covered into the
        committed transcript, in time order.

        Returns the number of words spliced. After this runs,
        ``_uncovered_speech_sec`` measures only speech Deepgram itself
        never hypothesised — the honest residual, not the recoverable
        loss it used to be.
        """
        # Orphan-vs-interim dedupe (BUG-78): a word displaced to the
        # orphan pool can be re-emitted by a LATER interim at shifted
        # times — the rolling re-decode moves word boundaries. Both
        # copies would survive the coverage test and the splice would
        # emit the same spoken word twice. ``word_accounted_for`` is the
        # same predicate the interim purge uses; the interim copy wins
        # (newer hypothesis). Legit repeats ("да, да") have disjoint
        # times and survive.
        candidates_deduped = [
            w for w in self._orphan_interim_words
            if not word_accounted_for(w, self._interim_words)
        ]
        candidates = self._interim_words + candidates_deduped
        if not candidates:
            self._orphan_interim_words = []
            return 0
        # Hypotheses are consumed exactly once: whether they were
        # spliced or judged covered-and-discarded here, keeping them
        # would let a second finalize() call splice duplicates.
        orphan_count = len(self._orphan_interim_words)
        self._interim_words = []
        self._orphan_interim_words = []
        if orphan_count:
            logger.info(
                "deepgram-live: splice pool included %d orphaned interim words",
                orphan_count,
            )
        survivors: list[dict] = []
        for word in sorted(candidates, key=lambda w: (w["start"], w["end"])):
            owner = self._covering_final_word_for(word)
            if owner is not None:
                # The second place a hypothesis is discarded for being
                # covered — same rule, same record (``_note_overruled_word``).
                self._note_overruled_word(word, owner)
                continue
            if self._word_covered_by_spanless_final(word):
                continue
            survivors.append(word)
        if not survivors:
            return 0

        # Words that fall inside a final's span go back into that final,
        # at their time position; only words outside every final become
        # segments of their own.
        inserted = 0
        outside: list[dict] = []
        for word in survivors:
            host = self._host_final_for(word)
            if host is None:
                outside.append(word)
                continue
            if self._insert_word_into_segment(host, word):
                inserted += 1
        if not outside:
            if inserted:
                logger.warning(
                    "deepgram-live: spliced %d uncovered interim word(s) back "
                    "into the finals that omitted them",
                    inserted,
                )
            return inserted
        survivors = outside

        # Group consecutive words into segments; a silence gap longer
        # than INTERIM_WORD_GAP_SPLIT_SEC starts a new group so words
        # from different clauses do not fuse into one run-on blob.
        groups: list[list[dict]] = [[survivors[0]]]
        for prev, cur in zip(survivors, survivors[1:]):
            if cur["start"] - prev["end"] > INTERIM_WORD_GAP_SPLIT_SEC:
                groups.append([cur])
            else:
                groups[-1].append(cur)

        # Seam guard (rule 2/3 of the A/B fix): a group about to become a
        # brand-new fallback segment sits at a SEAM against whatever
        # finals are already in the transcript, and nothing has checked
        # that seam yet — the per-final neighbour guard in
        # ``_insert_word_into_segment`` only ever runs when a word has a
        # host final to be inserted INTO. Trim from each end until the
        # boundary word both differs in stem from, and has room beside,
        # the nearest final word on that side; a group can shrink to
        # nothing; only internal words (never checked against a final,
        # by construction — they are already the interior of one
        # recovered run of speech) are exempt. This is what stops "them"
        # (recovered) landing next to the final's own "them", and
        # "WAV"/"WAB" doing the same across a fallback-segment seam.
        trimmed_groups: list[list[dict]] = []
        for group in groups:
            group = list(group)
            while group:
                prev_word = self._nearest_final_word(group[0]["start"], before=True)
                if not self._fits_beside(group[0], prev_word, neighbour_before=True):
                    group.pop(0)
                    continue
                next_word = self._nearest_final_word(group[-1]["end"], before=False)
                if not self._fits_beside(group[-1], next_word, neighbour_before=False):
                    group.pop()
                    continue
                break
            if group:
                trimmed_groups.append(group)
        groups = trimmed_groups
        if not groups:
            if inserted:
                logger.warning(
                    "deepgram-live: spliced %d uncovered interim word(s) back "
                    "into the finals that omitted them",
                    inserted,
                )
            return inserted
        spliced_outside = sum(len(group) for group in groups)

        fallback_segments = [
            {
                "start": round(group[0]["start"], 3),
                "end": round(max(w["end"] for w in group), 3),
                "text": " ".join(str(w["word"]) for w in group),
                "confidence": 0.0,
                "is_final": True,
                "speech_final": False,
                # The recovered words travel with the segment they
                # became, exactly like a native final's — so seam repair
                # and coverage read one shape, not two.
                "words": [dict(w) for w in group],
                # Distinguishes recovered content from native finals;
                # the frontend merges by time and text like any other
                # segment, so this is diagnostic metadata only.
                "source": "interim-fallback",
            }
            for group in groups
        ]
        self._finalized_segments = sorted(
            [*self._finalized_segments, *fallback_segments],
            key=lambda s: (float(s.get("start", 0.0)), float(s.get("end", 0.0))),
        )
        logger.warning(
            "deepgram-live: spliced %d uncovered interim words across %d "
            "fallback segment(s) into the final transcript "
            "(+%d word(s) put back inside the finals that omitted them)",
            spliced_outside,
            len(fallback_segments),
            inserted,
        )
        return spliced_outside + inserted

    def _log_coverage_holes(
        self,
        holes: list[tuple[float, float]],
        spliced_words: int,
        uncovered_sec: float,
    ) -> None:
        """One block naming every hole and what was heard over it.

        Audit §3.9: the per-interim sampling line records a LENGTH, so
        when words went missing from a shipped recording the log could
        not say whether Deepgram had ever heard them — the question that
        took a re-run of the audio to answer. This prints, once per
        stop and only when something was actually missing, each hole
        span next to the interim hypotheses that overlapped it.

        The overruled words recorded during the session
        (``_note_overruled_word``) are listed too: they are the other
        way a word goes missing, the one that leaves no hole behind
        because a differently-spelled final word claimed its audio.
        They belong in this block rather than one of their own so that
        a reader chasing a missing word has exactly one place to look.

        Bounded on every axis: the ring holds the newest
        ``INTERIM_HYPOTHESIS_RING_SIZE`` hypotheses, at most
        ``_HOLE_REPORT_MAX_INTERIMS`` are printed per hole, at most
        ``_HOLE_REPORT_MAX_OVERRULED`` overruled words are printed, and
        each line is truncated to ``_HOLE_REPORT_TEXT_CHARS``.
        """
        overruled = list(self._overruled_words)
        lines = [
            "deepgram-live: coverage holes at finalize "
            f"(spliced_words={spliced_words} uncovered={uncovered_sec:.2f}s "
            f"holes={len(holes)} overruled={self._overruled_total})"
        ]
        if not holes:
            lines.append("  (no hole spans — words were recovered before measuring)")
        for h_start, h_end in holes:
            lines.append(
                f"  hole {h_start:.2f}-{h_end:.2f}s ({h_end - h_start:.2f}s)"
            )
            touching = [
                (i_start, i_end, text)
                for i_start, i_end, text in self._interim_ring
                if i_end > h_start and i_start < h_end
            ]
            if not touching:
                lines.append("    interim: (none retained for this span)")
                continue
            for i_start, i_end, text in touching[-_HOLE_REPORT_MAX_INTERIMS:]:
                clipped = text[:_HOLE_REPORT_TEXT_CHARS]
                suffix = "…" if len(text) > _HOLE_REPORT_TEXT_CHARS else ""
                lines.append(
                    f"    interim [{i_start:.2f}-{i_end:.2f}] {clipped!r}{suffix}"
                )
        if overruled:
            lines.append(
                "  overruled interim words — judged covered by a "
                f"DIFFERENT final word ({self._overruled_total}):"
            )
            for word, owner in overruled[:_HOLE_REPORT_MAX_OVERRULED]:
                lines.append(
                    "    overruled interim "
                    f"[{_as_float(word.get('start')):.2f}-"
                    f"{_as_float(word.get('end')):.2f}] "
                    f"{str(word.get('word') or '')!r} → final "
                    f"[{_as_float(owner.get('start')):.2f}-"
                    f"{_as_float(owner.get('end')):.2f}] "
                    f"{str(owner.get('word') or '')!r} "
                    f"(overlap {max(0.0, _time_overlap(word, owner)):.2f}s)"
                )
            not_shown = self._overruled_total - min(
                len(overruled), _HOLE_REPORT_MAX_OVERRULED
            )
            if not_shown > 0:
                lines.append(f"    … {not_shown} more not shown")
        logger.info("\n".join(lines))

    def _tail_coverage(self) -> tuple[float, float, float, float]:
        """What is unflushed at the end of the stream.

        Returns ``(streamed_sec, covered_end_sec, tail_gap_sec,
        tail_speech_sec)``.

        ``tail_gap_sec`` is raw audio past the last finalized segment.
        ``tail_speech_sec`` is the part of that gap where an interim
        actually *recognised words*.

        The distinction is the whole point. A user finishes a sentence
        and then reaches for the stop hotkey, so almost every recording
        ends with a second or two of streamed silence. Measured by audio
        alone, that silence reads as "unflushed tail" and triggers the
        retry path — a 3 s wait, a second Finalize, another 3 s wait —
        to discover that Deepgram had nothing to send, because there was
        nothing there. Observed in main.log: a 54.0 s recording whose
        last final ended at 52.08 s spent 6272 ms at finalize and
        spliced nothing, twice over in consecutive sessions.

        With ``interim_results`` on, Deepgram emits a hypothesis as it
        decodes, so a trailing region that produced no interim produced
        no words — and a Finalize cannot flush words that were never
        decoded. Speech is therefore the signal that says whether
        waiting can possibly pay.

        Derived entirely from state we already hold, so it can be
        consulted *before* deciding how long to wait rather than only
        after a wait has expired.

        ``streamed_sec`` is deliberately ``max(bytes_offered, bytes_sent)``
        rather than ``bytes_sent`` alone (B1, audit §3.6): a mid-stream
        send timeout drops the chunk from ``bytes_sent`` but the audio
        was still captured, so using the smaller, "actually delivered"
        count would shrink ``tail_gap`` and could hide a real hole. A
        session that never drops a send has ``bytes_offered ==
        bytes_sent`` and this is a no-op.
        """
        streamed_sec = max(self.stats.bytes_offered, self.stats.bytes_sent) / (
            2 * max(1, int(self._cfg.sample_rate))
        )
        covered_end = max(
            (float(seg.get("end", 0.0) or 0.0) for seg in self._finalized_segments),
            default=0.0,
        )
        tail_gap = streamed_sec - covered_end
        # Recognised speech lying past the last final. Spans are clipped
        # to the uncovered region and merged, so overlapping interims
        # (a rolling re-decode emits many) cannot be counted twice.
        tail_speech = 0.0
        if tail_gap > 0 and self._interim_speech_spans:
            clipped = sorted(
                (max(start, covered_end), min(end, streamed_sec))
                for start, end in self._interim_speech_spans
                if end > covered_end
            )
            merged_end = covered_end
            for start, end in clipped:
                if end <= start:
                    continue
                start = max(start, merged_end)
                if end > start:
                    tail_speech += end - start
                    merged_end = end
        # UtteranceEnd evidence (C7, audit §3.5): Deepgram's own signal
        # that the utterance ended at ``last_word_end``, distinct from
        # (and stronger than) "no interim has spoken up recently" — the
        # absence of interims is ambiguous (a quiet provider looks the
        # same as a quiet user), but an UtteranceEnd is an affirmative
        # claim. When it falls inside the current tail AND nothing since
        # has recognised speech past it, the audio beyond it is confirmed
        # silence, not an unflushed tail — shrink the gap to only the
        # confirmed-uncertain span. A later interim carrying speech past
        # the UtteranceEnd (the utterance resumed) leaves tail_gap alone.
        utterance_end = self._last_utterance_end
        if (
            utterance_end is not None
            and covered_end <= utterance_end < streamed_sec
            and not any(
                sp_end > utterance_end for _sp_start, sp_end in self._interim_speech_spans
            )
        ):
            tail_gap = max(0.0, utterance_end - covered_end)
        return streamed_sec, covered_end, tail_gap, tail_speech

    def _tail_needs_flush(self, tail_gap: float, tail_speech: float) -> bool:
        """Is the trailing region worth waiting — and retrying — for?

        UNCOVERED AUDIO decides. Recognised speech in the gap is an
        additional reason to retry, never a reason not to.

        This briefly gated on speech alone, on the reasoning that with
        ``interim_results`` on a region producing no interim produced no
        words, so a Finalize could not flush what was never decoded.
        That premise is false in exactly the case the guard exists for.
        Measured in production, one stop after it shipped:

            streamed=20.08s covered=16.07s gap=4.01s speech_in_gap=0.00s

        Four seconds of the user's speech, and the speech signal read
        zero — because Deepgram had stopped emitting interims 3.7 s
        before Stop and then never flushed the final either. A provider
        that goes quiet and a user who stops talking look identical to
        this signal, and the first is precisely the failure mode that
        loses a tail. Absence of interims is not evidence of absence of
        speech.

        So the signal can only add confidence, never remove it. The cost
        is that a pause before Stop still pays the retry path; losing
        the user's closing sentence is not a trade worth three seconds.
        ``speech_in_gap`` stays measured and logged — it is genuinely
        useful for telling the two shapes apart after the fact, which is
        how this was caught.
        """
        return tail_gap >= TAIL_GUARD_MIN_SEC or tail_speech >= TAIL_GUARD_MIN_SEC

    def _last_final_ended_the_utterance(self) -> bool:
        """Did the newest final claim to end where the speaker stopped?

        ``speech_final=true`` is Deepgram saying it closed the utterance
        at an endpoint it detected; ``false`` says the final was forced
        out mid-utterance (which is exactly what ``Finalize`` does), so
        more of the same utterance may still be on its way.

        True when there is no final to judge: the caller only consults
        this to decide whether to keep waiting, and "we have heard
        nothing at all" is a question ``_tail_needs_flush`` answers on
        the audio, which is the stronger signal.
        """
        if not self._finalized_segments:
            return True
        return bool(self._finalized_segments[-1].get("speech_final"))

    def _tail_awaits_more_finals(self, tail_gap: float, tail_speech: float) -> bool:
        """Is the post-Finalize flush still incomplete?

        Asked after each final that lands during the flush wait, to
        decide whether the wait has been answered or only partly
        answered. Two ways it can still be owed:

        * the tail is uncovered by the same measure the retry uses
          (``_tail_needs_flush``) — the flush has not reached the end of
          the streamed audio; or
        * the newest final was forced out mid-utterance
          (``speech_final=false``) and something, however small, still
          lies past it. Deepgram splits a forced flush across finals,
          and the continuation carries the rest of that clause.

        A gap no larger than ``COVERAGE_GAP_MIN_SEC`` is segment-boundary
        jitter, not a tail (the same floor the budget uses), so it ends
        the wait whatever ``speech_final`` said — otherwise every stop
        landing mid-utterance would burn its whole budget on a sliver.
        """
        if self._tail_needs_flush(tail_gap, tail_speech):
            return True
        if tail_gap <= COVERAGE_GAP_MIN_SEC:
            return False
        return not self._last_final_ended_the_utterance()

    @staticmethod
    def _union(spans: Iterable[tuple[float, float]]) -> list[tuple[float, float]]:
        """Merge overlapping spans so nothing is measured twice."""
        merged: list[tuple[float, float]] = []
        for start, end in sorted(s for s in spans if s[1] > s[0]):
            if merged and start <= merged[-1][1]:
                merged[-1] = (merged[-1][0], max(merged[-1][1], end))
            else:
                merged.append((start, end))
        return merged

    def _final_coverage(self) -> list[tuple[float, float]]:
        return self._union(
            (_as_float(s.get("start")), _as_float(s.get("end")))
            for s in self._finalized_segments
        )

    def _uncovered_word_spans(self) -> list[tuple[float, float]]:
        """Spans of retained interim words no final accounts for.

        The raw evidence, unclipped: these are exactly the words the
        splice is about to recover, so the finalize report can name the
        ground they were found on even when it lies outside anything the
        span-level measurement can see (a hypothesis too short to count
        as speech still carries real words).
        """
        return self._union(
            (_as_float(w.get("start")), _as_float(w.get("end")))
            for w in (*self._interim_words, *self._orphan_interim_words)
            if not self._word_covered_by_finals(w)
        )

    def _word_level_holes(self) -> list[tuple[float, float]]:
        """Spans of interim-heard words that no final WORD accounts for.

        Clipped to the ground the finals CLAIM to cover, because that is
        exactly where the span-level measurement below is structurally
        blind: contiguous finals leave no gap to measure, and a word
        they simply failed to transcribe disappears without trace
        (audit §3.4 — the 12 s recording whose finals ran 0-4.91-9.70-
        12.11 and whose metric read 0 while "субагента" was gone).

        No minimum applies here. A hole this measurement can see is a
        specific missing WORD, and one word is a few hundred
        milliseconds — the 0.25 s floor that keeps segment-boundary
        jitter out of the span measurement would discard every one of
        them.
        """
        covered = self._final_coverage()
        if not covered:
            return []
        clipped: list[tuple[float, float]] = []
        for w_start, w_end in self._uncovered_word_spans():
            for c_start, c_end in covered:
                lo = max(w_start, c_start)
                hi = min(w_end, c_end)
                if hi > lo:
                    clipped.append((lo, hi))
        return self._union(clipped)

    def _coverage_hole_spans(self) -> list[tuple[float, float]]:
        """Every span this session believes is missing from the transcript.

        The union of the word-level evidence — unclipped, so a region no
        final reached at all is named too — with the span-level holes.
        Used for the finalize report (audit §3.9), which needs the
        SPANS; ``_uncovered_speech_sec`` needs a total instead and
        charges each region to exactly one measurement.
        """
        return self._union([*self._uncovered_word_spans(), *self._span_level_holes()])

    def _span_level_holes(self) -> list[tuple[float, float]]:
        """Spans where an interim heard speech and no final landed at all.

        The original measurement, unchanged: interim speech minus final
        coverage, with sub-``COVERAGE_GAP_MIN_SEC`` slivers dropped as
        segment-boundary jitter. It is the only thing available for a
        hypothesis that arrived without word timings, and it is what
        sees a region no final reached.
        """
        if not self._finalized_segments or not self._interim_speech_spans:
            return []
        covered = self._final_coverage()
        speech = self._union(self._interim_speech_spans)
        holes: list[tuple[float, float]] = []

        def _add(start: float, end: float) -> None:
            if end - start >= COVERAGE_GAP_MIN_SEC:
                holes.append((start, end))

        for sp_start, sp_end in speech:
            cursor = sp_start
            for c_start, c_end in covered:
                if c_end <= cursor:
                    continue
                if c_start >= sp_end:
                    break
                if c_start > cursor:
                    _add(cursor, c_start)
                cursor = max(cursor, c_end)
                if cursor >= sp_end:
                    break
            if cursor < sp_end:
                _add(cursor, sp_end)
        return holes

    def _uncovered_speech_sec(self) -> float:
        """Seconds where an interim heard words but no final ever landed.

        Deepgram can emit a final that stops short of what its own
        interim already recognised and then resume the next final past
        the difference. Observed in main.log: a final ended at 455.78 s,
        the next started at 460.09 s, and interim #446 had covered
        452.76-457.56 s carrying 75 characters. Those words are simply
        absent from the committed transcript.

        Ordinary pauses do not register: silence produces no interims
        with text, so a gap with no overlapping speech span contributes
        nothing. This measures only holes the service itself contradicts.

        TWO measurements, over disjoint ground, added:

        * ``_span_level_holes`` — regions no final reached at all, the
          original time-difference measure with its jitter floor;
        * ``_word_level_holes`` — words no final CARRIED, inside the
          span the finals do cover, where a time difference is zero by
          construction (audit §3.4).

        Each region is charged to exactly one of the two, so a word that
        is both outside every final and unaccounted for cannot be
        counted twice.
        """
        word_total = sum(end - start for start, end in self._word_level_holes())
        span_total = sum(end - start for start, end in self._span_level_holes())
        return word_total + span_total

    async def discard(self) -> None:
        """Close a session the CALLER has decided to replace.

        Identical to ``close()`` except that the teardown is not
        reported as an error. A caller that swaps one upstream socket
        for another mid-recording (the warm-socket liveness path in
        ``backend.main``, audit §3.7) is performing the recovery, not
        suffering a failure: routing the resulting ``ConnectionClosed``
        through ``_report_error`` would push ``{"fatal": true}`` at the
        renderer and abort a recording that is about to continue on the
        replacement socket.

        Flipping ``_closed`` first also makes every in-flight
        ``send_pcm`` a silent no-op, so audio still in the caller's send
        queue is not written into a socket that is going away — it is
        replayed into the new one instead.
        """
        self._discarded = True
        self._closed = True
        await self.close()

    async def close(self) -> None:
        """Idempotently release the upstream socket and background tasks."""
        if self._close_ran:
            return
        self._close_ran = True
        self._closed = True

        if self._keepalive_task is not None and not self._keepalive_task.done():
            self._keepalive_task.cancel()
            try:
                await self._keepalive_task
            except (asyncio.CancelledError, Exception):
                pass

        ws = self._ws
        self._ws = None
        if ws is not None:
            try:
                await ws.close()
            except Exception as e:
                logger.debug("deepgram-live: close() ignored: %s", e)

        # Also cancel and await the recv task. Without this, if the
        # upstream TCP connection is wedged such that `ws.close()`
        # returns before the peer actually closes, `_recv_loop`
        # continues running until the OS-level RST eventually lands —
        # potentially seconds. During that window, _recv_task holds
        # references to the socket, queue, and closures, leaking the
        # whole session object well past the caller's lifetime.
        # Mirror finalize()'s bounded cancel pattern.
        if self._recv_task is not None and not self._recv_task.done():
            self._recv_task.cancel()
            try:
                await asyncio.wait_for(self._recv_task, timeout=2.0)
            except (asyncio.CancelledError, asyncio.TimeoutError):
                pass
            except Exception as e:
                logger.debug("deepgram-live: close() recv_task await: %s", e)

        # Ensure any consumer blocked on events() unblocks. The sentinel
        # is routed through _enqueue_event so it survives overflow — if
        # the queue is full of interim events, one is evicted to make
        # room, guaranteeing the consumer sees termination.
        self._enqueue_event(self._QUEUE_SENTINEL, is_critical=True)

    # ----- Accessors --------------------------------------------------------

    @property
    def is_closed(self) -> bool:
        return self._closed

    @property
    def last_error(self) -> Optional[str]:
        return self._last_error

    @property
    def last_fatal(self) -> bool:
        return self._last_fatal

    @staticmethod
    def _join_segment_texts(segments: Iterable[dict]) -> str:
        """SSOT join: the ONE place seam-merged segments become ``text``.

        ``final_text()`` and ``drain_transcript()`` both go through this
        so ``text`` and ``segments`` in the envelope can never describe
        different transcripts (C6, audit §3.8) — they are built from
        exactly the same merged list.
        """
        parts = [str(seg.get("text") or "").strip() for seg in segments]
        return " ".join(p for p in parts if p).strip()

    def final_text(self) -> str:
        """Best-effort transcript text independent of drain_transcript().

        Used on the error path where ``drain_transcript()`` itself raised
        and there is no merged-segment list to reuse (see the WS
        handler's exception branch) — recomputes the seam merge on
        demand. The normal path computes the merge once inside
        ``drain_transcript()`` and reuses it for both ``text`` and
        ``segments`` rather than calling this method.
        """
        return self._join_segment_texts(
            drop_repeated_seam_ngrams(merge_seam_fragments(list(self._finalized_segments)))
        )

    # ----- Internals --------------------------------------------------------

    def _enqueue_event(self, event: object, *, is_critical: bool) -> None:
        """Put an event on the bounded queue with smart overflow handling.

        Priority (highest → lowest):

        1. ``QUEUE_SENTINEL`` — drains the entire queue if necessary to
           land. Its whole purpose is consumer termination, so dropping
           queued data is the correct trade-off; without this guarantee
           ``events()`` would hang on pathological queue saturation.
        2. ``is_critical=True`` (finals, errors) — evicts the oldest
           interim to make room. If no interim exists the critical event
           is unavoidably dropped with an error log.
        3. ``is_critical=False`` (interim segments) — drops on overflow
           and logs a one-shot warning.
        """
        # Fast path: queue has room.
        try:
            self._event_queue.put_nowait(event)
            return
        except asyncio.QueueFull:
            pass
        except RuntimeError as e:
            logger.debug("deepgram-live: enqueue runtime error: %s", e)
            return
        # --- Overflow path ---
        if event is self._QUEUE_SENTINEL:
            # Sentinel MUST land. Drain the queue (up to current size)
            # and re-enqueue. This only fires on close()/recv-exit, so
            # any queued interim or final is being discarded during
            # session-end anyway — consumer termination is paramount.
            for _ in range(self._event_queue.qsize() + 1):
                try:
                    self._event_queue.get_nowait()
                except asyncio.QueueEmpty:
                    break
            try:
                self._event_queue.put_nowait(event)
            except (asyncio.QueueFull, RuntimeError) as e:
                logger.error("deepgram-live: sentinel land failed after drain: %s", e)
            return
        if not is_critical:
            # Slow consumer — drop this interim.
            if not self._queue_overflow_warned:
                self._queue_overflow_warned = True
                logger.warning(
                    "deepgram-live: event queue full (cap=%d); dropping interim segments",
                    self._event_queue.maxsize,
                )
            return
        # Critical (non-sentinel): evict the oldest queued interim to
        # make room, then append the new event at the TAIL.
        #
        # ORDER IS THE CONTRACT. Consumers merge segments in arrival
        # order, so the queue must stay FIFO across an eviction. The
        # previous implementation popped items until it found an
        # interim, then re-enqueued those popped head items — which put
        # them BEHIND everything still sitting in the queue. Committed
        # ``is_final`` segments were silently reordered and the user saw
        # scrambled sentences whenever the renderer fell behind.
        #
        # Correct approach: drain the WHOLE queue into a list (order
        # preserved), drop the first interim from that list, append the
        # new event, and push the list back in the same order.
        drained: list[object] = []
        try:
            while True:
                drained.append(self._event_queue.get_nowait())
        except asyncio.QueueEmpty:
            pass
        except RuntimeError:
            return
        victim_index = next(
            (
                i
                for i, item in enumerate(drained)
                if isinstance(item, dict) and item.get("type") == "interim"
            ),
            -1,
        )
        if victim_index >= 0:
            drained.pop(victim_index)
            drained.append(event)
        else:
            logger.error(
                "deepgram-live: queue full with no interim to evict; "
                "critical event dropped: %r",
                event,
            )
        for item in drained:
            try:
                self._event_queue.put_nowait(item)
            except (asyncio.QueueFull, RuntimeError) as e:
                logger.error("deepgram-live: re-enqueue after eviction failed: %s", e)
                break

    def _report_error(self, message: str, *, fatal: bool) -> None:
        """Record an error and push a normalized error event to the queue."""
        if self._discarded:
            # The caller replaced this socket deliberately (``discard()``).
            # Everything the teardown raises from here on is the expected
            # consequence of that decision, not a failure the user needs
            # to see — and emitting it would abort the recording that is
            # already continuing on the replacement socket.
            logger.debug("deepgram-live: error on discarded session: %s", message)
            return
        self._last_error = message
        self._last_fatal = fatal or self._last_fatal
        logger.warning(
            "deepgram-live: error (fatal=%s): %s", fatal, message
        )
        self._enqueue_event(
            {"type": "error", "error": message, "fatal": bool(fatal)},
            is_critical=True,
        )
        if fatal:
            self._closed = True

    async def _recv_loop(self) -> None:
        assert self._ws is not None
        try:
            async for raw in self._ws:
                if isinstance(raw, (bytes, bytearray)):
                    # Deepgram may send keepalive binary frames; ignore.
                    continue
                try:
                    msg = json.loads(raw)
                except (ValueError, TypeError):
                    logger.debug("deepgram-live: non-json frame ignored")
                    continue
                if not isinstance(msg, dict):
                    continue
                self.stats.last_recv_at = time.monotonic()
                event = self._process_deepgram_message(msg)
                if event is not None:
                    # Finals, errors, and segment events are critical;
                    # interims can be dropped under back-pressure.
                    ev_type = event.get("type") if isinstance(event, dict) else ""
                    is_interim = ev_type == "interim"
                    self._enqueue_event(event, is_critical=not is_interim)
        except ConnectionClosed as e:
            code = getattr(e, "code", None)
            reason = getattr(e, "reason", "") or ""
            logger.info(
                "deepgram-live: upstream closed code=%s reason=%s finalize_sent=%s final_segs=%d",
                code,
                reason,
                self._finalize_sent,
                self.stats.segments_final,
            )
            # Normal closure codes — nothing to report.
            if code in (None, 1000, 1001, 1005) or self._finalize_sent:
                pass
            elif self.stats.segments_final > 0:
                # Stream dropped mid-session, BUT we already committed
                # some final segments. Don't raise a fatal error — the
                # caller will use the committed text as the transcript.
                # This is the common case when Deepgram closes an idle
                # connection that we haven't managed to keep awake.
                logger.warning(
                    "deepgram-live: stream ended early with %d committed segments, using them as transcript",
                    self.stats.segments_final,
                )
                self._last_error = (
                    f"stream ended early (code={code}, reason={reason or 'none'})"
                )
            else:
                # No committed text and the stream dropped — this IS a
                # fatal error the caller must surface.
                self._report_error(
                    f"Deepgram upstream closed unexpectedly (code={code}, reason={reason or 'none'})",
                    fatal=True,
                )
        except asyncio.CancelledError:
            raise
        except Exception as e:
            # Same logic: if we have committed segments, don't scream
            # at the user — use what we have.
            if self.stats.segments_final > 0:
                logger.warning(
                    "deepgram-live: recv error after %d committed segments: %s",
                    self.stats.segments_final,
                    e,
                )
                self._last_error = f"recv error: {e}"
            else:
                self._report_error(f"Deepgram recv error: {e}", fatal=True)
                logger.error("deepgram-live: recv_loop exception", exc_info=True)
        finally:
            self._closed = True
            self._enqueue_event(self._QUEUE_SENTINEL, is_critical=True)

    async def _keepalive_loop(self) -> None:
        """Emit ``{"type":"KeepAlive"}`` on prolonged upstream idle.

        Deepgram auto-closes an idle WebSocket after ~10 seconds. During
        quiet moments (long pauses or end-of-sentence silence) the
        frontend still sends PCM frames, but those can shrink below the
        threshold that keeps Deepgram happy. Emitting an explicit
        KeepAlive control message costs nothing and prevents unexpected
        disconnects.

        This is also the whole mechanism keeping a PRE-WARMED socket
        open, where no audio flows at all — Deepgram documents the
        10 s idle timeout as reset by "audio data or ``KeepAlive``
        messages", so no silence-frame trickle is needed. See
        ``backend.deepgram_warm`` for the cited sentences and for the
        4 s cadence a warm socket is constructed with.
        """
        try:
            while not self._closed and self._ws is not None:
                await asyncio.sleep(self._keepalive_interval_sec)
                # 1.1.25: snapshot ``self._ws`` BEFORE the send. close()
                # on the same event loop can null ``self._ws`` after we
                # passed the guard but before ``self._ws.send(...)``
                # re-reads the attribute, raising AttributeError on
                # ``None.send``. Snapshotting under the no-await window
                # of the guard makes the send a real WebSocket reference
                # whose own send-error semantics we already handle.
                ws = self._ws
                if self._closed or ws is None:
                    return
                last = self.stats.last_send_at or 0.0
                idle_for = time.monotonic() - last if last else float("inf")
                if idle_for < self._keepalive_idle_threshold_sec:
                    continue
                try:
                    await ws.send(json.dumps({"type": "KeepAlive"}))
                    self.stats.keepalives_sent += 1
                    self.stats.last_keepalive_at = time.monotonic()
                    logger.debug(
                        "deepgram-live: sent KeepAlive after %.1fs idle",
                        idle_for,
                    )
                except ConnectionClosed:
                    return
                except WebSocketException as e:
                    logger.debug("deepgram-live: KeepAlive send failed: %s", e)
                    return
                except AttributeError:
                    # Race lost: close() ran between our snapshot and the
                    # send call (rare but observed under heavy load).
                    return
        except asyncio.CancelledError:
            raise

    def _process_deepgram_message(self, msg: dict) -> Optional[dict]:
        mtype = msg.get("type")

        if mtype == "Metadata":
            logger.debug(
                "deepgram-live: metadata request_id=%s",
                str(msg.get("request_id") or "")[:12],
            )
            return None

        if mtype == "SpeechStarted":
            return None

        if mtype == "UtteranceEnd":
            # C7 (audit §3.5): Deepgram's own "the utterance ended here"
            # signal — record it so ``_tail_coverage`` can tell confirmed
            # trailing silence apart from a tail that merely has no
            # recent interim (ambiguous: a quiet provider looks the same).
            last_word_end = msg.get("last_word_end")
            try:
                value = float(last_word_end) if last_word_end is not None else None
            except (TypeError, ValueError):
                value = None
            if value is not None:
                self._last_utterance_end = value
                logger.debug(
                    "deepgram-live: UtteranceEnd last_word_end=%.2f", value,
                )
            return None

        if mtype == "Error":
            err = str(msg.get("description") or msg.get("message") or msg)[:300]
            self._report_error(f"Deepgram upstream error: {err}", fatal=False)
            return None

        if mtype != "Results":
            logger.debug("deepgram-live: unknown message type=%s", mtype)
            return None

        channel = msg.get("channel")
        if not isinstance(channel, dict):
            return None
        alts = channel.get("alternatives")
        if not isinstance(alts, list) or not alts:
            return None
        alt = alts[0]
        if not isinstance(alt, dict):
            return None
        text = str(alt.get("transcript") or "").strip()
        if not text:
            return None

        # Defensive numeric coercion (module-level ``_as_float``): a
        # malformed upstream message (non-numeric
        # ``start``/``duration``/``confidence``) must NEVER crash the
        # recv loop, because that would terminate the whole recording
        # session over a single stray frame. Invalid numerics degrade to
        # 0.0 and the segment still renders.
        start = _as_float(msg.get("start"))
        duration = _as_float(msg.get("duration"))
        end = start + duration
        is_final = bool(msg.get("is_final"))
        speech_final = bool(msg.get("speech_final"))
        confidence = _as_float(alt.get("confidence"))

        # When diarization is enabled, Deepgram populates ``words`` with a
        # per-word ``speaker`` index (0, 1, 2, ...). We expose the
        # dominant speaker for the segment so the frontend can render
        # "Speaker 0: hello world".
        raw_words = alt.get("words")
        speaker: Optional[int] = None
        if self._cfg.diarize:
            speaker = self._dominant_speaker(raw_words)

        # Parsed on EVERY Results frame, interim and final alike (audit
        # §3.1). The word list is what a message actually CONTAINS; its
        # start/duration is only the window it was decoded over, and
        # treating the window as the content is what evicted words the
        # final never carried.
        message_words = normalize_words(raw_words)

        segment = {
            "start": round(start, 3),
            "end": round(end, 3),
            "text": text,
            "confidence": round(confidence, 3),
            "is_final": is_final,
            "speech_final": speech_final,
        }
        if speaker is not None:
            segment["speaker"] = speaker

        if is_final:
            # The final's own words travel with it, so every later
            # coverage question ("is this interim word already in the
            # transcript?") is answered from the transcript itself
            # rather than from its time window.
            segment["words"] = message_words
            self._finalized_segments.append(segment)
            self.stats.segments_final += 1
            self._final_arrived.set()
            # This final is authoritative for the words it CONTAINS, not
            # for its time range. A final that says "три на или если
            # это" over 4.91-9.70 s does not account for "субагента" at
            # 5.5-6.1 s just because the span covers it — that word
            # stays retained and reaches the finalize splice (§3.1).
            #
            # A provider response with no word list at all leaves the
            # span as the only thing knowable, so that case keeps the
            # old centre rule rather than retaining everything forever.
            if message_words:
                self._interim_words = self._evict_words_covered_by(
                    self._interim_words, message_words
                )
                self._orphan_interim_words = self._evict_words_covered_by(
                    self._orphan_interim_words, message_words
                )
            else:
                self._interim_words = [
                    w for w in self._interim_words
                    if not (start < (w["start"] + w["end"]) / 2.0 < end)
                ]
                self._orphan_interim_words = [
                    w for w in self._orphan_interim_words
                    if not (start < (w["start"] + w["end"]) / 2.0 < end)
                ]
            logger.info(
                "deepgram-live: is_final start=%.2f end=%.2f speech_final=%s textLen=%d text=%r",
                start, end, speech_final, len(text), text[:80],
            )
            out_segment: dict[str, object] = {
                "start": segment["start"],
                "end": segment["end"],
                "text": segment["text"],
            }
            if speaker is not None:
                out_segment["speaker"] = speaker
            return {
                "type": "segments",
                "segments": [out_segment],
                "is_final": True,
                "speech_final": speech_final,
            }

        self.stats.segments_interim += 1
        # Retain this hypothesis's words for hole-splicing at finalize.
        # An interim is a ROLLING re-decode of recent audio, so each new
        # one supersedes every stored word that overlaps its range —
        # without that, the same spoken word would pile up once per
        # interim message and the splice would duplicate it.
        new_words = message_words
        self._interim_ring.append((round(start, 3), round(end, 3), text))
        # Record where the service actually heard WORDS. The message span
        # is the re-decode window, not the speech in it: a rolling interim
        # can span five seconds and carry two words near its end, and
        # charging the whole window as "recognised speech" made every such
        # message report seconds of loss that were never spoken. Word
        # timings are the honest measure; the message span is the fallback
        # for a hypothesis that arrives without them. The length threshold
        # keeps single-character noise hypotheses out either way.
        if len(text) >= INTERIM_SPEECH_MIN_CHARS:
            if new_words:
                self._interim_speech_spans.extend(_word_speech_spans(new_words))
            elif end > start:
                self._interim_speech_spans.append((start, end))
        # ``new_words`` is non-empty only when the hypothesis carried a
        # word list, so this is the same guard the parse above applied.
        if new_words:
            def _overlaps_range(w: dict) -> bool:
                return not (w["end"] <= start or w["start"] >= end)

            displaced = [w for w in self._interim_words if _overlaps_range(w)]
            self._interim_words = [
                w for w in self._interim_words if not _overlaps_range(w)
            ]
            # Displaced ≠ wrong: the newer hypothesis merely did not
            # confirm them YET. Park them as orphans unless the NEWEST
            # words actually cover the same ground (newest wins).
            seen = {
                (o["word"], o["start"], o["end"])
                for o in self._orphan_interim_words
            }
            for w in displaced:
                key = (w["word"], w["start"], w["end"])
                if key not in seen:
                    seen.add(key)
                    self._orphan_interim_words.append(dict(w))
            # Purge by IDENTITY, not by any temporal overlap (audit
            # §3.2). A rolling re-decode nearly always puts *something*
            # on the same ground, so overlap-based purging emptied the
            # pool unless the newer hypothesis happened to leave a hole
            # in exactly that place. An orphan dies only when the newest
            # words contain the same spoken word — the same question
            # ``word_accounted_for`` answers at splice time.
            self._orphan_interim_words = [
                o
                for o in self._orphan_interim_words
                if not word_accounted_for(o, new_words)
            ]
            self._interim_words.extend(new_words)
        if self.stats.segments_interim % 5 == 1:
            # Sample 1-in-5 interim emissions to keep log volume bounded
            # while still proving Deepgram is producing output.
            logger.info(
                "deepgram-live: interim #%d start=%.2f end=%.2f textLen=%d",
                self.stats.segments_interim, start, end, len(text),
            )
        interim_segment: dict[str, object] = {
            "start": segment["start"],
            "end": segment["end"],
            "text": segment["text"],
        }
        if speaker is not None:
            interim_segment["speaker"] = speaker
        return {
            "type": "interim",
            "segment": interim_segment,
        }

    @staticmethod
    def _dominant_speaker(words: object) -> Optional[int]:
        """Return the most common speaker index across ``words``.

        Deepgram emits one speaker id per word when ``diarize=true``.
        For a segment that belongs almost entirely to one speaker, the
        dominant index is stable; for mixed segments (rare at sentence
        granularity) we pick whichever speaker spoke most words.
        """
        if not isinstance(words, list) or not words:
            return None
        counts: dict[int, int] = {}
        for w in words:
            if not isinstance(w, dict):
                continue
            sp = w.get("speaker")
            if sp is None:
                continue
            try:
                key = int(sp)
            except (TypeError, ValueError):
                continue
            counts[key] = counts.get(key, 0) + 1
        if not counts:
            return None
        return max(counts.items(), key=lambda kv: kv[1])[0]


__all__ = [
    "DeepgramLiveConfig",
    "DeepgramLiveError",
    "DeepgramLiveSession",
    "DeepgramLiveStats",
    # Word-level coverage (audit §3.1-§3.4). Public because they are the
    # definitions the rest of the module — and its tests — reason about:
    # what a word record is, when two of them are the same spoken word,
    # and when a final already accounts for one.
    "covering_final_word",
    "drop_repeated_seam_ngrams",
    "final_words_cover",
    "merge_seam_fragments",
    "normalize_words",
    "word_accounted_for",
]
