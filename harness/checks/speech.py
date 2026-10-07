"""Judging synthesized speech by whether it can be read back.

This is the suite's first quality axis. The objective checks elsewhere separate
working from broken and cannot order two candidates that both work; word error
rate can.

IT IS A JOINT MEASUREMENT of the TTS model and the STT model reading it, and it
cannot separate them. That is sound for the comparison it is used for -- hold
one side fixed, vary the other, and the ordering is real -- but a WER from here
is not an absolute score for either model on its own. Ranking STT models needs
reference audio with a human transcript (LibriSpeech test-clean), which this
machine does not have yet.
"""
from __future__ import annotations

import re
from dataclasses import dataclass, field
from pathlib import Path

import jiwer
from num2words import num2words

from harness.audio import AudioError

# A WAV header is 44 bytes. Anything near it holds no speech, and transcribing
# it would report the empty result as a terrible TTS model.
MIN_AUDIO_BYTES = 8000

_PUNCT = re.compile(r"[^\w\s]")
_DIGITS = re.compile(r"\d+")
_EN_NUMBER = re.compile(r"(\d+)(?:\.(\d+)|(st|nd|rd|th)\b)?")
_EN_GROUPING = re.compile(r"(?<=\d),(?=\d{3}\b)")
_SCALES = {"hundred", "thousand", "million", "billion"}
_SMALL = {"one", "two", "three", "four", "five", "six", "seven", "eight", "nine",
          "ten", "eleven", "twelve", "thirteen", "fourteen", "fifteen", "sixteen",
          "seventeen", "eighteen", "nineteen", "twenty", "thirty", "forty", "fifty",
          "sixty", "seventy", "eighty", "ninety"}


@dataclass
class SpeechResult:
    ok: bool
    reason: str = ""
    warnings: list[str] = field(default_factory=list)
    wer: float | None = None
    transcript: str = ""

    #: Errors and reference length, so the suite can aggregate a CORPUS rate.
    errors: int = 0
    words: int = 0

    @property
    def metrics(self) -> dict:
        """What the eval ranks on. Empty when nothing was measured, never 0.0:
        a zero error rate is the best possible score and would rank a candidate
        that never ran at the top.

        The counts travel with the rate so summarize() can total them. A mean
        of per-utterance rates lets a two-word clip weigh as much as a
        forty-word one, which is why ASR reports corpus wer instead.
        """
        if self.wer is None:
            return {}
        return {"wer": round(self.wer, 4),
                "wer_errors": self.errors, "wer_words": self.words}


def _en_number(m: re.Match) -> str:
    whole, frac, suffix = m.groups()
    if suffix:
        return num2words(int(whole), lang="en", to="ordinal")
    words = num2words(int(whole), lang="en")
    if frac:
        words += " point " + " ".join(num2words(int(d), lang="en") for d in frac)
    return words


def drop_number_and(words: list[str]) -> list[str]:
    """One spoken form for English numbers: "hundred and five" and "a hundred" become "hundred five" and "one hundred"."""
    result = []
    for i, word in enumerate(words):
        if (word == "and" and i > 0 and words[i - 1] in _SCALES
                and i + 1 < len(words) and words[i + 1] in _SMALL):
            continue
        if word == "a" and i + 1 < len(words) and words[i + 1] in _SCALES:
            result.append("one")
        else:
            result.append(word)
    return result


def normalize(text: str, language: str = "en") -> str:
    """Strip everything that would measure transcription style, not speech.

    Parakeet emits no reliable punctuation and inconsistent casing, and it
    spells numbers out: "MLX 200" comes back as "mlx two hundred". Counting
    those as errors ranks models on how they write, not on what they heard.

    The expansion has to happen in the language being spoken. French 92 is
    "quatre-vingt-douze" -- four words for two digits -- so expanding it with
    the English table turns a correct reading into four errors and reports it
    as the TTS model failing.
    """
    if language == "en":
        text = _EN_NUMBER.sub(_en_number, _EN_GROUPING.sub("", text))
        return " ".join(drop_number_and(_PUNCT.sub(" ", text.lower()).split()))
    try:
        text = _DIGITS.sub(
            lambda m: num2words(int(m.group()), lang=language), text)
    except NotImplementedError as exc:
        # Silently leaving the digits alone would score a correct reading as
        # wrong, which is the failure this function exists to prevent.
        raise ValueError(
            f"cannot normalize numbers for language {language!r}: {exc}") from exc
    text = _PUNCT.sub(" ", text.lower())
    return " ".join(text.split())


def wer(reference: str, hypothesis: str, language: str = "en") -> float:
    """Word error rate, after normalization. 0.0 is perfect."""
    ref = normalize(reference, language)
    if not ref:
        raise ValueError("cannot score against an empty reference")
    hyp = normalize(hypothesis, language)
    if not hyp:
        # jiwer treats an empty hypothesis as every word deleted, which is 1.0;
        # spelling it out keeps the edge case from depending on jiwer's version.
        return 1.0
    return jiwer.wer(ref, hyp)


def wer_counts(reference: str, hypothesis: str,
               language: str = "en") -> tuple[int, int]:
    """(errors, reference words) after the same normalization wer() uses.

    Needed for a corpus rate: total errors over total words, rather than a mean
    of per-utterance rates in which a two-word clip outweighs a long one.
    """
    ref = normalize(reference, language)
    if not ref:
        raise ValueError("cannot score against an empty reference")
    words = len(ref.split())
    hyp = normalize(hypothesis, language)
    if not hyp:
        return words, words
    out = jiwer.process_words(ref, hyp)
    return out.substitutions + out.deletions + out.insertions, words


def check(path: str | Path, reference: str, max_wer: float | None = None,
          transcriber=None, language: str = "en") -> SpeechResult:
    """Transcribe the audio at `path` and compare it to `reference`.

    `max_wer` is optional: with no limit the check measures without judging,
    which is what ranking needs.
    """
    from harness import audio  # imported here so tests can inject a stub

    transcriber = transcriber or audio.transcribe
    path = Path(path)
    if not path.exists():
        return SpeechResult(False, f"no audio file at {path}")
    size = path.stat().st_size
    if size < MIN_AUDIO_BYTES:
        return SpeechResult(
            False, f"audio is {size} bytes, too small to hold speech")

    try:
        transcript = transcriber(path)
    except AudioError as exc:
        # An STT outage must not be recorded as this candidate scoring 100%
        # error: that is a broken instrument, not a bad model.
        return SpeechResult(False, f"could not transcribe: {exc}")

    rate = wer(reference, transcript, language)
    errors, words = wer_counts(reference, transcript, language)
    if max_wer is not None and rate > max_wer:
        return SpeechResult(
            False,
            f"word error rate {rate:.2f} over the limit of {max_wer}; "
            f"heard {transcript!r}",
            wer=rate, transcript=transcript, errors=errors, words=words)
    return SpeechResult(True, "", wer=rate, transcript=transcript,
                        errors=errors, words=words)
