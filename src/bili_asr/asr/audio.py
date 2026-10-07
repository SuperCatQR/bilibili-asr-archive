"""Audio implementation."""

from __future__ import annotations

import os
import shutil
import subprocess
import tempfile
from typing import Any
import bili_asr.asr.constants as _dependency_constants
import bili_asr.asr.errors as _dependency_errors


def _materialize_input(audio_path: str) -> tuple[str, str | None]:
    """Return an input path the audio reader can open.

    The CLI hands this boundary a confined descriptor path so the audio never leaves the archive
    root.  Descriptor paths are not universally openable by the decoder libraries, so one is copied
    to a temporary file which the caller removes.  A plain path is returned untouched.

    The original reason (plan §13.1) was a child ``ffmpeg``, which a descriptor cannot be handed to,
    and that reason is live again: ``_decode_with_ffmpeg`` runs ``ffmpeg`` as a child for every
    container libsndfile cannot open, i.e. for every ``.m4a`` this archive downloads.  The descriptor
    is not passed through (``subprocess.run`` is called without ``pass_fds``), so a ``/proc/self/fd``
    path handed to it would resolve inside the child to a closed descriptor — measured: the fallback
    raises ``AudioDecodeError`` for such a path.  This step is therefore load-bearing for the
    project's primary input format, not merely a legacy convenience, and a ``.m4a`` run exercises it.
    """

    if not isinstance(audio_path, str) or not _dependency_constants._DESCRIPTOR_PATH.match(audio_path):
        return audio_path, None
    handle, temporary = tempfile.mkstemp(prefix="bili-asr-asr-", suffix=".audio")
    try:
        with os.fdopen(handle, "wb") as target, open(audio_path, "rb") as source:
            shutil.copyfileobj(source, target)
    except OSError:
        try:
            os.unlink(temporary)
        except OSError:
            pass
        raise
    return temporary, temporary


def _decode_with_ffmpeg(path: str) -> tuple[Any, int]:
    """Decode a container ``libsndfile`` cannot open, through the ``ffmpeg`` binary.

    ``ffmpeg`` is a declared requirement of the product (``AGENTS.md``), and the download layer
    already shells out to it to remux explicit FLAC streams, so this adds no new kind of
    dependency — it only moves the AAC decode onto a tool that is guaranteed present rather than
    onto a Python package whose support for it varies by release.

    The audio is decoded to a float WAV in a temporary file and read back with the same
    ``soundfile`` reader the primary path uses, which keeps one decode shape for both paths and
    preserves the source's native rate and channel count.  A pipe was rejected deliberately: the
    longer archive items are hours long, so buffering a whole WAV in memory to hand ``soundfile`` a
    seekable object would cost gigabytes, while a temp file costs only the decoded array.

    Three ffmpeg flags are load-bearing, each because a failure was measured rather than imagined:

    * ``-nostdin`` — without a stdin guard ``ffmpeg`` reads the inherited stdin, and ``q`` is its
      quit key (reproduced: a piped ``q\\n`` turned a valid ``.m4a`` into ``AudioDecodeError`` while
      an empty stdin decoded fine).  This flag **and** ``stdin=subprocess.DEVNULL`` below both
      address it, and either alone suffices — measured by removing each independently.  Both are
      kept on purpose: the flag is ffmpeg's own contract and holds however the child is spawned,
      the call-site argument is what a reader of this function sees, and only removing **both**
      brings the bug back (``test_the_ffmpeg_decode_survives_a_piped_quit_key`` fails then).
    * ``-rf64 auto`` — the RIFF/WAVE muxer cannot express a file over 4 GiB and, past that limit,
      ``ffmpeg`` **exits 0** while printing ``Filesize … invalid for wav, output file will be
      broken`` to the stderr this call discards.  Measured on a 11600 s 48 kHz stereo source: the
      WAV held 536 870 911 of 552 000 000 frames and ``soundfile`` read the truncated array without
      raising, so ~3.1 h of audio would vanish silently.  ``-rf64 auto`` writes RF64 only when a
      plain WAV would overflow, and libsndfile reads RF64.
    * ``-v error`` — keeps the child's chatter out of the parent's stderr on the success path.
    """

    ffmpeg = shutil.which("ffmpeg")
    if not ffmpeg:
        raise _dependency_errors.ASRDependencyError(
            "reading .m4a/AAC needs the `ffmpeg` binary and it is not on PATH; "
            "install it (e.g. `apt install ffmpeg`) and re-run"
        )

    handle, scratch = tempfile.mkstemp(prefix="bili-asr-decode-", suffix=".wav")
    os.close(handle)
    try:
        completed = subprocess.run(
            [
                ffmpeg,
                "-v", "error",
                "-nostdin",
                "-y",
                "-i", path,
                "-acodec", "pcm_f32le",
                "-rf64", "auto",
                scratch,
            ],
            stdin=subprocess.DEVNULL,
            stdout=subprocess.DEVNULL,
            stderr=subprocess.PIPE,
            check=False,
        )
        if completed.returncode != 0:
            detail = completed.stderr.decode("utf-8", "replace").strip().splitlines()
            reason = detail[-1] if detail else f"ffmpeg exited {completed.returncode}"
            # Only the LAST stderr line is reported, and that is load-bearing rather than incidental:
            # ffmpeg's middle line echoes the offending path verbatim ("Error opening input file
            # /tmp/…m4a."), measured for a missing file and for a non-audio file, while its final
            # line is path-free ("Error opening input files: No such file or directory").  The path
            # is deliberately kept out of this message because the product's own convention for an
            # unusable input is a description rather than a location (``audio.py`` says "invalid
            # audio path" and never quotes it), and the caller already knows which item it asked for.
            # So do not "improve" this by joining every line: that would leak the input path, and it
            # would leak ``scratch``'s path too.  Changing to ``detail[0]`` is safer than joining and
            # also more specific, since the first line names the cause; it is not done here because
            # the two cases measured would each need their own check first.
            raise _dependency_errors.AudioDecodeError(f"ffmpeg could not decode the audio input: {reason}")
        import soundfile as sf

        return sf.read(scratch, dtype="float32")
    finally:
        try:
            os.unlink(scratch)
        except OSError:
            pass


def _read_audio(path: str) -> tuple[Any, int]:
    """Read one audio file to ``(samples, rate)``, mono or ``(samples, channels)``.

    ``soundfile`` is the primary reader and libsndfile reads WAV, FLAC, OGG and MP3 — but not AAC,
    which is the codec inside the ``.m4a`` container this archive's own downloader writes for the
    preferred DASH audio stream.  A format the primary reader cannot open is therefore not a missing
    dependency: it is the documented input, so the reader has to be wide enough for it or the
    product cannot transcribe what it downloaded.

    The fallback is the **``ffmpeg`` binary**, not a Python package.  An earlier revision routed this
    through ``librosa.load`` on the belief that it reaches ``audioread`` and then ``ffmpeg``; that
    chain broke when ``librosa`` 1.0 dropped ``audioread`` and made ``load`` a bare ``soundfile``
    call, so the fallback silently re-raised the very error it existed to catch while every test
    still passed (residual ``iter-2026-09-qwen3-asr-closeout · R5``).  ``ffmpeg`` is pinned by the
    platform rather than by a version range, and the archive already requires it.

    The returned shape is the one ``soundfile.read`` returns, so the caller's channel collapse and
    resample stay the only place that shaping happens.
    """

    import numpy as np
    import soundfile as sf

    try:
        return sf.read(path, dtype="float32")
    except sf.LibsndfileError:
        samples, rate = _decode_with_ffmpeg(path)
        return np.asarray(samples, dtype=np.float32), int(rate)


def _split_audio(samples: Any, sample_rate: int, max_chunk_seconds: float) -> list[tuple[Any, float]]:
    """Cut a waveform into chunks near ``max_chunk_seconds``, at low-energy boundaries.

    Returns ``(chunk_samples, offset_seconds)`` pairs in order whose lengths **tile the input
    exactly**: no overlap, no gap, nothing dropped and nothing added.  Padding a degenerate chunk up
    to the aligner's minimum is the caller's business, not the splitter's, precisely so that promise
    stays checkable.
    """

    import numpy as np

    samples = np.asarray(samples, dtype=np.float32)
    if samples.ndim > 1:
        samples = samples.mean(-1).astype(np.float32)
    total = int(samples.shape[0])
    if total <= 0:
        return []
    if total / float(sample_rate) <= max_chunk_seconds:
        return [(samples, 0.0)]

    max_len = int(max_chunk_seconds * sample_rate)
    expand = int(_dependency_constants._CHUNK_SEARCH_EXPAND_S * sample_rate)
    window = max(4, int((_dependency_constants._CHUNK_MIN_WINDOW_MS / 1000.0) * sample_rate))

    chunks: list[tuple[Any, float]] = []
    start = 0
    offset = 0.0
    while (total - start) > max_len:
        cut = start + max_len
        # The boundary may only be searched where the window is centred AND clear of the current
        # start.  Otherwise the quietest point lands on the window's edge — measured: a 3.01 s
        # recording came back as 161 chunks of ~4 samples, and merely flooring the progress at one
        # window turned that into a run of 100 ms chunks.  When the window cannot be centred, the
        # cut itself is the only honest boundary.
        left = cut - expand
        right = min(total, cut + expand)
        if left <= start or right - left <= window:
            boundary = cut
        else:
            segment = np.abs(samples[left:right])
            windows = np.convolve(segment, np.ones(window, dtype=np.float32), mode="valid")
            quietest = int(np.argmin(windows))
            boundary = left + quietest + int(np.argmin(segment[quietest:quietest + window]))
            boundary = max(boundary, start + window)
        boundary = max(boundary, start + 1)
        boundary = min(boundary, total)
        chunks.append((samples[start:boundary], offset))
        offset += (boundary - start) / float(sample_rate)
        start = boundary
    chunks.append((samples[start:total], offset))
    return chunks
