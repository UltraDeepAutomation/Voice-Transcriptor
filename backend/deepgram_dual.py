"""Two readings of one recording, merged by word timestamps.

Why
---
``BUGS_AUDIT_2026-09-03.md`` §1 measured ``language=multi`` dropping
whole clauses of Russian speech, non-deterministically, on this app's
own recordings — and ``language=ru`` on the identical audio keeping
every one of them while losing the French and English ones instead.
Neither reading is complete on a recording that switches language, and
no Deepgram parameter fixes either: the two fail in DIFFERENT places.

The dual-stream measurement (2026-09-04, 11 files x 2 languages x 2
repeats = 44 sessions; report and prototype under
``evidence-2026-09-03/session-2026-09-04-dual-stream/``) ran both
readings on the same audio and merged their FINAL segments by word
time. On the 72.7 s trilingual recording that closed both holes,
verbatim and in both directions:

* ``multi`` emitted nothing at all between 21.82 s and 25.99 s — 4.17 s
  of speech — and ``ru`` had every word of it ("говорю просто большую
  кучу разных слов, довольно долго. И ты можешь detect and find"),
  code-switch included;
* ``ru`` skipped the French clause entirely, and ``multi`` had it
  ("lab de la capitale de la France.").

9 of 11 merged transcripts were byte-identical across repeat runs; the
other 2 differed only in punctuation and capitalisation, with no word
added or lost. Two concurrent sockets did not slow the connect (p50
871 ms across 44 sessions, against 880 ms measured single-stream in
production) — the cost is money, not latency: twice the Deepgram
streaming seconds.

What this module owns
---------------------
1. The DECISION (``dual_stream_enabled``): one preference, and the one
   condition that makes it meaningful — the recording must actually be
   running multilingual, because a second reading in the language the
   user already chose reads the same audio the same way and buys
   nothing for double the money.
2. The MERGE (``merge_readings``): the rules the measurement validated,
   with the one defect it found closed (see ``_pairs``).
3. The FACADE (``DualLiveSession``): two sessions behind the interface
   of one, so the WebSocket handler drives the same object either way.
"""

from __future__ import annotations

import asyncio
import heapq
import logging
from dataclasses import dataclass, field, replace
from typing import Any, Iterable, Optional

from backend.async_tasks import cancel_and_await
from backend.remote_deepgram_live import (
    CROSS_FINAL_NGRAM_MAX_WORDS,
    INTERIM_WORD_GAP_SPLIT_SEC,
    SPLICE_COVERAGE_OVERLAP_FRACTION,
    DeepgramLiveConfig,
    DeepgramLiveSession,
    DeepgramLiveStats,
    SPANLESS_WORD_FLAG,
    intersect_spans,
    resolve_live_language,
    segment_word_records,
    subtract_spans,
    union_spans,
)
# The merge has to answer the same questions the single-stream splice
# already answers — "are these two records the same spoken word?", "how
# much of this word's time does that one occupy?" — and answering them
# a second way is how two parts of one product come to disagree about
# what a duplicate is. These are that module's own rules, imported
# rather than restated.
from backend.remote_deepgram_live import (  # noqa: E402  (deliberate reuse)
    _time_overlap,
    _token_stem,
    _word_core,
    _word_duration,
)

logger = logging.getLogger(__name__)


# The user pays twice the Deepgram seconds for this, so it is a
# preference — but it defaults ON because what it buys is the words the
# user actually said, and the failure it fixes is silent: a dropped
# clause looks exactly like a clause that was never spoken.
DUAL_STREAM_DEFAULT = True

# The second reading's language. Russian is what the measurement was
# made on and what this user dictates; a different primary language
# would want a different partner, which is why it is configurable rather
# than hard-coded — and why it is read from ONE place.
DUAL_SECONDARY_LANGUAGE_DEFAULT = "ru"

# Two words with the same stem, this close in time, are one spoken word
# whose boundaries the two decoders placed differently.
#
# This is the defect the measurement found and named. On the 10.6 s
# recording "Очень важно починить", ``multi``'s word "truth," swallowed
# the pause after it (ending at 7.35 s where ``ru``'s "truth" ended at
# 7.11 s), which pushed ``multi``'s next word "без" to 7.75-7.99 while
# ``ru``'s "без" sat at 7.11-7.59. The two do not overlap AT ALL — the
# gap is 0.16 s — so a rule that only knows about overlap saw two
# different words and shipped "без без" to the user. Reproducible in
# both repeat runs.
#
# 0.3 s is a pause a decoder can absorb into the preceding word without
# the next word being a different utterance; it is comfortably over the
# few tens of ms a re-decode normally shifts a boundary by, and well
# under any real inter-word pause.
ADJACENT_SAME_STEM_MAX_GAP_SEC = 0.3

# Merged words further apart than ``INTERIM_WORD_GAP_SPLIT_SEC`` start a
# new segment — deliberately the same number the single-stream splice
# uses to group recovered words into fallback segments, so "these words
# belong to one clause" means one thing in this product.

_LATIN = set("abcdefghijklmnopqrstuvwxyz")


def _has_latin(token: str) -> bool:
    return any(ch in _LATIN for ch in token.casefold())


# ---------------------------------------------------------------------
# The decision
# ---------------------------------------------------------------------


def _deepgram_prefs(cfg: Any) -> dict:
    prefs = cfg.get("preferences") if isinstance(cfg, dict) else None
    dg = prefs.get("deepgram") if isinstance(prefs, dict) else None
    return dg if isinstance(dg, dict) else {}


def dual_stream_enabled(cfg: Any, language: str) -> bool:
    """Should this recording open a second Deepgram reading?

    Two conditions, and both are load-bearing:

    * the preference is on (``preferences.deepgram.dual_stream``,
      default ``True``); and
    * the recording resolves to Deepgram's multilingual mode
      (``resolve_live_language`` — the same function that decides what
      goes on the wire, so the two cannot disagree).

    The second is what keeps the cost honest. A user who has chosen
    ``ru`` is already getting the reading the merge would add; running
    it twice would double the bill for an identical transcript.
    """
    if resolve_live_language(language) != "multi":
        return False
    value = _deepgram_prefs(cfg).get("dual_stream")
    if value is None:
        return DUAL_STREAM_DEFAULT
    return bool(value)


def dual_secondary_language(cfg: Any) -> str:
    """The language of the second reading — one place, one answer."""
    value = _deepgram_prefs(cfg).get("dual_secondary_language")
    if isinstance(value, str) and value.strip():
        return value.strip().lower()
    return DUAL_SECONDARY_LANGUAGE_DEFAULT


def secondary_config(cfg: DeepgramLiveConfig, language: str) -> DeepgramLiveConfig:
    """The primary config, re-read in another language.

    Everything else — model, keyterms, sample rate, endpointing — is
    deliberately identical: the merge pairs words by TIME, and two
    readings decoded with different endpointing would place their
    boundaries differently for reasons that have nothing to do with
    what was said.
    """
    return replace(cfg, language=language)


# ---------------------------------------------------------------------
# The merge
# ---------------------------------------------------------------------


@dataclass
class MergedReading:
    """One transcript assembled from two readings of the same audio."""

    words: list[dict] = field(default_factory=list)
    segments: list[dict] = field(default_factory=list)
    text: str = ""
    primary_word_count: int = 0
    secondary_word_count: int = 0
    filled_from_secondary: int = 0
    filled_from_primary: int = 0
    duplicates_removed: int = 0

    def covered_end_sec(self) -> float:
        return max((float(w["end"]) for w in self.words), default=0.0)

    def covered_spans(self) -> list[tuple[float, float]]:
        return union_spans((float(w["start"]), float(w["end"])) for w in self.words)


def flatten_words(segments: Iterable[dict], source: str) -> list[dict]:
    """Finalized segments to one time-ordered word list, tagged.

    Reads every segment through ``segment_word_records`` — the ONE rule
    for a final that arrived without a word list (B-001). This function
    used to take ``_segment_words`` alone, so such a final contributed
    nothing at all: since ``merged.text`` is built from words, the whole
    clause disappeared from the transcript of a recording running the
    default Auto mode, with no error and no log line. The single-stream
    path had named that case three times over (``_spanless_coverage``,
    ``_word_covered_by_spanless_final``, the wordless branch of
    ``_process_deepgram_message``); the merge is the fourth asker and
    now shares their answer instead of inventing a fourth.
    """
    out: list[dict] = []
    for seg in segments or []:
        for w in segment_word_records(seg):
            token = str(w.get("word") or "")
            if not token:
                continue
            record = {
                "word": token,
                "start": float(w.get("start") or 0.0),
                "end": float(w.get("end") or 0.0),
                "source": source,
            }
            if w.get(SPANLESS_WORD_FLAG):
                record[SPANLESS_WORD_FLAG] = True
            out.append(record)
    out.sort(key=lambda w: (w["start"], w["end"]))
    return out


# How much of a clause-level record's span the OTHER reading has to
# transcribe with real words before that clause is dropped in its
# favour. Half: below it the clause is the only reading of most of that
# ground and dropping it would lose text (which is B-001 all over
# again); above it the other reading is the same audio, positioned word
# by word, and keeping the blob beside it would print the clause twice.
SPANLESS_SHADOW_MIN_FRACTION = 0.5


def _reconcile_spanless(
    primary: list[dict], secondary: list[dict]
) -> tuple[list[dict], list[dict]]:
    """Decide, per span of ground, between a clause blob and real words.

    A final without a word list becomes ONE record spanning its whole
    segment (``segment_word_records``). That record is a real reading of
    that ground — dropping it outright is B-001, a whole clause deleted
    from the transcript — but it is the coarsest possible one, and it
    cannot be merged word by word with anything. So exactly one of the
    two readings owns any ground a blob covers, and it is decided here,
    once, before any pairing:

    1. A blob whose span the OTHER reading transcribes with real words
       over at least ``SPANLESS_SHADOW_MIN_FRACTION`` of it loses: those
       words are the same audio, positioned, and the blob beside them
       would print the clause twice.
    2. Under any blob that survives, the other reading's real words lose
       instead — the blob already says what was spoken there, and
       keeping both is the same double-printing from the other side.
       "Inside" is the centre rule ``_word_covered_by_spanless_final``
       uses on the single-stream path, so "this word is answered for by
       a wordless final" means one thing in this product.
    """
    if not any(
        w.get(SPANLESS_WORD_FLAG) for w in (*primary, *secondary)
    ):
        # The common case by far: both readings came with word timings,
        # and there is no blob for either side to lose ground to.
        return primary, secondary
    kept_primary = _drop_shadowed_spanless(primary, secondary)
    kept_secondary = _drop_shadowed_spanless(secondary, kept_primary)
    return (
        _drop_words_under_spanless(kept_primary, kept_secondary),
        _drop_words_under_spanless(kept_secondary, kept_primary),
    )


def _spanless_spans(words: Iterable[dict]) -> list[tuple[float, float]]:
    return union_spans(
        (w["start"], w["end"]) for w in words if w.get(SPANLESS_WORD_FLAG)
    )


def _drop_shadowed_spanless(
    words: list[dict], other: list[dict]
) -> list[dict]:
    """Step 1 of ``_reconcile_spanless``: blobs the other reading beat."""
    covered = union_spans(
        (w["start"], w["end"]) for w in other if not w.get(SPANLESS_WORD_FLAG)
    )
    if not covered:
        return words
    kept: list[dict] = []
    for word in words:
        if not word.get(SPANLESS_WORD_FLAG):
            kept.append(word)
            continue
        span = max(0.0, word["end"] - word["start"])
        if span <= 0.0:
            kept.append(word)
            continue
        overlap = sum(
            end - start
            for start, end in intersect_spans([(word["start"], word["end"])], covered)
        )
        if overlap / span < SPANLESS_SHADOW_MIN_FRACTION:
            kept.append(word)
    return kept


def _drop_words_under_spanless(
    words: list[dict], other: list[dict]
) -> list[dict]:
    """Step 2 of ``_reconcile_spanless``: words a surviving blob answers for."""
    blobs = _spanless_spans(other)
    if not blobs:
        return words
    kept: list[dict] = []
    for word in words:
        if word.get(SPANLESS_WORD_FLAG):
            kept.append(word)
            continue
        center = (word["start"] + word["end"]) / 2.0
        if not any(start < center < end for start, end in blobs):
            kept.append(word)
    return kept


def _same_audio(a: dict, b: dict) -> bool:
    """Do these two words describe the same moment of the recording?

    The yes/no reading of ``_pair_overlap``; see it for the rules.
    """
    return _pair_overlap(a, b) is not None


def _pair_overlap(a: dict, b: dict) -> Optional[float]:
    """Their time overlap when they are the same moment, else ``None``.

    Overlap first — the measured rule, ``SPLICE_COVERAGE_OVERLAP_FRACTION``
    of EITHER word, the same threshold the single-stream splice uses.

    Then the fix for the "без без" case: two words whose stems match and
    which sit within ``ADJACENT_SAME_STEM_MAX_GAP_SEC`` of each other
    are the same word even with no overlap at all, because one decoder
    let the previous word swallow the pause and pushed this one late.
    Requiring the STEM to match is what keeps this from merging genuine
    consecutive words: "да да" said twice stays two words only if the
    times really are disjoint by more than the gap, and a real repeat
    ("subagents, subagents") is spoken over a longer span than 0.3 s.

    A clause-level record (``SPANLESS_WORD_FLAG`` — a final that arrived
    without word timings) is not a spoken word, so it is never paired
    with one: doing so would let a single word's spelling win
    ``_resolve`` against a whole clause and delete the clause. Which of
    the two survives is decided before any pairing, by
    ``_drop_shadowed_spanless``. Two clause records of the same ground
    ARE comparable, and are compared on overlap alone — a stem match
    between two multi-word blobs means nothing.

    Returns the overlap rather than a boolean because ``_pairs`` needs
    both the verdict and the same number as its ranking key, and
    computing it twice was a measurable share of the merge on a long
    dictation.
    """
    a_spanless = bool(a.get(SPANLESS_WORD_FLAG))
    b_spanless = bool(b.get(SPANLESS_WORD_FLAG))
    if a_spanless != b_spanless:
        return None
    overlap = _time_overlap(a, b)
    if overlap > 0 and (
        overlap >= SPLICE_COVERAGE_OVERLAP_FRACTION * _word_duration(a)
        or overlap >= SPLICE_COVERAGE_OVERLAP_FRACTION * _word_duration(b)
    ):
        return overlap
    if a_spanless:
        return None
    stem = _token_stem(a["word"])
    if not stem or stem != _token_stem(b["word"]):
        return None
    gap = max(a["start"], b["start"]) - min(a["end"], b["end"])
    return overlap if gap <= ADJACENT_SAME_STEM_MAX_GAP_SEC else None


def _pairs(
    primary: list[dict], secondary: list[dict]
) -> tuple[list[tuple[dict, dict]], list[dict], list[dict]]:
    """Pair words across readings, greedily, strongest evidence first.

    Ranked by time overlap so the best-matching pair claims each word
    before a weaker candidate can. Pairs accepted with no overlap at all
    (the same-stem neighbour rule) rank last, which is right: they are
    the weakest evidence of sameness and must not outbid a real overlap.

    Linear in the number of words, by a time sweep. This used to rescan
    the WHOLE secondary list from index 0 for every primary word — the
    early ``break`` bounded the tail of the scan but not its head — which
    is O(P x S) on a path that runs synchronously between the user's
    Stop and their text: measured 2.8 s for a 7-minute dictation and
    30.8 s for a 20-minute one, all of it inside the event loop, and all
    of it outside the budget this stop had already announced to the
    renderer (B-002).

    Both lists are time-sorted, so a secondary word can only match a
    window of primary words that moves forward with the cursor. The
    active set holds exactly the secondary words whose span can still
    reach the current primary word: anything ending more than
    ``ADJACENT_SAME_STEM_MAX_GAP_SEC`` before it can match neither this
    primary word nor any later one (later ones start no earlier), so it
    is retired for good — a heap keyed on ``end`` is what makes "the
    earliest-ending word still in play" the only one that has to be
    examined to decide that. Words are admitted by ``start``, in order,
    and never re-examined once retired, so every word enters and leaves
    once.
    """
    candidates: list[tuple[float, int, int]] = []
    active: list[tuple[float, int]] = []  # heap of (end, secondary index)
    next_secondary = 0
    total_secondary = len(secondary)
    for pi, pw in enumerate(primary):
        admit_until = pw["end"] + ADJACENT_SAME_STEM_MAX_GAP_SEC
        while (
            next_secondary < total_secondary
            and secondary[next_secondary]["start"] <= admit_until
        ):
            heapq.heappush(
                active,
                (secondary[next_secondary]["end"], next_secondary),
            )
            next_secondary += 1
        retire_before = pw["start"] - ADJACENT_SAME_STEM_MAX_GAP_SEC
        while active and active[0][0] < retire_before:
            heapq.heappop(active)
        for _end, si in active:
            overlap = _pair_overlap(pw, secondary[si])
            if overlap is not None:
                candidates.append((overlap, pi, si))
    # Explicit tie-break on (pi, si) rather than sort stability: the
    # sweep visits the active set in heap order, so insertion order is
    # no longer the source order, and two candidates with identical
    # overlap have to resolve the same way every run.
    candidates.sort(key=lambda t: (-t[0], t[1], t[2]))
    used_p: set[int] = set()
    used_s: set[int] = set()
    paired: list[tuple[dict, dict]] = []
    for _overlap, pi, si in candidates:
        if pi in used_p or si in used_s:
            continue
        used_p.add(pi)
        used_s.add(si)
        paired.append((primary[pi], secondary[si]))
    return (
        paired,
        [w for i, w in enumerate(primary) if i not in used_p],
        [w for i, w in enumerate(secondary) if i not in used_s],
    )


def _resolve(primary_word: dict, secondary_word: dict) -> dict:
    """Which spelling wins when both readings heard the same moment.

    * Same alpha core — no disagreement at all. The primary's token
      carries the formatting the app renders, so it wins.
    * Different cores, and either token has Latin letters — the
      multilingual reading wins: it keeps "Sonnet" as "Sonnet" where a
      monolingual Russian reading transliterates it.
    * Different cores, both Cyrillic — the secondary wins, because that
      is the measured stronger reading on Cyrillic content (audit §1).
      Measured side effect: this is what deleted the documented "Локи"
      hallucination from the 83 s recording.
    """
    core_p = _word_core(primary_word)
    if core_p and core_p == _word_core(secondary_word):
        return dict(primary_word)
    if _has_latin(primary_word["word"]) or _has_latin(secondary_word["word"]):
        winner = (
            primary_word
            if _has_latin(primary_word["word"])
            else secondary_word
        )
        return dict(winner)
    return dict(secondary_word)


def _drop_duplicate_runs(words: list[dict]) -> tuple[list[dict], int]:
    """Remove a run transcribed twice across a provenance junction.

    Where the merged sequence switches from one reading to the other, up
    to ``CROSS_FINAL_NGRAM_MAX_WORDS`` words on each side are compared by
    stem; a match counts as a duplicate only when every matched pair also
    describes the same audio (``_same_audio``). Without that second test
    a deliberate repeat — "subagents, subagents", confirmed by listening
    — would be silently halved.

    Mirrors ``drop_repeated_seam_ngrams``, which does the same job for
    the seam between two finals of ONE reading.
    """
    out = list(words)
    dropped = 0
    i = 1
    while i < len(out):
        if out[i]["source"] == out[i - 1]["source"]:
            i += 1
            continue
        matched = 0
        for n in range(min(CROSS_FINAL_NGRAM_MAX_WORDS, i, len(out) - i), 0, -1):
            tail = out[i - n:i]
            head = out[i:i + n]
            tail_stems = [_token_stem(w["word"]) for w in tail]
            head_stems = [_token_stem(w["word"]) for w in head]
            if not all(tail_stems) or tail_stems != head_stems:
                continue
            if all(_same_audio(t, h) for t, h in zip(tail, head)):
                matched = n
                break
        if not matched:
            i += 1
            continue
        tail = out[i - matched:i]
        head = out[i:i + matched]
        dropped += matched
        if tail[0]["start"] <= head[0]["start"]:
            del out[i:i + matched]
        else:
            del out[i - matched:i]
            i -= matched
        i += 1
    return out, dropped


def _segments_from_words(words: list[dict]) -> list[dict]:
    """Group merged words into segments at clause-length silences."""
    segments: list[dict] = []
    for word in words:
        if segments and word["start"] - segments[-1]["end"] <= INTERIM_WORD_GAP_SPLIT_SEC:
            segment = segments[-1]
            segment["end"] = round(max(segment["end"], word["end"]), 3)
            segment["words"].append(word)
            continue
        segments.append(
            {
                "start": round(word["start"], 3),
                "end": round(word["end"], 3),
                "text": "",
                "confidence": 0.0,
                "is_final": True,
                "speech_final": False,
                "words": [word],
                "source": "dual-merge",
            }
        )
    for segment in segments:
        segment["text"] = " ".join(w["word"] for w in segment["words"])
        segment["words"] = [dict(w) for w in segment["words"]]
    return segments


def merge_readings(
    primary_segments: Iterable[dict],
    secondary_segments: Iterable[dict],
    *,
    primary_source: str = "multi",
    secondary_source: str = "ru",
) -> MergedReading:
    """Merge two readings of one recording into one transcript.

    Pure: takes the two finalized segment lists, returns the merged
    words (each carrying the ``source`` it came from), the segments they
    group into, and the counts the stop line reports.
    """
    primary = flatten_words(primary_segments, primary_source)
    secondary = flatten_words(secondary_segments, secondary_source)
    if not secondary:
        # Single-stream degradation, and the common case when the
        # secondary socket failed: the primary reading, untouched.
        merged = [dict(w) for w in primary]
        return MergedReading(
            words=merged,
            segments=_segments_from_words(merged),
            text=" ".join(w["word"] for w in merged),
            primary_word_count=len(primary),
            secondary_word_count=0,
        )

    # What each reading actually delivered, before the merge starts
    # discarding from either — the stop line reports the readings, not
    # the merge's working set.
    primary_count = len(primary)
    secondary_count = len(secondary)
    # Clause-level records first, before anything is paired: a final
    # that arrived without word timings cannot be merged word by word,
    # so exactly one reading owns the ground it covers.
    primary, secondary = _reconcile_spanless(primary, secondary)
    paired, only_primary, only_secondary = _pairs(primary, secondary)
    merged = [_resolve(pw, sw) for pw, sw in paired]
    merged.extend(dict(w) for w in only_primary)
    merged.extend(dict(w) for w in only_secondary)
    merged.sort(key=lambda w: (w["start"], w["end"]))
    merged, duplicates = _drop_duplicate_runs(merged)
    return MergedReading(
        words=merged,
        segments=_segments_from_words(merged),
        text=" ".join(w["word"] for w in merged),
        primary_word_count=primary_count,
        secondary_word_count=secondary_count,
        filled_from_secondary=len(only_secondary),
        filled_from_primary=len(only_primary),
        duplicates_removed=duplicates,
    )


# ---------------------------------------------------------------------
# The facade
# ---------------------------------------------------------------------


class DualLiveSession:
    """Two ``DeepgramLiveSession``s behind the interface of one.

    The WebSocket handler drives this exactly as it drives a single
    session — one ``send_pcm``, one ``events()``, one
    ``drain_transcript``, one envelope — so there is one stop chain in
    this product, not two.

    Three asymmetries, all deliberate:

    * EVENTS come only from the primary — and ``events()`` follows a
      ``replace_primary`` swap transparently, so that stays true across
      the whole recording, not just up to the first replacement. The
      live preview and every renderer buffer downstream of it are built
      for one stream of interims and finals; two would interleave into
      nonsense, and the secondary's value is in the merge at stop, not
      on screen.
    * ERRORS are the primary's alone. A secondary that dies takes the
      recording's completeness back to where it was without this
      feature, which is not a failure worth aborting a recording for —
      it is logged once and the merge sees an empty reading.
    * AUDIO goes to both, awaited in order. A send is never cancelled
      (cancelling one mid-frame leaves that connection undefined), and
      the secondary's failure to accept a frame is swallowed after the
      first warning.
    """

    def __init__(
        self,
        primary: DeepgramLiveSession,
        secondary: DeepgramLiveSession,
        *,
        secondary_language: str = DUAL_SECONDARY_LANGUAGE_DEFAULT,
        primary_language: str = "multi",
    ) -> None:
        self.primary = primary
        self.secondary: Optional[DeepgramLiveSession] = secondary
        self._secondary_language = secondary_language
        self._primary_language = primary_language
        self._secondary_failed = False
        # The last merge this facade produced. Coverage questions
        # asked AFTER the stop ("what is still missing?") must be
        # answered against the merged transcript, not against either
        # reading alone — a hole the primary reported is not a hole in
        # what the user receives if the secondary's words went into it.
        self._last_merged: Optional[MergedReading] = None

    # ----- The single-session interface --------------------------------

    @property
    def stats(self) -> DeepgramLiveStats:
        return self.primary.stats

    @property
    def is_closed(self) -> bool:
        return self.primary.is_closed

    @property
    def last_error(self) -> Optional[str]:
        return self.primary.last_error

    @property
    def last_fatal(self) -> bool:
        return self.primary.last_fatal

    @property
    def stream_death_sec(self) -> Optional[float]:
        """When the recording's upstream died — the PRIMARY's answer.

        The secondary owns nothing the user would notice losing (see the
        class docstring), so the moment THIS recording stopped reaching
        Deepgram is the moment the primary stopped reaching it.
        """
        return self.primary.stream_death_sec

    @property
    def endpointing_sec(self) -> float:
        return self.primary.endpointing_sec

    @property
    def utterance_end_sec(self) -> float:
        """Both readings run the same config (``secondary_config``)."""
        return self.primary.utterance_end_sec

    @property
    def last_utterance_end(self) -> Optional[float]:
        """The furthest point EITHER reading has confirmed as an utterance end.

        Same shape as ``interim_window_end``: either decoder saying "the
        utterance ended here" is evidence about the recording, and the
        later claim is the one that describes the tail. A reading that
        never sent one contributes nothing rather than ``None`` for both.
        """
        ends = [
            value
            for value in (
                self.primary.last_utterance_end,
                self.secondary.last_utterance_end if self.secondary is not None else None,
            )
            if value is not None
        ]
        return max(ends) if ends else None

    @property
    def streamed_sec(self) -> float:
        """The recording's streamed position — both readings are fed the
        same bytes, so the furthest either got is the recording's."""
        values = [self.primary.streamed_sec]
        if self.secondary is not None:
            values.append(self.secondary.streamed_sec)
        return max(values)

    def committed_segments(self) -> list[dict]:
        """Both readings' committed segments, for coverage only.

        Not a transcript: overlapping segments from the two readings
        would read as a doubled one. It is the union of the GROUND the
        two readings account for, which is what the recovery budget
        prediction asks about — the merge that turns them into one
        transcript happens at stop, in ``_merged_envelope``.
        """
        out = list(self.primary.committed_segments())
        if self.secondary is not None:
            out.extend(self.secondary.committed_segments())
        return out

    @property
    def interim_window_end(self) -> float:
        """The furthest either reading's decoder has reached.

        Evidence that SOMETHING is still working the tail — and either
        reading still working it is evidence, so this is a max and not
        the primary's alone.
        """
        ends = [self.primary.interim_window_end]
        if self.secondary is not None:
            ends.append(self.secondary.interim_window_end)
        return max(ends)

    def interim_speech_spans(self) -> list[tuple[float, float]]:
        """Where EITHER reading heard words. Merged, so nothing counts twice."""
        spans = list(self.primary.interim_speech_spans())
        if self.secondary is not None:
            spans.extend(self.secondary.interim_speech_spans())
        return union_spans(spans)

    def coverage_hole_spans(self) -> list[tuple[float, float]]:
        """What the MERGED transcript still fails to cover.

        Both readings' holes taken together, minus whatever the merged
        words actually cover. Before the merge exists (the recovery
        budget is estimated at announce time, mid-stop) the honest
        answer is the union of both readings' holes.
        """
        holes = list(self.primary.coverage_hole_spans())
        if self.secondary is not None:
            holes.extend(self.secondary.coverage_hole_spans())
        if self._last_merged is None:
            return union_spans(holes)
        return subtract_spans(holes, self._last_merged.covered_spans())

    def report_fatal(self, message: str) -> None:
        self.primary.report_fatal(message)

    def note_undelivered_audio(self, nbytes: int) -> None:
        self.primary.note_undelivered_audio(nbytes)
        if self.secondary is not None:
            self.secondary.note_undelivered_audio(nbytes)

    async def events(self):
        """Yield the CURRENT primary's events, across any number of swaps.

        ``DeepgramLiveSession.events()`` promises "exactly one consumer,
        for the life of the session" — a caller gets one generator and
        drives it until the recording ends. This facade has to keep that
        same promise even though ITS primary can be replaced mid-flight
        (``replace_primary``, the warm-socket liveness path in
        ``backend.main``): a caller that took a snapshot of
        ``self.primary.events()`` at construction time would silently
        stop receiving anything the moment the old primary's socket was
        torn down (``discard()`` pushes the sentinel that ends its
        generator), even though a fresh primary is now live and still
        producing finals. That is exactly the failure this method exists
        to prevent — read ``self.primary`` fresh each time the previous
        primary's stream ends, and only stop once it truly is the same
        primary that started this leg.
        """
        while True:
            current_primary = self.primary
            async for event in current_primary.events():
                yield event
            if self.primary is current_primary:
                return

    def final_text(self) -> str:
        return self.primary.final_text()

    def partial_result(self) -> dict:
        """A merged envelope from whatever both readings hold RIGHT NOW.

        Same promise ``DeepgramLiveSession.partial_result`` makes — a
        read of committed state, no Finalize, no waiting — kept for a
        dual recording so a caller that cannot wait for
        ``drain_transcript`` (the WS handler's error path, whose payload
        is now the input to the REST recovery pass) gets the MERGED
        transcript rather than one reading of it.
        """
        return self._merged_envelope(
            self.primary.partial_result(),
            self.secondary.partial_result() if self.secondary is not None else None,
        )

    async def send_pcm(self, chunk: bytes) -> None:
        # The primary's exception is the caller's, unchanged: it owns
        # the recording. The secondary's is swallowed after one warning
        # — it owns nothing the user would notice losing.
        await self.primary.send_pcm(chunk)
        await self._feed_secondary(chunk)

    async def _feed_secondary(self, chunk: bytes) -> None:
        secondary = self.secondary
        if secondary is None:
            return
        try:
            await secondary.send_pcm(chunk)
        except Exception as e:
            self._fail_secondary(f"send failed: {e}")

    def _fail_secondary(self, reason: str) -> None:
        """Drop to one reading, once, loudly enough to find later."""
        if self._secondary_failed:
            return
        self._secondary_failed = True
        logger.warning(
            "dual-stream: secondary reading (%s) dropped, continuing "
            "single-stream: %s",
            self._secondary_language,
            reason,
        )

    @property
    def secondary_failed(self) -> bool:
        return self._secondary_failed

    def replace_primary(self, fresh: DeepgramLiveSession) -> DeepgramLiveSession:
        """Swap the primary socket, returning the one replaced.

        The warm-socket liveness path in ``backend.main`` replaces a
        socket that never answered. Only the primary is probed — it is
        the one whose silence the user would notice — so this is where
        that swap lands when the recording is running two readings.

        Mutates ``self.primary`` in place rather than handing back a new
        facade, which is exactly why ``events()`` has to notice the swap
        itself instead of relying on a caller's identity check: the
        facade object a WS handler holds never changes, only what it
        wraps does.
        """
        old = self.primary
        self.primary = fresh
        return old

    # ----- Stop --------------------------------------------------------

    async def finalize(
        self,
        wait_timeout: float = 3.0,
        on_budget=None,
    ) -> dict:
        """Back-compat convenience: ``drain_transcript()`` then ``shutdown()``.

        Mirrors ``DeepgramLiveSession.finalize`` (see its docstring) —
        the same "one interface either way" promise this class exists
        for means a caller that only knows the single-session API (the
        A/B tool; any future non-WS caller) must not have to special
        case a dual recording to get its transcript and clean up.
        """
        result = await self.drain_transcript(on_budget=on_budget)
        await self.shutdown(wait_timeout=wait_timeout)
        return result

    async def drain_transcript(self, on_budget=None) -> dict:
        """Drain both readings under ONE budget and merge them.

        The budget is announced by the PRIMARY, once — it is the same
        recording, the same stop, and the renderer is owed one deadline.
        The secondary is drained concurrently so it costs no extra wall
        time, and is given the primary's own budget as a hard ceiling:
        it must never be the reason a stop runs long. That budget is
        already the honest one for BOTH shapes of stop — an uncovered
        primary tail announces a larger ceiling (``on_budget``'s
        ``worst_case``, which includes the retry) than a covered one, so
        this method does not need to ask separately whether the primary's
        own tail was covered before deciding how long the secondary may
        run: the ceiling already says so.
        """
        secondary = self.secondary
        secondary_task: Optional[asyncio.Task] = None
        announced: list[float] = []

        def _on_budget(budget_sec: float, expects_more: bool) -> None:
            announced.append(budget_sec)
            if on_budget is not None:
                on_budget(budget_sec, expects_more)

        if secondary is not None:
            secondary_task = asyncio.get_running_loop().create_task(
                secondary.drain_transcript(), name="deepgram-dual-secondary-drain",
            )
        primary_result = await self.primary.drain_transcript(on_budget=_on_budget)

        secondary_result: Optional[dict] = None
        if secondary_task is not None:
            # The primary's own announced budget, again: whatever the
            # secondary still owes, the user has already been told how
            # long this stop may take.
            ceiling = announced[0] if announced else 3.0
            try:
                secondary_result = await asyncio.wait_for(
                    secondary_task, timeout=max(0.1, ceiling)
                )
            except asyncio.TimeoutError:
                # Wait for the cancellation to LAND before snapshotting.
                # The abandoned ``drain_transcript`` is still mutating
                # the secondary's ``_finalized_segments`` (its interim
                # splice appends fallback segments), and the caller runs
                # ``shutdown()`` the moment this method returns — two
                # coroutines writing one socket, one of them sending
                # ``Finalize`` while the other sends ``CloseStream``.
                await cancel_and_await(
                    secondary_task, what="dual-stream secondary drain", log=logger
                )
                # The secondary is LATE, not WRONG: its own recv loop has
                # been appending finalized segments the whole time,
                # independently of its (now-abandoned) drain_transcript()
                # call, so whatever it committed before the primary's
                # announced budget ran out is real transcript — discarding
                # it would throw away words the user actually gets to keep
                # under the single-stream path. Snapshotting it is what
                # keeps the envelope inside the announced bound without
                # also reverting to "drop the secondary entirely" for a
                # reading that only ran long, never failed — that is
                # ``_fail_secondary``'s case, not this one, so it is not
                # called here and ``stats.dual_stream`` stays true.
                secondary_result = secondary.partial_result()
                logger.warning(
                    "dual-stream: secondary late, merged partial "
                    "(budget=%.2fs, secondary reached %.2fs of %.2fs streamed)",
                    ceiling,
                    float(secondary_result.get("coveredEndSec") or 0.0),
                    float(secondary_result.get("streamedSec") or 0.0),
                )
            except Exception as e:
                self._fail_secondary(f"drain failed: {e}")

        return self._merged_envelope(primary_result, secondary_result)

    def _merged_envelope(
        self, primary_result: dict, secondary_result: Optional[dict]
    ) -> dict:
        secondary_segments = (secondary_result or {}).get("segments") or []
        merged = merge_readings(
            primary_result.get("segments") or [],
            secondary_segments,
            primary_source=self._primary_language,
            secondary_source=self._secondary_language,
        )
        self._last_merged = merged
        logger.info(
            "dual-stream merge: %s=%d words %s=%d words merged=%d "
            "filled_from_%s=%d filled_from_%s=%d dups_removed=%d",
            self._primary_language,
            merged.primary_word_count,
            self._secondary_language,
            merged.secondary_word_count,
            len(merged.words),
            self._secondary_language,
            merged.filled_from_secondary,
            self._primary_language,
            merged.filled_from_primary,
            merged.duplicates_removed,
        )
        streamed_sec = max(
            float(primary_result.get("streamedSec") or 0.0),
            float((secondary_result or {}).get("streamedSec") or 0.0),
        )
        envelope = dict(primary_result)
        envelope["text"] = merged.text
        # ``words`` is the merged list; ``segments`` is that same list
        # grouped at clause-length silences, built from it in one place
        # (``_segments_from_words``) so the two are views of one
        # transcript rather than two transcripts. Every word carries the
        # ``source`` it came from, which is what makes a merge auditable
        # after the fact.
        envelope["segments"] = merged.segments
        envelope["words"] = merged.words
        envelope["durationSec"] = round(merged.covered_end_sec(), 3)
        # NOT the merged end: the merge includes each reading's spliced
        # interim fallback, and ``coveredEndSec`` means "committed
        # provider finals up to here" on both sides of the wire. Each
        # reading already measures its own (``_committed_end_sec``), so
        # the merged answer is the further of the two — a hole one
        # reading committed past is committed ground for this envelope.
        envelope["coveredEndSec"] = round(
            max(
                float(primary_result.get("coveredEndSec") or 0.0),
                float((secondary_result or {}).get("coveredEndSec") or 0.0),
            ),
            3,
        )
        envelope["streamedSec"] = round(streamed_sec, 3)
        envelope["uncoveredSpeechSec"] = round(
            self._merged_uncovered_speech_sec(), 3
        )
        # Wire contract with the renderer: ``stats.dual_stream`` is the
        # boolean it reads to know this envelope came from the merged
        # path. It is FALSE only when the secondary reading genuinely
        # failed (``_fail_secondary`` — no usable transcript exists),
        # because then the text is a single reading and saying otherwise
        # would misdescribe what the user received. A secondary that ran
        # past the announced budget is NOT that case: ``drain_transcript``
        # merges in whatever it had committed by then
        # (``DeepgramLiveSession.partial_result``), so the text genuinely
        # is a merge, just of a shorter secondary reading.
        merged_path = secondary_result is not None and not self._secondary_failed
        stats = dict(primary_result.get("stats") or {})
        stats["dual_stream"] = bool(merged_path)
        stats["dual_secondary_language"] = self._secondary_language
        stats["dual_filled_from_secondary"] = merged.filled_from_secondary
        stats["dual_filled_from_primary"] = merged.filled_from_primary
        stats["dual_duplicates_removed"] = merged.duplicates_removed
        envelope["stats"] = stats
        return envelope

    def _merged_uncovered_speech_sec(self) -> float:
        """Seconds neither reading committed and the merge could not fill.

        The total of ``coverage_hole_spans`` — one implementation of
        "what is still missing", read here as a number and by the
        recovery pass as spans, so the envelope's figure and the spans
        that get re-decoded can never describe different ground.
        """
        return sum(end - start for start, end in self.coverage_hole_spans())

    async def shutdown(self, wait_timeout: float = 3.0) -> None:
        await self._both("shutdown", wait_timeout=wait_timeout)

    async def close(self) -> None:
        await self._both("close")

    async def discard(self) -> None:
        await self._both("discard")

    async def _both(self, method: str, **kwargs) -> None:
        secondary = self.secondary
        if secondary is not None:
            try:
                await getattr(secondary, method)(**kwargs)
            except Exception as e:
                logger.debug("dual-stream: secondary %s ignored: %s", method, e)
        await getattr(self.primary, method)(**kwargs)


__all__ = [
    "ADJACENT_SAME_STEM_MAX_GAP_SEC",
    "DUAL_SECONDARY_LANGUAGE_DEFAULT",
    "DUAL_STREAM_DEFAULT",
    "DualLiveSession",
    "MergedReading",
    "dual_secondary_language",
    "dual_stream_enabled",
    "flatten_words",
    "merge_readings",
    "secondary_config",
]
