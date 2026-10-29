"""Run every stage of the pipeline, in order, from one call.

The stage order is the one ``app/pipeline/__init__.py`` documents::

    source video
      -> video.extract_audio            48 kHz stereo PCM WAV
      -> separation.separate_stems      speech / music / effects
      -> diarization.diarize            speaker turns
      -> transcription.transcribe       spoken lines, per speaker
      -> translation.adapt_dialogue     spoken Amharic (+ performance metadata when
                                        the backend produces it)
      -> voice_profiles.build_voice_profiles   one identity reference per speaker
                                        (per-character engines only)
      -> tts.synthesize_dialogue        Amharic speech clips
      -> timing.align_dialogue          each line fitted to its original window
      -> mixing.mix_track              dialogue over ducked music + effects
      -> video.mux_dub                  the Amharic mix back into the video

and the deliverable is a dubbed MP4: the original picture, untouched, with the
Amharic dialogue in place of the English.

Command line::

    python -m app.pipeline.orchestrator data/input/movie.mp4
    python -m app.pipeline.orchestrator movie.mp4 --out runs/movie --max-lines 5

What it deliberately does not do
--------------------------------
* **No caching of its own.** Every stage runs on every call. The expensive
  per-line work in :mod:`app.pipeline.tts` is already content-addressed and skips
  artifacts that are on disk, which is where the real cost is; resuming whole
  stages from a manifest is a later concern.
* **No stage settings of its own beyond passing ``settings`` through**, so the
  orchestrator can never disagree with a stage about a path or a limit.
* **No hiding of failures.** A stage error is wrapped only to say which stage it
  came from; the original exception and traceback are preserved.
"""

from __future__ import annotations

import argparse
import json
import sys
import time
import traceback
from collections.abc import Callable, Mapping
from dataclasses import dataclass
from pathlib import Path
from typing import Any

from app.config import Settings, get_settings
from app.pipeline import (
    dialogue_context,
    diarization,
    evaluation,
    mixing,
    qc,
    separation,
    timing,
    transcription,
    translation,
    tts,
    video,
    voice_profiles,
)
from app.pipeline.amharic_text import count_syllables
from app.pipeline.dialogue_context import placement_windows
from app.pipeline.diarization import CrosstalkRegion, SpeakerSegment
from app.pipeline.mixing import MixResult
from app.pipeline.timing import AlignedClip
from app.pipeline.transcription import TranscriptSegment
from app.pipeline.translation import AdaptedDialogue
from app.pipeline.tts import SkippedLine, TtsClip
from app.pipeline.video import MuxResult
from app.pipeline.voice_profiles import VoiceProfile, portable_path

#: Manifest written next to a run's artifacts.
MANIFEST_FILENAME = "manifest.json"

#: Sub-directory holding the extracted track and the separated stems: the large,
#: per-source intermediates, kept with the run rather than in ``WORK_DIR``.
STAGES_DIRNAME = "stages"

#: Stage names, in execution order, as recorded in the manifest.
STAGE_ORDER: tuple[str, ...] = (
    "extract",
    "separation",
    "diarization",
    "transcription",
    "translation",
    "voice_profiles",
    "tts",
    "timing",
    "mixing",
    "mux",
)


class OrchestrationError(RuntimeError):
    """Base class for every error raised by this module."""


class MissingSourceError(OrchestrationError):
    """The source video does not exist."""


class EmptyStageError(OrchestrationError):
    """A stage ran but produced nothing the next stage could use."""


class StageError(OrchestrationError):
    """A stage failed; the original exception is chained onto this one."""


@dataclass(frozen=True, slots=True)
class PipelineResult:
    """Everything the stages produced for one source video."""

    source: Path
    output_dir: Path
    track: Path
    stems: separation.StemPaths
    turns: tuple[SpeakerSegment, ...]
    lines: tuple[TranscriptSegment, ...]
    crosstalk: tuple[CrosstalkRegion, ...]
    dialogue: tuple[AdaptedDialogue, ...]
    profiles: Mapping[str, VoiceProfile]
    clips: tuple[TtsClip, ...]
    skipped: tuple[SkippedLine, ...]
    alignment: tuple[AlignedClip, ...]
    mix: MixResult
    dub: MuxResult
    manifest_path: Path
    stage_seconds: Mapping[str, float]
    elapsed_seconds: float
    synthesized_lines: int
    #: How much of the film's original dialogue survived separation into the bed.
    bleed: separation.BleedReport | None = None
    #: How much of the film's original audio survived into the dubbed dialogue track.
    dub_bleed: separation.BleedReport | None = None
    #: Anything the TTS stage wanted the run to know without treating it as a failure.
    notes: tuple[str, ...] = ()
    speaker_corrections: tuple[diarization.SpeakerAttributionCorrection, ...] = ()

    @property
    def final_video(self) -> Path:
        """The deliverable: the source video with the Amharic dialogue track."""

        return self.dub.path

    @property
    def partial(self) -> bool:
        """``True`` when only some lines were synthesized, so the dub is partial."""

        return self.synthesized_lines < len(self.dialogue)

    @property
    def unfitted_lines(self) -> tuple[AlignedClip, ...]:
        """Lines whose delivery could not be fitted to their original window."""

        return tuple(line for line in self.alignment if not line.fits)

    def to_dict(self) -> dict[str, Any]:
        """Return a JSON-safe view of the run, for a manifest or a report."""

        return {
            "source": portable_path(self.source),
            "output_dir": portable_path(self.output_dir),
            "final_video": portable_path(self.final_video),
            "partial": self.partial,
            "synthesized_lines": self.synthesized_lines,
            "elapsed_seconds": round(self.elapsed_seconds, 3),
            "stage_seconds": {
                name: round(seconds, 3) for name, seconds in self.stage_seconds.items()
            },
            "track": portable_path(self.track),
            "stems": {
                name: portable_path(path) for name, path in self.stems.as_dict().items()
            },
            "diarization": {
                "turns": len(self.turns),
                "speakers": sorted({turn.speaker_id for turn in self.turns}),
                "speaker_corrections": [
                    {
                        "start": correction.start,
                        "end": correction.end,
                        "from": correction.original_speaker_id,
                        "to": correction.corrected_speaker_id,
                        "similarity": round(correction.corrected_similarity, 4),
                        "margin": round(correction.similarity_margin, 4),
                    }
                    for correction in self.speaker_corrections
                ],
                # Simultaneous speech the exclusive attribution could not carry.
                # Reported so a run can be audited for it without re-listening.
                "crosstalk": {
                    "regions": len(self.crosstalk),
                    "seconds": round(
                        sum(region.duration for region in self.crosstalk), 3
                    ),
                    "detail": [
                        {
                            "start": region.start,
                            "end": region.end,
                            "speakers": list(region.speaker_ids),
                        }
                        for region in self.crosstalk
                    ],
                },
            },
            "transcription": {
                "lines": len(self.lines),
                "sentences": len(self.dialogue),
                "segments": [_segment_dict(segment) for segment in self.lines],
            },
            "translation": {
                "lines": len(self.dialogue),
                "segments": [_dialogue_dict(line) for line in self.dialogue],
            },
            "voice_profiles": {                speaker_id: {
                    "reference_audio": portable_path(profile.reference_audio),
                    "reference_start": profile.reference_start,
                    "reference_end": profile.reference_end,
                    "reference_duration": profile.reference_duration,
                    "reference_text": profile.reference_text,
                    "clone_prompt_path": (
                        None
                        if profile.clone_prompt_path is None
                        else portable_path(profile.clone_prompt_path)
                    ),
                    "quality_score": profile.quality_score,
                    "selection_reason": profile.selection_reason,
                    "estimated_vocal_presentation": profile.estimated_vocal_presentation,
                    "estimated_pitch_hz": profile.estimated_pitch_hz,
                }
                for speaker_id, profile in self.profiles.items()
            },
            "tts": {
                "clips": [clip.to_dict() for clip in self.clips],
                # Lines the stage could not voice. Recorded because a line missing
                # from the dub is audible, so a run has to be able to say which
                # ones and why without re-listening to the film.
                "skipped": [line.as_dict() for line in self.skipped],
            },
            "timing": {
                "lines": len(self.alignment),
                "unfitted": len(self.unfitted_lines),
                "segments": [line.to_dict() for line in self.alignment],
            },
            "mixing": self.mix.to_dict(),
            "mux": self.dub.to_dict(),
            "bleed": None if self.bleed is None else self.bleed.as_dict(),
            "dub_bleed": None if self.dub_bleed is None else self.dub_bleed.as_dict(),
        }

    def report(self) -> str:
        """Return a short human-readable summary of the run."""

        speakers = sorted({turn.speaker_id for turn in self.turns})
        stretched = sum(1 for line in self.alignment if line.tempo != 1.0)
        drifted = [line for line in self.alignment if line.drift > 0.005]
        lines = [
            f"source          {self.source}",
            f"output          {self.output_dir}",
            f"stems           {', '.join(path.name for path in self.stems.as_dict().values())}",
            f"diarization     {len(self.turns)} turn(s), {len(speakers)} speaker(s)",
            f"transcription   {len(self.lines)} line(s)",
            f"adaptation      {len(self.dialogue)} Amharic line(s)",
            f"voice profiles  {len(self.profiles)} profile(s)",
            f"tts             {len(self.clips)} clip(s)",
            f"timing          {len(self.alignment)} aligned, {stretched} stretched, "
            f"{len(self.unfitted_lines)} not fitted",
            f"placement       {len(drifted)} line(s) moved later to avoid speaking over "
            f"the line before them, worst "
            f"{max((line.drift for line in drifted), default=0.0):.2f} s",
            f"bleed           "
            f"{'not measured' if self.bleed is None else self.bleed.summary()}",
            f"dub bleed       "
            f"{'not measured' if self.dub_bleed is None else self.dub_bleed.summary()}",
            f"mixing          {self.mix.duration:.1f} s track, "
            f"{len(self.mix.overlaps)} overlapping line(s), "
            f"peak {self.mix.peak:.3f}",
            f"dub             {self.dub.path.name} "
            f"({self.dub.video_codec} video, {self.dub.audio_codec} "
            f"{self.dub.audio_sample_rate} Hz audio)",
            f"manifest        {self.manifest_path}",
            f"elapsed         {self.elapsed_seconds:.1f} s",
        ]
        for note in self.notes:
            lines.append(f"note            {note}")
        if self.partial or self.skipped:
            reasons: list[str] = []
            if self.skipped:
                reasons.append(f"{len(self.skipped)} line(s) could not be voiced")
            if self.synthesized_lines + len(self.skipped) < len(self.dialogue):
                reasons.append("--max-lines")
            detail = f" ({'; '.join(reasons)})" if reasons else ""
            lines.insert(
                6,
                f"PARTIAL DUB     only {self.synthesized_lines} of "
                f"{len(self.dialogue)} line(s) were synthesized{detail}",
            )
        return "\n".join(lines)


def _print_progress(message: str) -> None:
    """Default progress sink: one flushed line per stage."""

    print(message, flush=True)


def _stage(
    name: str,
    seconds: dict[str, float],
    progress: Callable[[str], None],
    work: Callable[..., Any],
    *args: Any,
    **kwargs: Any,
) -> Any:
    """Run one stage, timing it and naming it when it fails."""

    progress(f"  -> {name}")
    started = time.perf_counter()
    try:
        result = work(*args, **kwargs)
    except Exception as exc:
        raise StageError(
            f"the {name} stage failed with {type(exc).__name__}: {exc}"
        ) from exc
    finally:
        seconds[name] = time.perf_counter() - started
    return result


def _segment_dict(segment: Any) -> dict[str, Any]:
    """Return the timing and text fields of a diarized or transcribed segment.

    The segment types are frozen dataclasses without a JSON view, and the
    orchestrator only needs the fields a manifest reader would look for.
    """

    return {
        "speaker_id": segment.speaker_id,
        "start": segment.start,
        "end": segment.end,
        "text": segment.text,
    }


def _dialogue_dict(line: AdaptedDialogue) -> dict[str, Any]:
    """Return the full content of one adapted Amharic line."""

    entry: dict[str, Any] = {
        "speaker_id": line.speaker_id,
        "start": line.start,
        "end": line.end,
        "source_text": line.source_text,
        "amharic": line.amharic,
        "emotion": line.emotion,
        "intensity": line.intensity,
        "delivery": line.delivery,
        "pause_before": line.pause_before,
        "pause_after": line.pause_after,
    }
    if line.beats:
        # One sentence, several performances: the direction and the moment it
        # applies to, so nothing the dialogue model saw is lost in the manifest.
        entry["beats"] = [beat.as_dict() for beat in line.beats]
    return entry


def _report_dialogue_fit(
    dialogue: Sequence[Any],
    settings: Any,
    report: Callable[[str], None],
) -> None:
    """Say whether the Amharic can be spoken in the time the film gives it.

    This is the measurement that decides what the rest of the run can do. Amharic does not
    express the same idea in the same number of syllables as English, so a faithful
    translation of film dialogue is routinely longer than the lines it replaces - and if
    the total is longer than the time available, *something* has to give: the delivery is
    sped up, or lines are cut short, or two voices end up overlapping. Stating the ratio
    here means that is a known quantity from the adaptation stage onward rather than
    something inferred from an audio artefact at the end.
    """

    spans = [(line.start, line.end) for line in dialogue]
    if not spans:
        return
    rooms = placement_windows(spans, gap=settings.timing_min_line_gap)
    rate = settings.translation_syllables_per_second
    needed = sum(count_syllables(line.amharic) / rate for line in dialogue)
    available = sum(rooms)
    if available <= 0:
        return

    over = sum(
        1
        for line, room in zip(dialogue, rooms)
        if count_syllables(line.amharic) > max(1, round(room * rate))
    )
    ratio = needed / available
    report(
        f"  dialogue fit: {needed:.1f}s of Amharic in {available:.1f}s available "
        f"({ratio:.2f}x), {over} line(s) over their own time"
    )
    if ratio > 1.0:
        report(
            "        - the Amharic is longer than the film's dialogue time; the timing "
            "stage will use the silence between lines first, then speed lines up to "
            f"{settings.timing_max_tempo:g}x, and only then cut a line short"
        )


def run_pipeline(
    source: str | Path,
    *,
    output_dir: str | Path | None = None,
    settings: Settings | None = None,
    max_lines: int | None = None,
    progress: Callable[[str], None] | None = None,
) -> PipelineResult:
    """Run every implemented stage on ``source`` and return what they produced.

    Parameters
    ----------
    source:
        Source video. Its audio track is extracted first, so the stages never see
        the container format.
    output_dir:
        Directory for the run: the extracted track, the stems and the manifest.
        Defaults to ``<OUTPUT_DIR>/<source stem>``.
    settings:
        Project settings override; defaults to :func:`app.config.get_settings`.
    max_lines:
        Synthesize only the first ``N`` adapted lines. A cost control for the
        first run of a long film; every earlier stage still runs in full.
    progress:
        Callable receiving one line per stage. Defaults to printing.

    Returns
    -------
    PipelineResult
        Including :attr:`PipelineResult.final_video`, the dubbed MP4.

    Raises
    ------
    MissingSourceError
        The source video does not exist.
    EmptyStageError
        A stage produced nothing to pass on.
    StageError
        A stage failed. The stage's own exception is chained, so the original
        cause and traceback are still available.
    """

    resolved = settings if settings is not None else get_settings()

    video_path = Path(source)
    if not video_path.is_file():
        raise MissingSourceError(f"source video not found: {video_path}")

    # Only after the source is known to exist, so a typo never leaves empty
    # directories behind in the working tree.
    resolved.ensure_directories()

    run_dir = (
        Path(output_dir)
        if output_dir is not None
        else Path(resolved.output_dir) / video_path.stem
    )
    stages_dir = run_dir / STAGES_DIRNAME
    stages_dir.mkdir(parents=True, exist_ok=True)

    report = _print_progress if progress is None else progress
    seconds: dict[str, float] = {}
    started = time.perf_counter()

    report(f"{video_path.name}: running stages into {run_dir}")

    track = _stage(
        "extract",
        seconds,
        report,
        video.extract_audio,
        video_path,
        stages_dir / f"{video_path.stem}{video.DEFAULT_TRACK_SUFFIX}",
        settings=resolved,
    )
    stems = _stage(
        "separation",
        seconds,
        report,
        separation.separate_stems,
        track,
        output_dir=stages_dir,
        settings=resolved,
        on_progress=report,
    )

    diarized = _stage(
        "diarization",
        seconds,
        report,
        diarization.diarize_detailed,
        stems.speech,
        settings=resolved,
    )
    turns = tuple(diarized.turns)
    if not turns:
        raise EmptyStageError(
            f"diarization found no speech in {stems.speech}; nothing downstream can run"
        )
    crosstalk = tuple(diarized.crosstalk)
    speaker_corrections = tuple(diarized.corrections)
    if speaker_corrections:
        report(
            f"  speaker verification: corrected {len(speaker_corrections)} "
            "high-confidence turn attribution(s)"
        )
    if crosstalk:
        report(
            f"  crosstalk: {len(crosstalk)} region(s), "
            f"{diarized.crosstalk_seconds:.2f}s of simultaneous speech"
        )

    lines = tuple(
        _stage(
            "transcription",
            seconds,
            report,
            transcription.transcribe,
            stems.speech,
            turns,
            settings=resolved,
        )
    )
    if not lines:
        raise EmptyStageError("transcription produced no lines; nothing to adapt")

    # A transcriber segments on pauses, not on grammar, so one spoken sentence
    # routinely arrives as several segments. Adapting and speaking each of them
    # separately produces exactly what a listener hears as broken delivery: the
    # same thought becomes several utterances, each with its own final intonation.
    # The sentence is therefore the unit from here on; the raw segments stay the
    # record of what was transcribed, and the clauses inside a sentence stay
    # available as performance beats.
    sentences = tuple(transcription.assemble_sentences(lines))
    if sentences and len(sentences) < len(lines):
        report(
            f"  dialogue: {len(lines)} transcribed segment(s) assembled into "
            f"{len(sentences)} sentence(s)"
        )

    # Consistency state, not a guess: an absent bible yields an empty one, so a
    # first run works and a second run inherits whatever was filled in by hand.
    bible = dialogue_context.CharacterBible.load(resolved.dialogue_bible_path)

    dialogue = tuple(
        _stage(
            "translation",
            seconds,
            report,
            translation.adapt_dialogue,
            sentences,
            settings=resolved,
            bible=bible,
            enforce_budget=resolved.translation_enforce_budget,
            enforce_fidel_loanwords=resolved.translation_enforce_fidel_loanwords,
            maximum_reduction_attempts=resolved.translation_max_reduction_attempts,
            on_progress=report,
        )
    )
    if resolved.translation_backend == "nllb":
        # NLLB is a sentence-level translation model: it is handed one line at a time
        # and cannot be asked for a shorter rewrite, so the scene/character context,
        # the syllable-budget re-ask and the script check have nothing to act on here.
        # They are not silently skipped - the run says so.
        report(
            "  adaptation: NLLB translates line by line; scene/character context and "
            "length enforcement are not applied"
        )
        # Whether the Amharic can be spoken in the time the film gives it is the number
        # that decides whether the dub fits or has to be squashed, so it is measured and
        # stated here rather than left to be discovered from the timing report later.
        _report_dialogue_fit(dialogue, resolved, report)
    else:
        # Which model produced the Amharic, and how hard it was asked to think, are the
        # first things to know when comparing two runs. The provider also decides whether
        # the requested thinking level was even available, which a bare model name would
        # leave a reader to guess at.
        report(
            f"  adaptation: {resolved.translation_provider} "
            f"{resolved.translation_model} "
            f"({translation.describe_thinking(resolved)})"
        )
        report(f"  adaptation fallback: {translation.describe_fallback(resolved)}")
        report(
            "  adaptation requests: one per batch; no rewrites, retries, or failover"
        )
        # Only the instruction-following backend reads the bible, so only it can report
        # having applied one.
        if bible:
            report(f"  dialogue bible: {len(bible)} character(s) applied")
    if not dialogue:
        raise EmptyStageError("adaptation produced no lines; nothing to synthesize")

    # Voice profiles answer "what should this character sound like?" - a question only
    # an engine that reads a per-speaker reference can act on. A single-voice engine
    # speaks everyone the same way, so building identities for it would be work whose
    # only result is a set of references nothing reads. Which engines those are is the
    # TTS stage's own contract, asked rather than assumed here.
    needs_profiles = tts.engine_needs_profiles(resolved.tts_engine)
    profiles: Mapping[str, VoiceProfile] = {}
    if not needs_profiles:
        seconds["voice_profiles"] = 0.0
        report(f"  voice profiles: skipped ({resolved.tts_engine} is single-voice)")
    else:
        # Built from every transcribed line, not from a shortened run: a profile is a
        # character's identity and is reused across runs, so it is never truncated.
        profiles = _stage(
            "voice_profiles",
            seconds,
            report,
            voice_profiles.build_voice_profiles,
            turns,
            stems.speech,
            # Simultaneous speech is passed in because it is the one thing the
            # per-line overlap check cannot see: the turns it compares are exclusive,
            # so a window full of crosstalk still reports no overlap.
            crosstalk=crosstalk,
            transcript=lines,
            settings=resolved,
            require_reference_transcript=True,
        )
        if not profiles:
            raise EmptyStageError(
                "no voice profile could be built from the dialogue stem; the TTS stage "
                "needs one identity reference per speaker"
            )
        report(
            "  voice references: using clean, transcript-matched film-actor audio "
            "(one continuous 4-10 second interval per character; "
            "Amharic-tuned OmniVoice)"
        )
        for speaker_id, profile in profiles.items():
            pitch = (
                f", median pitch {profile.estimated_pitch_hz:.0f} Hz"
                if profile.estimated_pitch_hz is not None
                else ""
            )
            report(
                f"  voice presentation estimate: {speaker_id} "
                f"{profile.estimated_vocal_presentation}{pitch}; actor reference "
                "is the voice identity"
            )

    spoken = dialogue
    if max_lines is not None and max_lines < len(dialogue):
        if max_lines < 0:
            raise OrchestrationError(f"max_lines must be >= 0, got {max_lines}")
        report(
            f"  max-lines: synthesizing the first {max_lines} of {len(dialogue)} line(s)"
        )
        spoken = dialogue[:max_lines]

    synthesized = _stage(
        "tts",
        seconds,
        report,
        tts.synthesize_dialogue_detailed,
        spoken,
        stems.speech,
        profiles or None,
        settings=resolved,
    )
    clips = tuple(synthesized.clips)
    skipped = tuple(synthesized.skipped)
    if synthesized.pacing is not None:
        # Reported, not silent: "the whole film is being delivered 8% faster" is a
        # decision about the performance, and it should not have to be inferred.
        report(f"  pacing: film rate {synthesized.pacing.film_rate:.3f}")
    if skipped:
        report(
            f"  skipped: {len(skipped)} line(s) could not be voiced "
            f"({len(synthesized.failed)} engine failure(s))"
        )
    for note in synthesized.notes:
        report(f"  note: {note}")
    if not clips:
        raise EmptyStageError(
            "speech synthesis produced no clips; there is nothing to place or mix"
        )

    alignment = tuple(
        _stage(
            "timing",
            seconds,
            report,
            timing.align_dialogue,
            clips,
            output_dir=run_dir,
            settings=resolved,
        )
    )

    # Measured, because the one way the source language can survive into a finished
    # dub is the separator leaving it in the music or effects, which are re-mixed
    # untouched. Cheap next to the stages above, and the alternative is finding out
    # from a listener.
    try:
        bleed = separation.measure_bed_bleed(
            stems, [(line.start, line.end) for line in lines]
        )
    except separation.SeparationError as exc:
        # A diagnostic must never be the reason a finished dub is lost, so an
        # unreadable stem is reported as unmeasured rather than raised.
        bleed = None
        report(f"  bleed: not measured ({exc})")
    else:
        report(f"  bleed: {bleed.summary()}")
        if not bleed.clean:
            report(
                "  bleed: WARNING the original dialogue is still in the bed under "
                f"{bleed.leaked} line(s); it will be heard under the Amharic"
            )

    mixed = _stage(
        "mixing",
        seconds,
        report,
        mixing.mix_track,
        alignment,
        stems.music,
        stems.effects,
        output_dir=run_dir,
        settings=resolved,
    )

    # The bed check above cannot see the finished dub: it inspects the music and
    # effects, and the dubbed dialogue is not part of them. This is the other half -
    # the original audio surviving into the track a listener actually hears - and it
    # is what catches a mixing, placement or caching fault that reintroduces English.
    try:
        dub_bleed = separation.measure_dub_bleed(
            track,
            mixed.dialogue_path,
            [(line.start, line.end) for line in alignment],
        )
    except separation.SeparationError as exc:
        dub_bleed = None
        report(f"  dub bleed: not measured ({exc})")
    else:
        report(f"  dub bleed: {dub_bleed.summary()}")
        if not dub_bleed.clean:
            report(
                "  dub bleed: WARNING the original audio is audible inside the dubbed "
                f"dialogue on {dub_bleed.leaked} line(s)"
            )

    dub = _stage(
        "mux",
        seconds,
        report,
        video.mux_dub,
        video_path,
        mixed.mixed_path,
        run_dir / f"{video_path.stem}{video.DEFAULT_DUB_SUFFIX}",
        settings=resolved,
    )

    result = PipelineResult(
        source=video_path,
        output_dir=run_dir,
        track=track,
        stems=stems,
        turns=turns,
        lines=lines,
        crosstalk=crosstalk,
        speaker_corrections=speaker_corrections,
        dialogue=dialogue,
        profiles=dict(profiles),
        clips=clips,
        skipped=skipped,
        notes=tuple(synthesized.notes),
        bleed=bleed,
        dub_bleed=dub_bleed,
        alignment=alignment,
        mix=mixed,
        dub=dub,
        manifest_path=run_dir / MANIFEST_FILENAME,
        stage_seconds=dict(seconds),
        elapsed_seconds=time.perf_counter() - started,
        synthesized_lines=len(clips),
    )

    # Measured, not assumed: the model-free quality report is part of every run.
    # Pronunciation needs an Amharic ASR model and is off unless asked for: it loads a
    # second model and transcribes every clip, which is real time on a feature film.
    # When it *is* asked for, it is the only check that can see content the speech model
    # invented - a stray word, a fragment of the English prompt it was cloned from, a
    # mispronunciation. None of that is the original audio, so comparing the output with
    # the original, as the bleed measurements do, can never find it.
    transcriber: Callable[[Path], str] | None = None
    if resolved.qc_pronunciation:
        try:
            transcriber = transcription.build_amharic_transcriber(resolved)
        except Exception as exc:
            report(f"  qc: pronunciation unavailable ({type(exc).__name__}: {exc})")

    quality = qc.build_qc_report(
        result.alignment,
        dialogue=result.dialogue,
        clips=result.clips,
        crosstalk=result.crosstalk,
        transcribe=transcriber,
        transcription_model=resolved.transcription_model,
    )
    # Which hard cases the material actually contains. A run can score well simply
    # because it was easy, so this says what was *not* exercised.
    coverage = evaluation.measure_coverage(result.dialogue, crosstalk=result.crosstalk)

    _write_manifest(
        result,
        settings=resolved,
        quality=quality,
        coverage=coverage,
    )
    report(result.report())
    report(f"qc              {quality.summary()}")
    report(f"coverage        {coverage.summary()}")
    return result


def _provenance(settings: Settings) -> dict[str, Any]:
    """Describe what actually produced a run, for reproducibility.

    Which model adapted the dialogue, which speech engine spoke it, and how hard the
    model was asked to think are the first things two runs are compared on - and the
    terminal that printed them is gone as soon as the Pod stops, while the manifest
    travels home with the dub.
    """

    provenance: dict[str, Any] = {
        "tts_engine": settings.tts_engine,
        "translation_backend": settings.translation_backend,
    }

    if settings.translation_backend == "openai":
        provenance["translation_provider"] = settings.translation_provider
        provenance["translation_model"] = settings.translation_model
        # What was *sent*, not what was configured: the provider decides whether the
        # requested level was available, and a manifest must not claim reasoning the
        # request never carried.
        provenance["translation_thinking"] = translation.describe_thinking(settings)
        provenance["translation_fallback"] = translation.describe_fallback(settings)
    else:
        # NLLB is a local checkpoint, so it is the path that identifies it.
        provenance["translation_model"] = settings.translation_model

    return provenance


def _engine_note(settings: Settings) -> str:
    """Describe the synthesis chain this run actually used.

    What produced a dub has to be readable from the manifest alone, so the note names
    the engine and says whether it cloned a per-character voice or spoke everyone in
    one.
    """

    if tts.engine_needs_profiles(settings.tts_engine):
        return (
            f"{settings.tts_engine} runs voice cloning: each character is spoken in "
            "their own voice, cloned from their isolated performance in the film, so "
            "the dub carries that performance's accent as well as its timbre"
        )
    return (
        f"{settings.tts_engine} is a single-voice engine: one voice speaks every part"
    )


def _write_manifest(
    result: PipelineResult,
    *,
    settings: Settings,
    quality: qc.QcReport | None = None,
    coverage: evaluation.CoverageReport | None = None,
) -> Path:
    """Write the run's manifest, atomically, and return its path."""

    report = quality if quality is not None else qc.build_qc_report(
        result.alignment,
        dialogue=result.dialogue,
        clips=result.clips,
        crosstalk=result.crosstalk,
    )
    exercised = (
        coverage
        if coverage is not None
        else evaluation.measure_coverage(result.dialogue, crosstalk=result.crosstalk)
    )

    payload: dict[str, Any] = {
        "run": result.to_dict(),
        "settings": settings.as_dict(),
        "provenance": _provenance(settings),
        "qc": report.as_dict(),
        "coverage": exercised.as_dict(),
        "notes": [
            "video streams are copied, never re-encoded; the source's own audio "
            "streams are replaced by the Amharic mix",
            _engine_note(settings),
            "loudness normalization (EBU R128) is not applied: the mix is placed "
            "at a defined peak with defined dialogue and bed levels",
            "clip paths are content-addressed artifacts of the tts stage, so later "
            "runs of the same lines reuse them instead of re-synthesizing",
            "a line whose Amharic needs more time than the film gave it is moved "
            "later rather than being spoken over the next line, because two voices "
            "at once cannot be understood; the shift is recorded per line as 'drift'",
            "the qc block is measured, not assumed; pronunciation is left "
            "unmeasured because it needs an Amharic ASR model, which is injected "
            "by the caller rather than downloaded by a run",
        ],
    }
    if result.partial or result.skipped:
        why = (
            f"{len(result.skipped)} line(s) could not be voiced"
            if result.skipped
            else "the run was limited with --max-lines"
        )
        payload["notes"].insert(
            0,
            f"INCOMPLETE DUB: only {result.synthesized_lines} of "
            f"{len(result.dialogue)} line(s) were synthesized ({why}); see run.tts "
            "for the lines that are missing and why",
        )
    payload["notes"].extend(result.notes)

    target = result.manifest_path
    temporary = target.with_suffix(target.suffix + ".tmp")
    temporary.write_text(
        json.dumps(payload, ensure_ascii=False, indent=2) + "\n", encoding="utf-8"
    )
    temporary.replace(target)
    return target


def main(argv: list[str] | None = None) -> int:
    """Command-line entry point: ``python -m app.pipeline.orchestrator SOURCE``."""

    parser = argparse.ArgumentParser(
        prog="python -m app.pipeline.orchestrator",
        description=(
            "Run every dubbing stage on a source video and write a dubbed MP4: the "
            "original picture with an Amharic dialogue track."
        ),
    )
    parser.add_argument("source", type=Path, help="source video to dub")
    parser.add_argument(
        "--out",
        type=Path,
        default=None,
        help="directory for the run (default: <OUTPUT_DIR>/<source stem>)",
    )
    parser.add_argument(
        "--max-lines",
        type=int,
        default=None,
        help=(
            "synthesize only the first N adapted sentences (first-run cost control). "
            "The result is a partial dub: the remaining sentences are not voiced."
        ),
    )
    args = parser.parse_args(argv)

    try:
        result = run_pipeline(args.source, output_dir=args.out, max_lines=args.max_lines)
    except OrchestrationError as exc:
        print(f"\nFAILED: {exc}", file=sys.stderr)
        traceback.print_exc()
        return 1

    if result.skipped:
        # A dub missing lines is a deliverable that is wrong rather than a run that
        # failed, so it still exits non-zero: a caller that only checks the exit code
        # must not be able to ship a film with dialogue missing from it.
        print(
            f"\nINCOMPLETE DUB: {len(result.skipped)} of {len(result.dialogue)} "
            f"line(s) were not voiced. {result.manifest_path} records the reason for "
            "each one under run.tts.skipped_lines.",
            file=sys.stderr,
        )
        return 2
    return 0


if __name__ == "__main__":
    raise SystemExit(main())


__all__ = [
    "MANIFEST_FILENAME",
    "STAGES_DIRNAME",
    "STAGE_ORDER",
    "EmptyStageError",
    "MissingSourceError",
    "OrchestrationError",
    "PipelineResult",
    "StageError",
    "main",
    "run_pipeline",
]
