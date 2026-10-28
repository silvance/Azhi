# Sotto

Sotto is an offline desktop application for transcribing recordings,
working out who spoke when, and comparing a voice against reference profiles.
It is built for investigative triage on air-gapped Windows and
Linux machines: nothing it does reaches the network, and a voice comparison is a
lead for an analyst to review - never an identification.

> **Using it rather than building it?** [`docs/user-guide.md`](docs/user-guide.md)
> is the guide for operators: what each page is for, in the order you would work
> in, and what the results do and do not mean. This README is the technical
> account of the same thing.

**What it runs on.** Transcription uses OpenAI's Whisper speech-recognition
models through [faster-whisper](https://github.com/SYSTRAN/faster-whisper)
(CTranslate2). Speaker separation uses NVIDIA's Nemotron 3 Diarization,
pyannote.audio or sherpa-onnx; translation uses Argos Translate,
and OCR Tesseract. Reports name the exact models a result came from. Licences:
[`LICENSE`](LICENSE) for Sotto, [`THIRD_PARTY_NOTICES.md`](THIRD_PARTY_NOTICES.md)
for everything it ships.

**Formerly Whispers** (and Whispr before that). An earlier version's saved
work carries over on first launch:

- **The settings folder** (`%APPDATA%\Whispers`, or `~/.config/whispers` or
  `~/.config/whispr`) is renamed, never copied. It holds the speaker profiles,
  comparison records and operation profiles.
- **Files under the old endings** are renamed in place (`.whispers-speaker.json`,
  `.whispers-comparison.json` and so on). Projects (`.whispers.json`) and
  exported profiles still open.
- **Old environment variables** (`WHISPERS_ASSETS`, `WHISPERS_MODE`,
  `WHISPERS_DEBUG`) still count; the `SOTTO_` names win.
- **An existing `whispers_assets` folder** in a source checkout is still found.

## The application

Sotto transcribes audio and video files (and translates text) without the
command line. It is built for CPU-only hosts: transcription runs through
[faster-whisper](https://github.com/SYSTRAN/faster-whisper) (CTranslate2) with
int8 quantization, which is fast and light on a CPU.

**Processing hardware** (under *Options*) is *Auto* by default: an NVIDIA GPU is
used when CTranslate2 can see one, and the CPU otherwise. CPU remains fully
supported — every feature works on it, and the choice affects only how long a
run takes, never the transcript. Asking for *NVIDIA GPU (CUDA)* on a machine
without one falls back to the CPU **and says so** rather than failing the run,
and a GPU that fails mid-load (VRAM, driver, a busy card) is retried on the CPU.
The detection is a local query to the bundled inference library — no driver
install, no download, no network. **System status** reports what this machine has.

Install the optional GUI extras and launch it:

```bash
pip install ".[gui]"
sotto            # or: python -m sotto
```

In the window, pick a recording, choose a model, pick the **task** — *transcribe*
(keep the source language) or *translate* (to English) — and a language (or leave
it on **Auto**), then click **Run**.

For English audio, the English-only `.en` models are fastest and usually as
accurate: start with `base.en` (the quickest; mirrors whisper.cpp's
`ggml-base.en`) and step up to `small.en` / `medium.en` if accuracy on harder
audio (e.g. strong accents) needs it. The plain multilingual names (`small`,
`large-v3`, …) are required for non-English audio or the *translate* task. You can
also browse to a local CTranslate2 model directory. The transcript streams into
the *Transcript* tab as it is produced, progress and detected-language details
appear in the *Status* tab, and you can optionally write `.txt` (and `.srt`
subtitle) output to a folder. Work runs on a background thread so the UI stays
responsive.

**Expected words.** Enter names, places, jargon or callsigns likely in the audio in
the **Expected words** box to prime the model toward that vocabulary (Whisper's
``initial_prompt``) — a cheap accuracy win on domain-specific recordings where
proper nouns are otherwise mangled.

**Noise reduction.** *Advanced options → Audio and output* offers **Reduce
steady background noise** where the build includes the model (a ~0.5 MB GTCRN
denoiser, run on CPU through the sherpa-onnx already present). It earns its
place on a bad line, hum, hiss, traffic, an engine or machinery.

It is **not** a voice separator, and it is worth being blunt about the case
people ask for. Measured against clean speech with noise mixed in at a known
level, it moved the speech-to-noise margin by +21.5 dB on mains hum at -5 dB
in, and +10.8 dB on broadband hiss at 0 dB in — but **-1.7 dB on crowd babble
at 0 dB in, and -5.0 dB at -5 dB**. Where the background is other people
talking it does nothing useful and can make the recording worse, because the
interference is itself speech and a model trained to keep speech has no basis
for preferring one voice over another. Those figures come from synthetic
mixtures, which is a proxy; the number to believe is the one from your own
recordings.

The recording is never altered. Cleaning works on a normalised copy and writes
another, named `<recording>.cleaned.wav` beside the output, and the run
transcribes that copy — recorded in the analysis provenance (`denoised`, plus
the model's SHA-256) so a transcript can always say which audio produced it.

Cleaned audio is kept out of **Speaker Profiles** and **Compare Speakers**:
noise reduction alters exactly the spectral detail a voiceprint measures, so a
profile built from original audio and a questioned sample that has been cleaned
are not measuring the same thing. Both pages recognise the `.cleaned.wav`
naming and say so rather than scoring it.

**Confidence highlighting.** Tick **Highlight low-confidence words** to colour the
parts the model was unsure about (per-word when available, otherwise per
segment), so an analyst can jump straight to what needs verifying on low-quality
audio.

**Re-listen to any line.** **Ctrl-click** a transcript line (or a single word) to
play just that span of the source audio — or use **▶ Play this line** in the
right-click menu and **⏹ Stop audio**. The segment is extracted on the fly with
the bundled ffmpeg and played with the OS's built-in audio, so it works offline.

**Save & reopen a project.** Transcription and the manual speaker fixes are real
work, so **Save project…** writes the result, your speaker names and corrections,
and the source path to a `.sotto.json` file; **Open project…** loads it back so
you can keep editing (and re-listening) in a later session.

**Batch.** Drop a whole folder onto the window — or use **Add a folder…** — and
every recording in it is queued, including the ones in its subfolders. **Add
several files…** and dropping several files do the same for a hand-picked set.
**Run** transcribes them in sequence; each file's output is written to the chosen
output folder, or beside the source when none is set, and each finished
transcript appears as it is done, so the last one is left open for review.

Output names are worked out for the whole batch before it starts, because
whether two recordings collide is a property of the batch rather than of either
file. A recording whose name is unique keeps it; where two would collide — a
case folder holding `2026-09-01/interview.wav` and `2026-09-02/interview.wav` —
each takes as much of its folder path as it needs to be distinct, and the
Status tab says so. Nothing in a run can overwrite another recording's output.

Transcribed and saved are reported separately. A destination that goes away
mid-run — an unplugged drive, a share that drops — is a failure of that
recording's output and not of the transcription, so the banner reads
"Transcribed 47 of 47 recordings and saved 46" rather than claiming a clean
finish over an empty folder.

What a folder actually holds is rarely only recordings, so the queue says what it
took and what it passed over: the notes and photographs it ignored, any subfolder
it could not read, and any WAV that looks like the converted copy a previous run
made of a video of the same name (which would otherwise transcribe the same hour
twice). Anything left out by that guess can be added back by choosing the file
directly.

A batch carries on past a recording it cannot transcribe. A folder left running
unattended must not be lost to one unreadable file at position three, so the
failure is recorded, the run continues, and the banner at the end says how many
succeeded and what happened to the rest — with the detail in the Status tab. When
a whole folder fails for one reason (a model that is not in the build, say), it
is reported once rather than fifty times.

**Remembered settings.** The Transcribe tab's choices (model, language, output
folder, diarization and the other options) are saved on exit and restored next
launch, so you don't re-set them each time. Stored in a small per-user JSON file
(`%APPDATA%\Sotto\settings.json` on Windows).

**Find.** Use the **Find** box under the transcript to jump through matches
(Enter = next, Shift+Enter = previous); every hit is highlighted and the current
one is centred.

**Analyst notes.** Right-click a line › **Add a note…** pins a note to the
moment the line starts (`TranscriptionResult.notes`), so it stays with what it
was about when lines are split or joined. Notes are shown under their lines,
saved in the project (schema 4), and written out labelled "Analyst note" in
text, Word, the spreadsheet's own column and the analysis report, unless the
option to include them is off.

**Watch list.** **Watch › Edit list…** keeps names, places and other terms (one
per line) that are highlighted in every transcript as it is shown, and in the
live transcript; the hits are counted and **Next hit** steps through them.
Whole words, any case, phrases with any spacing; speaker tags are not searched
(`sotto/watchlist.py`). The list is saved with the settings and in operation
profiles.

When **Convert video to audio first (ffmpeg)** is enabled (the default), choosing a
video file (`.mp4`, `.mkv`, `.mov`, `.avi`, `.webm`) extracts its audio to a 16 kHz
mono WAV with [`ffmpeg`](https://ffmpeg.org/) before transcribing. If an output
folder is set the WAV is kept there; otherwise it is written to a temporary file
and removed afterwards. This step requires `ffmpeg` to be installed and on `PATH`.

### Speaker identification (diarization)

Enable **Identify who is speaking** to label who spoke when. Each transcript
line (and `.srt` cue) is prefixed with a speaker tag, e.g. `[SPEAKER_00]`. **How many people are speaking?** then has to be answered before a run will
start — a specific count, or *Not sure — work it out*. A count is the most
reliable control there is, and answering it is what stops a two-person call
coming back as five speakers. Giving one also reveals optional **Speaker N**
name fields, so the transcript comes out labelled with real names instead of
`SPEAKER_00`/`SPEAKER_01`.

If a split does come out wrong, **Redo speaker separation…** under the
transcript re-splits the existing words with a different count, without
transcribing the recording again. Speakers are renumbered, so typed names have
to be put back.

In auto mode, **Grouping sensitivity** tunes clustering: higher merges more
(fewer speakers), lower splits more (more speakers); it has no effect when a
count is set or when using pyannote.

**Correcting speakers.** Diarization on hard or overlapping audio is never perfect,
so the transcript is editable: click any `[speaker]` tag to **rename that speaker
everywhere** (bulk) or **move just that line to a different speaker** (individual);
click a single **word** to move just that word (or from it onward); or **highlight
a run of words and drag them onto another speaker's line** to move just that span —
for when one speaker's sentence is lumped into the middle of another's line
(right-click still offers the same move as a menu). The labelling a diarizer
assigns is arbitrary, so if two names land on the wrong voices it's a one-click
swap.

**Backends.** Three are supported, chosen with the **Method** dropdown under
*Advanced options* → *Speaker separation* (default **Auto**):

- **pyannote.audio** (`speaker-diarization-3.1`, PyTorch) — much better on hard /
  low-quality / overlapping audio. Loads from a bundled offline model cache at
  `sotto_assets/pyannote` (no network or token needed at runtime; see below).
- **sherpa-onnx** (ONNX / CPU, no PyTorch) — lighter and faster, with no PyTorch
  to load; a good choice for clean audio. Needs a segmentation model and a speaker
  embedding model at `sotto_assets/diarization/segmentation.onnx` and
  `.../embedding.onnx` (embedding is NeMo TitaNet-large, English).

- **Nemotron** (the default; NVIDIA Nemotron 3 Diarization through the
  [NeMo-Speech.cpp](https://github.com/NVIDIA/NeMo-Speech.cpp) CPU runtime) — one
  model that decides every 10 ms which of up to eight people is speaking,
  overlapping speech included, instead of cutting, measuring and grouping. Built
  for exactly the case the other two find hardest: short turns in quick
  succession. In bundles built with `nemotron=yes` (the default), where Auto
  picks it for up to eight speakers. Turns are built from the model's own per-10 ms speaker
  probabilities — each moment goes to the most likely speaker — rather than from
  the runtime's turns, which are widened, bridged across short gaps and drop
  anything under half a second, and so lost one-word replies. With a speaker
  count given, the voices heard longest are kept and each moment of any other
  goes to whichever of them is more likely; it cannot split a voice it heard as
  one, and says so. The model is licensed **OpenMDW-1.1** (the runtime is
  Apache-2.0), which is permissive: a copy must keep the agreement and NVIDIA's
  notices, and the build puts both beside the model (see
  [THIRD_PARTY_NOTICES.md](THIRD_PARTY_NOTICES.md)). NVIDIA's published results (DIHARD III 12.7% DER against 21.4%
  for pyannote 3.1) are its own, on its own benchmarks; in this office's use it
  has also been faster than sherpa and more accurate than pyannote. The
  [test set](docs/test-set.md) measures it on your own recordings.

**Auto** uses Nemotron where the bundle has it (and the speaker count is eight
or fewer), then pyannote when it's installed/bundled, then sherpa; pick a specific engine to force it (e.g. sherpa for a quick pass on clean
audio). A `both` bundle (see below) ships both so you can switch per recording.
**Grouping sensitivity** applies to sherpa only.

The audio is normalised to 16 kHz mono with ffmpeg first. Speaker labels are
assigned **per word** (using Whisper word timestamps): each word goes to the
speaker heard alone for most of it, so a single transcript segment that spans a
speaker change is split at the boundary. A smoothing pass then absorbs stray
sub-second fragments where a word has landed on a sliver of someone else's turn —
but leaves a short reply alone when the diarizer itself heard that person over
most of it, so a quick "Yes." is not handed back to whoever asked the question.
Finally, a new speaker's first word or two that landed just before the change
(the transcription's timing swallows the pause, the diarizer hears the new voice
a moment late) goes with the rest of the sentence it begins — "…for me? **Who**
else would you answer for?" — when it carries the previous sentence's speaker.

### Profiles that learn speaker voices

Recurring operations tend to feature the same people. A **profile** (the
**Profile (learn speakers)** section) saves the settings for one operation —
model, engine, expected speaker count, custom words — and, more usefully, builds
a roster of **voiceprints** for the people in it so their voices are recognised
automatically next time.

- **Pick a profile** per operation, or create one with **New…**. Its saved
  settings are applied on selection; **Save** updates them from the current
  fields. The choice is remembered between launches.
- **It learns from your corrections.** With **Recognise & learn speaker voices**
  ticked and diarization on, every fix you make that assigns audio to a *named*
  speaker — renaming a speaker, or moving a line/word/selection to one — embeds
  that audio and folds it into that person's voiceprint. Nothing extra to click;
  correcting the transcript *is* the training.
- **Next run, voices are recognised — one turn at a time.** Each diarized turn is
  judged **on its own audio**: it is labelled with a known person only when its
  own embedding clears the acceptance threshold *and* beats the runner-up by the
  required margin. A turn that is too short to embed, matches nothing, or is
  ambiguous keeps its `SPEAKER_xx` label. An identity is deliberately **not**
  propagated across a diarization cluster — sharing a cluster with a matched turn
  is evidence about clustering, not about who is speaking — so a name never lands
  on audio that was never matched to that person.
- **A correction is a proposal, not a promotion.** If a known-subject profile
  exists with that name (see *Speaker profiles* below), the corrected audio is
  added to it as a **pending, unapproved** sample for review. It does not move
  the subject's reference centroid until an analyst approves it, so a mistaken
  correction cannot quietly contaminate a known actor's reference material.

Voiceprints reuse the bundled speaker-embedding model (the same one the sherpa
diarizer uses), so recognition works offline and adds no new dependency; if that
model isn't bundled the feature quietly disables itself. Profiles are small JSON
files stored beside the app settings. One honest limit: voiceprints only sharpen
*who-said-what* labelling — they do **not** retrain the transcription model, so
they don't change the words Whisper decodes. For word accuracy, use a larger model
than `base.en` (try `small.en`/`medium.en`) and the **Expected words** box.

### Speaker profiles and Speaker Compare

Two dedicated tabs appear when the build bundles a speaker-embedding model. They
are separate from the operation profiles above: those are a disposable
who-said-what aid, while these hold the **reference voices of known subjects**.

**Speaker profiles** builds a subject's reference material from historical
recordings — no transcript correction required:

- **Add historical recording…** takes a whole file, a chosen speaker from a
  diarized file, or explicit time ranges (`0:10-0:45, 1:20-2:00`).
- Audio is enrolled as **multiple embeddings** (8-second windows), not a single
  averaged vector, and each sample records where it came from: source filename,
  source SHA-256, start/end, usable speech duration, quality metrics and notes.
- Samples are either **reference** (trusted, from deliberate enrolment) or
  **learned** (proposed automatically, pending approval). Only trusted samples
  form the centroid a comparison runs against; pending samples are listed with
  **Approve** / **Remove**, and one that sits far from the current reference is
  flagged as a probable mis-correction.
- The panel shows sample counts, usable speech duration, source files, and the
  embedding model with its SHA-256 and vector dimension.

**Speaker Compare** is the 1:1 workflow: pick a reference profile, pick a
questioned recording (whole file, a diarized speaker, or time ranges), and
compare. The result gives the raw similarity score out of 1.00, the qualitative
band, the threshold and margin in force, the speech duration and quality on each
side, the model-compatibility verdict and the disclaimer — laid out to be
screenshotted or exported as a report. **Search all subjects** ranks the
questioned speaker against every stored profile, but ranking is not
identification: the same acceptance-and-margin rule applies, and when nothing
clears it the answer is *No known profile produced a sufficiently strong match.*
On audio too poor or too short to assess, the ranking is still shown but the
search draws no conclusion from it at all.

**How the questioned speaker is measured.** The selection is unioned first, so
ranges that overlap, repeat or run straight on are read once and cannot be
counted twice. Where it is several turns — the usual shape of a surreptitious
recording, where the target speaks in bursts between other people — those turns
are joined into one speaker-only stretch before being split into windows. Every
usable window is embedded and the embeddings averaged, exactly as a reference
profile's centroid is built. This matters operationally: a target with 15
seconds of speech across seven turns, none longer than three seconds, is
measurable together and would be measurable in no other way. **Only the
selected speaker's audio is joined**, the joins are never presented as
continuous speech, and every window is reported back in the source recording's
own timeline. The duration on the result is the speech behind the embedding —
never the duration of a selection that was only partly usable.

**Sharing and comparing speakers.** A profile can be moved between machines with
**Export…** / **Import…** (the whole profile — settings and learned voices — as one
`*.sotto-profile.json`; import warns before overwriting a same-named profile).

Comparing one voice with another is done on the **Compare Speakers** page, against
a subject built on **Speaker Profiles**, and nowhere else. It reports a
**similarity score out of 1.00** with a qualitative band — **High similarity /
Intermediate similarity / Low similarity / Insufficient data** — alongside the
operational threshold, the speech duration on each side and the quality of each,
and it refuses a comparison across different voice models.

An earlier **Compare voices…** button on the operation-profile card compared two
exported voiceprint files directly. It was removed: a voiceprint file records
neither how much speech built it nor which model measured it, so that dialog could
apply neither the minimum-speech rule nor the model check, scored prints of
different models as "Low similarity" instead of refusing, and called two
single-sample prints "High similarity". Its results were also never logged to
Comparison History. **Export speaker…**, which only produced those files, went
with it.

The score is **not** a percentage and **not** a probability: a cosine similarity of
0.78 does not mean "78% the same person". Sotto deliberately never reports a
percentage, a confidence of identity or a likelihood of identity.

> Speaker similarity results produced by Sotto are investigative indicators
> intended to support lead development and analyst review. They are not forensic
> speaker identification, are not a biometric probability of identity, and should
> not be treated as proof that two recordings contain the same person.

A high-similarity result never becomes "this is John Doe" — it means *the questioned
speaker produced high similarity to the John Doe reference profile, and further
review is warranted*. Both voiceprints must come from builds using the same
speaker-embedding model; Sotto refuses the comparison outright when the model
hash or vector dimension differs, and asks for explicit confirmation when an older
profile cannot prove which model produced it.

### Validating speaker comparison (developer/analyst tool)

The unit tests exercise software behaviour on synthetic vectors. They say nothing
about whether the system can tell two people apart — that needs real recordings of
known speakers. `sotto.validation` is the offline harness for measuring it:

```bash
python -m sotto.validation /path/to/corpus --out validation-results
```

The corpus is either a directory of per-speaker folders
(`corpus/SPEAKER_A/call1.wav`) or a JSON/CSV manifest with `speaker_id`, `path`
and an optional `condition` (channel, microphone, environment) so results can be
grouped. It embeds each recording with the bundled model, builds **genuine**
(same speaker, different recordings) and **impostor** (different speakers)
comparisons, and writes:

- `validation.json` — score distributions, error rates by threshold, equal error
  rate, and results grouped by how much speech was available
- `trials.csv` — every raw trial score, for re-analysis
- `roc.csv` — ROC data (false-accept vs genuine-accept)
- `validation.png` — plots, if matplotlib is installed (never a bundle dependency)

**The operational thresholds in `sotto/thresholds.py` are conservative defaults,
not calibrated values.** They should be replaced with figures measured on
recordings representative of the intended deployment — language, channel,
microphone, noise and speech duration all move these numbers substantially. Until
that has been done, treat similarity results as directional only.

### Measuring who-said-what (quick-exchange test set)

Speaker labels are weakest in quick exchanges — one-word replies, interruptions,
overlapping speech — and how weak depends on the deployment's own audio.
`sotto.diarization_eval` scores the transcript against recordings an analyst
has labelled by ear (Audacity label exports or RTTM), offline:

```bash
Sotto --score-test-set /path/to/testset --out results     # shipped copy
python -m sotto.diarization_eval /path/to/testset --out results
```

It reports, per recording and pooled: the share of words shown against the
right person, how many sub-second reference turns kept their speaker, and the
diarization error rate (no edge collar, overlap scored). Transcription and
separation are cached in the output folder (text and timings, never audio), so
`--rescore` re-measures a change to word assignment in seconds.
[`docs/test-set.md`](docs/test-set.md) is the guide for building and labelling a
test set.

### Live transcription (a stream or a microphone)

The **Live** tab transcribes an incoming stream in near-real-time — e.g. a GoPro
pushing **RTMP** to this PC during a training session — or a microphone plugged
into this PC. It appears whenever ffmpeg is available (always, in a bundle).

It is *chunked* near-live, not true streaming: ffmpeg reads the stream and splits
its audio into short fixed-length segments, and each finished segment is
transcribed and appended. End-to-end lag is roughly **one chunk length + the
model's inference time**, so use a **small model** (`base.en` / `small.en`) to
keep up on CPU — a big model will fall behind.

- **Stream URL** — anything ffmpeg can read: an `rtmp://` / `udp://` / `http://`
  URL, or a file. For a GoPro, point it at your local RTMP server
  (e.g. `rtmp://localhost/live/stream`). Tick **Wait for an incoming connection**
  only if this PC itself should listen for the stream (ffmpeg `-listen`).
- **Chunk length** — shorter feels more live but is choppier at the boundaries;
  longer is smoother but lags more. 8 seconds is a good start.
- **Save to file** — appends the transcript to a `.txt` as it comes in, so a
  session is captured even if the app is closed.
- **Test connection** — a quick few-second probe that confirms the stream is
  reachable (and audio is flowing) before you start a session; handy while
  setting up.
- **Start** / **Stop** control capture. Cancel on another page does not stop
  it: each page's Cancel stops only that page's work.

**A microphone on this PC** (Windows through DirectShow, Linux through ALSA,
both in the ffmpeg a bundle already ships; no other library) is the other
source. **Refresh** lists what is plugged in. Its audio exists nowhere else, so
the whole of it is always kept: ffmpeg writes it, at the device's own rate and
channels, to a WAV in **Keep recordings in** (`Documents\Sotto recordings`
by default), beside the live chunks it transcribes. On **Stop**, a record is
written next to it (`<recording>.wav.capture.json`): the device, start and stop
times, the transcription model, the file's size and SHA-256, and the rate,
channels and length read back from the file. A red line on the page names the
device and the time for as long as it records. A microphone that sends nothing
but exact zeros for ten seconds (muted, or blocked by Windows' privacy
settings) is reported in the status line; the recording carries on. Nothing is
sent anywhere, and no network is used. For a careful transcript, open the kept
recording on the Transcribe page afterwards.

Accuracy on a live feed is bounded by the audio: room noise, distance from the
mic and overlapping speech all hurt more than on a clean recording. For a room,
a mic close to the speaker beats the camera's on-board mic.

The transcription backend is also usable directly from Python:

```python
from sotto import transcribe_audio

result = transcribe_audio(
    "recording.mp3", model_size="base", task="transcribe", language=None
)
print(result.text)
```

### Translating text, images and PDFs

When translation packs are bundled (or `argostranslate` is installed), a
**Translate** tab appears for turning foreign text into English, fully offline.
Pick the source language under **From** — or **Auto-detect language**, which
identifies it for you (via `langdetect`) — then either paste text and click
**Translate**, or add files under **Translate files (batch)** to write a
`<name>.en.<ext>` beside each original.

**Images and PDFs (OCR).** With OCR bundled, the batch picker also accepts images
(`.png`, `.jpg`, …) and PDFs: each is read with [Tesseract](https://github.com/tesseract-ocr/tesseract)
(digital PDFs use their embedded text; scans are rendered and OCR'd), the
extracted text is saved as `<name>.ocr.txt`, and its translation as
`<name>.en.txt`. For a single file, **Extract from image/PDF…** drops the text
into the paste box so you can fix OCR errors before translating. OCR needs a
specific **From** language (so Tesseract knows the script), so it isn't available
under Auto-detect.

**Export & drag-and-drop.** Transcripts and translations can be copied to the
clipboard or saved as Word (`.docx`); when `tkinterdnd2` is present you can also
drag a file straight onto the window (audio onto the transcript pane, an
image/PDF/text file onto the Translate tab).

## Offline / air-gapped deployment (sneakernet)

For machines with no internet access, the GUI can be shipped as a **self-contained
bundle** for Windows and Linux that includes the Python runtime, all dependencies,
an `ffmpeg` binary, and one or more pre-downloaded Whisper models. Nothing is
fetched at runtime.

**Build the bundles** with the `release-bundles` GitHub Actions workflow
(Actions → *release-bundles* → *Run workflow*, or push a `bundle-v*` tag). It
builds on hosted Windows and Linux runners and uploads `sotto-windows-x86_64` and
`sotto-linux-x86_64` artifacts. The build runners use the internet; the target
machines never do. You choose which models to bundle via the **`models`** input —
a comma-separated list such as `base.en,small,medium.en,large-v3`. **Only the
models you list here are in the build**; the app's Model dropdown still shows every
size, but a size that wasn't bundled can't be fetched on an air-gapped machine (the
box shows a "⚠ not in this build" note, and Run reports it clearly). On a manual
*Run workflow* the field is pre-filled with `base.en` — change it if you want more.
You also choose which **diarizer** to include: `both` (default — pyannote + sherpa,
switchable at runtime via the Engine dropdown), `pyannote`, or `sherpa`.

The **`embedding`** input picks the **speaker-embedding model** used for speaker
profiles and the *Speaker Compare* tool (and for sherpa diarization). It is
bundled on **every** build regardless of the diarizer choice, so speaker profiles
work even in a `pyannote`-only bundle. Each option is described by the file that
is actually downloaded, not by a broad label:

| Alias | Model | Trained on |
| --- | --- | --- |
| `titanet-large` (default) | NeMo TitaNet Large | English speaker-verification corpora |
| `titanet-small` | NeMo TitaNet Small | English speaker-verification corpora |
| `wespeaker-en` | WeSpeaker ResNet34 | VoxCeleb (predominantly English interview speech) |
| `campplus` | CAM++ (3D-Speaker) | Mandarin (zh-cn) 16 kHz common-domain data |
| `eres2net` | ERes2Net (3D-Speaker) | Mandarin (zh-cn) 16 kHz common-domain data |

The CAM++ and ERes2Net checkpoints published by sherpa-onnx are the 3D-Speaker
*zh-cn 16k-common* files — Mandarin-trained, not general multilingual models — so
pick them on that basis rather than as a catch-all for non-English audio. A direct
`.onnx` URL (any sherpa-onnx speaker-embedding model) also works; nothing is
recorded about such a file beyond its name, source and SHA-256.

**Verification performance varies substantially** with language, channel,
microphone, background noise, how much usable speech there is, and any mismatch
between the reference and questioned recordings. None of these models is
validated for a particular operational setting — measure yours with the
validation harness (below) before relying on a threshold.

**System status** shows which embedding model a build carries, what it was trained
on and its SHA-256; speaker profiles and comparisons are only valid between
builds that share that exact model.

**Getting a large bundle (bypassing the 2 GB release cap).** Every run already
uploads the full per-OS bundle as an **Actions artifact** (`dist/Sotto`), and
artifacts are **not** subject to the 2 GB per-file limit that Release assets are —
so to ship `medium.en`/`large-v3` and the full translation/OCR stacks, just *Run
workflow* with your chosen `models` and **leave `release_tag` empty**. Download the
`sotto-linux-x86_64` / `sotto-windows-x86_64` artifact from the run's **Summary**
page, and copy it to the air-gapped machine. The artifact downloads as a single
`.zip`; unzip it once to get the runnable `Sotto` bundle folder. Two caveats vs. a
Release: only someone signed in with repo access can download an artifact, and it's
retained for 14 days by default (raise `retention-days` in the workflow if you need
longer). The **`translate_langs`** input controls which offline text-translation
packs (each `<code>→en`) are bundled for the Translate tab (default
`ar,ru,zh,fa,uk,he,ko`; empty to skip translation). Packs and their sentence
splitter are baked in, so translation also runs with no network. The
**`ocr_langs`** input bundles Tesseract OCR language data (and the Tesseract
binary) for translating images/PDFs (default `ar,ru,zh,fa,uk,he,ko`; empty to
skip OCR), so OCR also runs air-gapped.

**Publishing a downloadable release.** To put a build on the repo's **Releases**
page (a permanent, public download — unlike the temporary, login-only Actions
*artifacts*), give the **`release_tag`** input a version (e.g. `v1.0.0`) when you
*Run workflow*, or push a `bundle-v*` tag. The per-OS bundle is archived
(`sotto-windows-x86_64.zip`, `sotto-linux-x86_64.tar.gz`) and attached to a
GitHub Release at that tag; visitors then download it, unzip, and run
`Sotto` / `Sotto.exe` — no install or network. **Mind the size:** a release
asset is capped at ~2 GB, so a public release should be a lean build (e.g.
`models=base.en`, `diarizer=sherpa`, empty `translate_langs`/`ocr_langs`) — the
full multi-GB bundle won't upload as a single asset. (Re-running the same tag
re-uploads/overwrites that OS's asset.)

**Lean transcriber-only build.** A full bundle (all models + translation packs)
is large. For users who only transcribe English, build a much smaller bundle by
setting **`models=base.en`**, **`translate_langs=`** and **`ocr_langs=`** (both
empty): this drops the multi-GB models and the ~1 GB Argos/translation and OCR
stacks while keeping full transcription and diarization. The GUI detects that no translation engine is
present and **hides the Translate tab**, so the app opens as a clean,
single-purpose transcriber. (Even on a full bundle, set the `SOTTO_MODE=transcribe`
environment variable to force the transcriber-only view — e.g. on a locked-down
shortcut.)

**Verify a bundle before handing it out.** The **System status** button (top-right of
the window) leads with **READY** or **NOT READY** (naming anything missing), then
reports the build identity, the offline posture, exactly which engines, models and
assets the build contains — transcription, both diarizers, translation packs, OCR
(Tesseract + tessdata languages), ffmpeg, and the export/detect/playback add-ons —
the speaker-embedding model and its SHA-256, the decision thresholds in force, and
the processing hardware. Run it before copying a bundle to an air-gapped machine.

**Auditable, and pinned.** Two files do two different jobs.

`packaging/build_manifest.py` writes `sotto_assets/build_manifest.json` with the
build id, git commit, timestamp, platform, resolved dependency versions and a
SHA-256 for every bundled model, so a result can always be traced back to the
exact bundle that produced it — and two bundles can be compared file by file.
That is **auditing**: what a build *was*.

`packaging/lockfile.txt` and `packaging/assets.lock.json` decide what a build is
**allowed to be**. The first pins every dependency whose version can change how
the application behaves; the second pins the Hugging Face revision of every
bundled model and the SHA-256 of every plain-URL download. `packaging/check_lock.py`
runs in the release workflow after the installs and fails the build on any drift,
and `packaging/fetch_assets.py` refuses weights that do not match the lock. The
point is not to have the newest versions — it is that the bundle your operators
tested and a rebuild of the same commit six months later are the same software.

To change a version deliberately, on a branch:

```bash
python packaging/check_lock.py --write   # re-pin to what is installed
```

read the diff, build a bundle, test it, then merge.

**Keeping it complete.** The lock covers the whole installed set — 144 packages,
including `pyannote.audio`'s own tree (lightning, torchmetrics, speechbrain and
the rest), which can only be resolved by a real build. Every release run records
what it actually installed and uploads it as `pip-freeze.txt` beside the asset
lock, so the lock can be brought back in step from the run that produced the
bundle you tested:

```bash
python packaging/check_lock.py --write --from-freeze pip-freeze.txt --add-all
```

Read the diff — it prints what it added and what it moved — then merge.
`pip-freeze.txt` itself is not committed; it is only the source the pins come
from. For the model weights, delete
the entry you want to move (or the whole `assets.lock.json`), run a build, and
commit the lock it uploads as `<artifact>-assets-lock`. An update nobody chose is
what this prevents; an update somebody chose is one commit.

Freezing the bundle you tested and recording its SHA-256 is still worth doing —
`Sotto --verify` checks a copy against `bundle-inventory.json` — but it is no
longer the only defence against a rebuild drifting.

Bundling **pyannote** (i.e. `both` or `pyannote`) uses gated Hugging Face models,
so the build needs a token. Add a repository secret named **`HF_TOKEN`** (Settings
→ Secrets and variables → Actions) holding a Hugging Face token whose account has
accepted the licenses for `pyannote/speaker-diarization-3.1`,
`pyannote/segmentation-3.0`, and `pyannote/wespeaker-voxceleb-resnet34-LM`. The
models are downloaded at build time and baked into the bundle's offline cache; the
deployed app needs neither the token nor network access.

That cache is not just the weights. Each repository also needs `refs/main`, the
one-line file saying which commit `main` is, because `main` is the only thing
pyannote asks for and offline there is nothing else to answer with. Pinning the
revisions removes it — a download pinned to a commit has no name to record — so
`fetch_assets.py pyannote` writes it back and then refuses to finish if any
bundled repository cannot be read offline. The app checks the same thing on the
way in, repairs it where the commit on disk is unambiguous, and otherwise says
so plainly instead of reaching for the network. Choose the `sherpa`
diarizer for a smaller, token-free build (no PyTorch).

To build locally instead on a connected machine of each OS:

```bash
# sherpa-onnx diarizer (smaller, no token)
pip install "sotto[gui,bundle]"
python packaging/fetch_assets.py ffmpeg
python packaging/fetch_assets.py models small,medium,large-v3
python packaging/fetch_assets.py diarization
pyinstaller --noconfirm packaging/sotto.spec      # output in dist/Sotto/

# pyannote diarizer (best quality; adds CPU PyTorch, needs a token)
pip install torch torchaudio --index-url https://download.pytorch.org/whl/cpu
pip install "sotto[gui,bundle,pyannote]"
python packaging/fetch_assets.py ffmpeg
python packaging/fetch_assets.py models small,medium,large-v3
HF_TOKEN=hf_... python packaging/fetch_assets.py pyannote
pyinstaller --noconfirm packaging/sotto.spec      # output in dist/Sotto/
```

**Deploy:** download/copy the bundle folder onto a USB drive, copy it to the
air-gapped PC, and run the `Sotto` executable inside (`Sotto.exe` on Windows; on
Linux you may need `chmod +x Sotto`). The bundled models appear at the top of the
**Model** dropdown and are used without any download; the bundled `ffmpeg` is found
automatically. (Set the `SOTTO_ASSETS` environment variable to point at a
`sotto_assets/` directory if you keep models/ffmpeg outside the bundle.)

## Licence

Sotto is released under the MIT licence - see [`LICENSE`](LICENSE). The
models and libraries it runs on keep their own licences; see
[`THIRD_PARTY_NOTICES.md`](THIRD_PARTY_NOTICES.md), and a bundle's `licenses/`
folder for every Python package it contains.
