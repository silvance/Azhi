"""Audio/video transcription backend for the Whispers GUI.

This wraps `faster-whisper <https://github.com/SYSTRAN/faster-whisper>`_
(a CTranslate2 reimplementation of Whisper) which is substantially faster and
lighter than the reference PyTorch implementation on CPU-only hardware.

The ``faster_whisper`` import is deferred to call time so that importing this
module - and therefore the rest of the package - does not require the optional
transcription/GUI dependencies to be installed.
"""

from __future__ import annotations

import os
import subprocess
import tempfile
from dataclasses import dataclass, field
from pathlib import Path
from typing import Any, Callable, Dict, List, Optional, Sequence, Tuple, Union

from .resources import find_ffmpeg, is_bundle
from .speaker_names import LEAD_LEGEND, any_leads

PathLike = Union[str, Path]
ProgressCallback = Callable[[str], None]
# A predicate the GUI can pass so long-running work can be stopped cooperatively.
CancelCallback = Callable[[], bool]


class CancelledError(Exception):
    """Raised to unwind a transcription/diarization that the user cancelled."""


# Media container extensions the GUI offers for transcription. faster-whisper
# decodes via ffmpeg, so anything ffmpeg can read will work; this list just
# drives the file picker filter and ``is_supported_media``.
AUDIO_EXTENSIONS = (
    ".mp3",
    ".wav",
    ".m4a",
    ".flac",
    ".ogg",
    ".opus",
    ".aac",
    ".wma",
    ".mp4",
    ".mkv",
    ".mov",
    ".avi",
    ".webm",
)

# Subset of AUDIO_EXTENSIONS that are video containers. When the GUI's
# "convert video to WAV" option is on, these are pre-converted with ffmpeg.
VIDEO_EXTENSIONS = (
    ".mp4",
    ".mkv",
    ".mov",
    ".avi",
    ".webm",
)

# Sample rate Whisper operates at; converting to it keeps the WAV small.
WHISPER_SAMPLE_RATE = 16000

# Model sizes accepted by faster-whisper's ``WhisperModel``. The English-only
# ".en" models are smaller/faster and usually as accurate on English audio
# (base.en mirrors whisper.cpp's ggml-base.en). The plain names are multilingual
# and required for non-English audio or the translate task.
MODEL_SIZES = (
    "base.en",
    "small.en",
    "medium.en",
    "tiny.en",
    "tiny",
    "base",
    "small",
    "medium",
    "large-v3",
    "turbo",
)

# What a fresh install starts on, and the order it falls back through when the
# build does not carry that model.
#
# medium, because the recordings this is pointed at are covert and often muffled
# or distant, where a larger model is the difference between a usable transcript
# and a guess - and an operator who never opens a settings panel should get the
# one that copes. It is multilingual, which the .en models are not: the same
# operators work in the languages this build ships translation packs for. It is
# slower per minute of audio than base.en, and that is the trade being made.
# Silence skipping, tuned for the audio this is actually pointed at.
#
# Silero decides speech with hysteresis: a region is *entered* at `threshold`
# and only left below `neg_threshold`. faster-whisper's defaults are 0.5 and
# 0.35, which suit clean speech and quietly destroy covert recordings. On
# muffled or distant audio the speech probability sits around 0.3-0.5, so once
# a genuine pause ends a region, the quieter speech after it never reaches 0.5
# to start a new one - and is discarded, with nothing on screen to say so. That
# is the field report this exists to answer: a pause, then words gone until
# somebody spoke up.
#
# Entry is therefore low, and the gap to the exit threshold is kept narrow so a
# region still ends when the audio really does go quiet. The cost of being
# wrong in this direction is some noise transcribed; the cost of being wrong in
# the other is evidence missing from a transcript with no indication it was
# ever there.
VAD_THRESHOLD = 0.25
VAD_NEG_THRESHOLD = 0.15
# How long the audio must stay quiet before a speech region is closed. Pauses
# in conversation are routinely longer than a second; ending a region on one
# invites exactly the failure above.
VAD_MIN_SILENCE_MS = 2000
# Kept either side of a region. The onset of a word is the quietest part of it
# and the first thing a detector clips, so this is more generous than the 400 ms
# default.
VAD_SPEECH_PAD_MS = 600


def vad_options() -> "Dict[str, Any]":
    """The silence-skipping settings passed to faster-whisper."""
    return {
        "threshold": VAD_THRESHOLD,
        "neg_threshold": VAD_NEG_THRESHOLD,
        "min_silence_duration_ms": VAD_MIN_SILENCE_MS,
        "speech_pad_ms": VAD_SPEECH_PAD_MS,
    }


def translation_refusal(model: str) -> Optional[str]:
    """Why ``model`` cannot translate into English, or None when it can.

    The translate task needs a multilingual model trained for it, and three
    kinds were offered for it that are not. ``turbo`` (large-v3-turbo) was
    fine-tuned on transcription only: asked to translate, it writes the original
    language - a Chinese recording set to translate came back in Chinese, with
    nothing to say so. The ``.en`` models are English-only, and distil-whisper
    models were distilled from transcription. Judged by name, which is what a
    bundled model or a copied model folder carries.
    """
    name = Path((model or "").strip()).name.lower()
    if "turbo" in name:
        return (
            "The turbo model was not trained to translate: asked to, it writes "
            "the original language. Choose medium or large-v3 to translate "
            "into English."
        )
    if name.endswith(".en"):
        return (
            "English-only models cannot translate. Choose medium or large-v3 "
            "to translate into English."
        )
    if name.startswith("distil"):
        return (
            "Distilled models cannot translate. Choose medium or large-v3 to "
            "translate into English."
        )
    return None


def untranslated_share(segments: "Sequence[Segment]") -> float:
    """Of the letters in a translation, the share not in the Latin alphabet.

    A model that ignores the translate task writes the original language, and
    for the languages this is pointed at that is another script. Counted per
    character, so a dense script weighs more than its share of the meaning: a
    figure for spotting a translation that did not happen, not a measure of
    how much did.
    """
    import unicodedata

    latin = other = 0
    for segment in segments:
        for char in segment.text:
            if not char.isalpha():
                continue
            if unicodedata.name(char, "").startswith("LATIN"):
                latin += 1
            else:
                other += 1
    total = latin + other
    return other / total if total else 0.0


# More than this share of a "translation" outside the Latin alphabet, and the
# operator is told it was not translated.
UNTRANSLATED_SHARE = 0.5


DEFAULT_MODEL = "medium"
MODEL_PREFERENCE = ("medium", "small", "base.en", "base")


@dataclass
class Word:
    """A single timestamped word (from faster-whisper word timestamps).

    ``probability`` is the model's confidence for this word (0..1), when word
    timestamps were computed; used to highlight shaky words in the GUI.
    """

    start: float
    end: float
    word: str
    probability: Optional[float] = None


@dataclass
class Segment:
    """A single timestamped transcript segment.

    ``speaker`` is set when speaker diarization has been applied (see
    :func:`whispers.diarization.assign_speakers`); otherwise it is ``None``.
    ``words`` carries per-word timestamps when available, enabling word-level
    speaker assignment.
    """

    start: float
    end: float
    text: str
    speaker: Optional[str] = None
    words: List[Word] = field(default_factory=list)
    # Average token log-probability for the segment (higher is more confident);
    # None when not provided by the backend. Used for confidence highlighting.
    avg_logprob: Optional[float] = None


# Thresholds for the GUI's low-confidence highlighting. Word ``probability`` is
# 0..1 (from word timestamps); segment ``avg_logprob`` is a log-prob (roughly
# -0.1 is excellent, below ~-0.7 is shaky). Below these, text is flagged so an
# analyst knows which parts to re-check.
LOW_WORD_PROBABILITY = 0.55
LOW_SEGMENT_LOGPROB = -0.7


def is_low_confidence_word(word: "Word") -> bool:
    """True if ``word`` has a probability below the low-confidence threshold."""
    return word.probability is not None and word.probability < LOW_WORD_PROBABILITY


def is_low_confidence_segment(segment: "Segment") -> bool:
    """True if ``segment``'s average log-prob is below the low-confidence cut."""
    return segment.avg_logprob is not None and segment.avg_logprob < LOW_SEGMENT_LOGPROB


@dataclass
class TranscriptionResult:
    """The full result of transcribing one media file."""

    text: str
    language: str
    language_probability: float
    duration: float
    segments: List[Segment] = field(default_factory=list)
    # Seconds of audio actually transcribed. Equal to ``duration`` when silence
    # skipping is off; less when it is on, and the difference is what was
    # thrown away before the model ever saw it.
    duration_after_vad: Optional[float] = None

    @property
    def skipped_seconds(self) -> float:
        """Audio the silence filter removed. 0.0 when it was not used."""
        if self.duration_after_vad is None:
            return 0.0
        return max(0.0, self.duration - self.duration_after_vad)

    @property
    def kept_fraction(self) -> Optional[float]:
        """Share of the recording that reached the model (None when unfiltered)."""
        if self.duration_after_vad is None or self.duration <= 0:
            return None
        return max(0.0, min(1.0, self.duration_after_vad / self.duration))

    @property
    def has_speakers(self) -> bool:
        return any(segment.speaker for segment in self.segments)

    def _speaker_label(
        self, speaker: Optional[str], speaker_names: Optional[Dict[str, str]]
    ) -> str:
        label = speaker or "UNKNOWN"
        if speaker_names:
            return speaker_names.get(label, label)
        return label

    def to_txt(
        self,
        speaker_names: Optional[Dict[str, str]] = None,
        *,
        blank_lines: bool = False,
    ) -> str:
        """Plain-text transcript. When diarized, lines are prefixed with the
        speaker (optionally remapped via ``speaker_names``: id -> display name).

        ``blank_lines`` puts an empty line between segments (between speaker turns
        when diarized) - easier to read and to paste into a document.
        """
        sep = "\n\n" if blank_lines else "\n"
        if not self.has_speakers:
            if self.segments:
                return sep.join(segment.text for segment in self.segments)
            return self.text
        labels = [
            self._speaker_label(segment.speaker, speaker_names)
            for segment in self.segments
        ]
        body = sep.join(
            f"[{label}] {segment.text}" for label, segment in zip(labels, self.segments)
        )
        if any_leads(labels):
            # A transcript leaves this machine as this file; the marker on each
            # line is only self-explanatory if the file says what it means.
            return f"{LEAD_LEGEND}\n\n{body}"
        return body

    def to_srt(self, speaker_names: Optional[Dict[str, str]] = None) -> str:
        """Render the segments as SubRip (``.srt``) subtitles."""
        blocks = []
        for index, segment in enumerate(self.segments, start=1):
            start = _format_timestamp(segment.start)
            end = _format_timestamp(segment.end)
            if segment.speaker:
                label = self._speaker_label(segment.speaker, speaker_names)
                text = f"[{label}] {segment.text}"
            else:
                text = segment.text
            blocks.append(f"{index}\n{start} --> {end}\n{text}\n")
        return "\n".join(blocks)


def _format_timestamp(seconds: float) -> str:
    """Format ``seconds`` as an ``HH:MM:SS,mmm`` SubRip timestamp."""
    if seconds < 0:
        seconds = 0.0
    milliseconds = round(seconds * 1000)
    hours, milliseconds = divmod(milliseconds, 3_600_000)
    minutes, milliseconds = divmod(milliseconds, 60_000)
    secs, milliseconds = divmod(milliseconds, 1000)
    return f"{hours:02d}:{minutes:02d}:{secs:02d},{milliseconds:03d}"


def is_supported_media(path: PathLike) -> bool:
    """Return True if ``path`` has a known audio/video extension."""
    return Path(path).suffix.lower() in AUDIO_EXTENSIONS


def is_video(path: PathLike) -> bool:
    """Return True if ``path`` has a known video container extension."""
    return Path(path).suffix.lower() in VIDEO_EXTENSIONS


def convert_to_wav(
    path: PathLike,
    dest: Optional[PathLike] = None,
    *,
    sample_rate: int = WHISPER_SAMPLE_RATE,
    progress: Optional[ProgressCallback] = None,
) -> Path:
    """Extract/convert a media file's audio to a mono PCM WAV with ffmpeg.

    Parameters
    ----------
    path
        Source audio or video file.
    dest
        Destination ``.wav`` path. If ``None``, a temporary file is created and
        returned; the caller is responsible for deleting it.
    sample_rate
        Output sample rate in Hz (defaults to Whisper's 16 kHz).
    progress
        Optional status callback.

    Returns
    -------
    Path
        The path to the written WAV file.
    """
    src = Path(path)
    if not src.exists():
        raise FileNotFoundError(f"Input file does not exist: {src}")

    ffmpeg = find_ffmpeg()
    if ffmpeg is None:
        raise RuntimeError(
            "ffmpeg was not found (neither bundled in whispers_assets nor on PATH). "
            "Install it to convert video files (e.g. `sudo apt install ffmpeg`, "
            "`brew install ffmpeg`)."
        )

    created_temp = dest is None
    if dest is None:
        handle, tmp = tempfile.mkstemp(suffix=".wav")
        os.close(handle)
        out = Path(tmp)
    else:
        out = Path(dest)

    if progress is not None:
        progress(f"Converting {src.name} to WAV (ffmpeg)...")

    try:
        result = subprocess.run(
            [
                str(ffmpeg),
                "-y",
                "-i",
                str(src),
                "-vn",  # drop any video stream
                "-ac",
                "1",  # mono
                "-ar",
                str(sample_rate),
                "-acodec",
                "pcm_s16le",
                str(out),
            ],
            capture_output=True,
            text=True,
        )
        if result.returncode != 0:
            raise RuntimeError(f"ffmpeg conversion failed:\n{result.stderr.strip()}")
    except BaseException:
        # Don't leak the temp file we created if ffmpeg fails (or is interrupted).
        if created_temp:
            try:
                out.unlink()
            except OSError:
                pass
        raise
    return out


# Loaded faster-whisper models, keyed by (model_size, device, compute_type), so
# repeated runs (different files, retry after cancel) don't pay the load cost each
# time. Models are read-only at inference time, so sharing one is safe.
_MODEL_CACHE: Dict[Tuple[str, str, str], Any] = {}


class ModelUnavailable(RuntimeError):
    """The chosen model cannot be used here, in words an operator can act on."""


def usable_model_folder(path: PathLike) -> bool:
    """Whether ``path`` is a folder holding a converted (CTranslate2) model."""
    folder = Path(path)
    return folder.is_dir() and (folder / "model.bin").is_file()


def resolve_model_choice(name: str, bundled: "Dict[str, Path]") -> str:
    """What to hand faster-whisper for the model called ``name``.

    The one place that decides whether a model may be used, shared by the
    Transcribe and Live pages so they cannot disagree. A bundled name resolves
    to its folder; a folder holding a model is used as it is. Anything else is
    refused in a bundle - or wherever models are bundled - because the only
    thing faster-whisper could do with it is download it.

    Raises :class:`ModelUnavailable`. Running from source with nothing bundled,
    a plain size name is returned as-is and faster-whisper fetches it, which is
    the developer convenience and never happens in a shipped copy.
    """
    name = (name or "").strip()
    if not name:
        raise ModelUnavailable("Choose a model first.")
    if name in bundled:
        return str(bundled[name])
    if usable_model_folder(name):
        return str(Path(name))
    if Path(name).is_dir():
        raise ModelUnavailable(
            f"{name} is a folder but not a model: there is no model.bin in it. "
            "Choose the folder a converted model was copied into."
        )
    if bundled or is_bundle():
        raise ModelUnavailable(
            f"This copy has no \u2018{name}\u2019 model. System status (top "
            "right) lists the ones it has; another would need a rebuilt copy."
        )
    return name


def _load_model(
    model_size: str,
    device: str,
    compute_type: str,
    *,
    report: Optional[ProgressCallback] = None,
) -> Any:
    key = (model_size, device, compute_type)
    model = _MODEL_CACHE.get(key)
    if model is not None:
        return model
    try:
        from faster_whisper import WhisperModel
    except ImportError as exc:
        raise RuntimeError(
            "faster-whisper is not installed. Install the GUI/transcription "
            "extras with:  pip install 'whispers[gui]'"
        ) from exc
    if report is not None:
        report(f"Loading model '{model_size}' ({device}/{compute_type})...")
    # In a bundle, refuse to download even if something upstream let a bare
    # name through: resolve_model_choice is the gate, and this is the backstop.
    model = WhisperModel(
        model_size,
        device=device,
        compute_type=compute_type,
        local_files_only=is_bundle(),
    )
    _MODEL_CACHE[key] = model
    return model


def transcribe_audio(
    path: PathLike,
    *,
    model_size: str = "base",
    device: str = "cpu",
    compute_type: str = "int8",
    task: str = "transcribe",
    language: Optional[str] = None,
    beam_size: int = 5,
    vad_filter: bool = True,
    word_timestamps: bool = False,
    initial_prompt: Optional[str] = None,
    progress: Optional[ProgressCallback] = None,
    on_progress: Optional[Callable[[float], None]] = None,
    cancelled: Optional[CancelCallback] = None,
) -> TranscriptionResult:
    """Transcribe a single audio/video file with faster-whisper.

    Parameters
    ----------
    path
        Path to the audio or video file.
    model_size
        A faster-whisper model size (see ``MODEL_SIZES``) or a path to a
        local CTranslate2 model directory.
    device
        ``"cpu"`` (default, recommended for CPU-only hosts), ``"cuda"`` or
        ``"auto"``.
    compute_type
        Quantization, e.g. ``"int8"`` (default, best for CPU), ``"int8_float16"``
        or ``"float16"`` (GPU).
    task
        ``"transcribe"`` (default) keeps the source language; ``"translate"``
        translates speech into English.
    language
        ISO language code (e.g. ``"en"``) or ``None`` to auto-detect.
    beam_size
        Beam search width.
    vad_filter
        Drop non-speech with the Silero VAD before transcription.
    initial_prompt
        Optional text to prime the decoder - e.g. names, places, jargon or
        callsigns likely in the audio - which biases recognition toward that
        vocabulary. ``None`` (default) disables it.
    progress
        Optional callback invoked with human-readable status/segment strings;
        the GUI uses this to stream output as it is produced.
    """
    path = Path(path)
    if not path.exists():
        raise FileNotFoundError(f"Input file does not exist: {path}")

    def _report(message: str) -> None:
        if progress is not None:
            progress(message)

    model = _load_model(model_size, device, compute_type, report=_report)

    verb = "Translating" if task == "translate" else "Transcribing"
    _report(f"{verb} {path.name}...")
    segments_iter, info = model.transcribe(
        str(path),
        task=task,
        language=language,
        beam_size=beam_size,
        vad_filter=vad_filter,
        vad_parameters=vad_options() if vad_filter else None,
        # Word timestamps add an alignment pass; only compute them when needed
        # (diarization uses them for word-level speaker assignment).
        word_timestamps=word_timestamps,
        # None is the faster-whisper default (no priming).
        initial_prompt=initial_prompt or None,
    )

    segments: List[Segment] = []
    texts: List[str] = []
    for raw in segments_iter:
        if cancelled is not None and cancelled():
            raise CancelledError("Transcription cancelled.")
        text = raw.text.strip()
        words = [
            Word(
                start=w.start,
                end=w.end,
                word=w.word,
                probability=getattr(w, "probability", None),
            )
            for w in (raw.words or [])
        ]
        segments.append(
            Segment(
                start=raw.start,
                end=raw.end,
                text=text,
                words=words,
                avg_logprob=getattr(raw, "avg_logprob", None),
            )
        )
        texts.append(text)
        _report(f"[{_format_timestamp(raw.end)}] {text}")
        # Real progress: how far the latest segment's end is through the audio.
        if on_progress is not None and info.duration:
            on_progress(min(raw.end / info.duration, 1.0))
    if on_progress is not None:
        on_progress(1.0)

    return TranscriptionResult(
        text="\n".join(texts).strip(),
        language=info.language,
        language_probability=info.language_probability,
        duration=info.duration,
        duration_after_vad=(
            getattr(info, "duration_after_vad", None) if vad_filter else None
        ),
        segments=segments,
    )
