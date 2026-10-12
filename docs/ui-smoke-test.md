# Whispers UI smoke test

Automated checks cannot prove a graphical interface is right. `pytest`, `ruff`
and `mypy` say the code is sound; only a person at the window can say whether
the screen explains itself. This is the list to work through before a build
goes out, and after any change to `whispr/gui/`.

Run it on the deployment machine if you can — Windows scaling and the platform
font change spacing, and that is exactly what this list is for.

## Before anything else: is this copy intact?

Do this first, on the machine that will actually run it, and before reading any
traceback. A bundle damaged in transit fails at whichever file it reaches first,
which can be a different file on each run.

- [ ] From a terminal in the extracted folder, `whispr --verify`
      (`whispr.exe --verify` on Windows) reports that the copy matches the build
      and exits 0.
- [ ] If it names missing, altered or unreadable files, the copy is the problem
      and not the software. Extract the archive again with 7-Zip rather than
      Windows Explorer, which is unreliable on archives of several GB; copy the
      extracted folder to a local disk rather than running it from removable
      media; and check whether a scanner has quarantined anything.
- [ ] If it reports that there is no inventory to check against, the bundle
      predates this check - rebuild before deploying.
- [ ] `whispr --self-test` then prints the report and exits 0, naming the build
      ID and commit and listing the models actually bundled.
- [ ] In that report, **Diarization: pyannote model cache** reads
      `bundled and readable` - not merely `bundled`. A cache can hold every
      weight and still be unreadable offline, in which case the first
      transcription with speaker separation fails at the point of loading the
      pipeline. If it reads `bundled but unreadable offline`, the line names
      what is wrong; the build has to be redone, and nothing on the deployment
      machine will fix it.

## Startup

- [ ] The window opens at a sensible size and can be resized down to its
      minimum (940×600) without controls being clipped or overlapping.
- [ ] The header shows **Whispers**, "Offline audio analysis", the green
      **Local processing** marker, **Help** and **System status**.
- [ ] The navigation rail lists only the pages this build supports. On a
      transcribe-only build (or `WHISPR_MODE=transcribe`) the rail is absent
      and the Transcribe page fills the window.
- [ ] Nothing renders as a pale box on the dark ground — text areas,
      scrollbars, tables and dialogs all take the application's own colours.

## Navigation

- [ ] Each rail entry raises its page; the current page is the highlighted one.
- [ ] Switching pages and returning preserves what was on the first page
      (chosen file, transcript, comparison result).

## Transcribe

- [ ] **Empty:** the page title and sentence are visible, the Recording box
      invites a drop, and the transcript area says what to do next.
- [ ] **Choose file** opens the picker; the chosen recording shows its name and
      size, with the folder as quiet metadata, and a **Change file** action.
- [ ] **Drag and drop** a recording onto the Recording box, the transcript pane
      and the Status pane — each loads the file.
- [ ] The **Quality** dropdown reads "Fast — base.en" and similar; picking one
      keeps the availability note underneath correct.
- [ ] **Advanced options** opens and closes, and contains hardware, silence
      skipping, the speaker method, sensitivity, expected words, conversion,
      subtitles, formatting and the operation profile. The number of speakers is
      *not* in there — a line in Speaker separation says where it went.
- [ ] **Running:** the primary button is disabled, Cancel is enabled, the
      progress bar moves, and the line beneath it names the current step in
      words. The settings put themselves away.
- [ ] **Complete:** a green banner says so, the transcript has the page, and
      the line above it names the recording, language, duration and speakers.
- [ ] **Cancelled** and **failed** runs both say so where the eye already is,
      and a failure names the friendly reason and points at the Status tab. No
      traceback appears outside the Status tab.
- [ ] **No file chosen:** selecting Transcribe recording says so rather than
      failing silently.
- [ ] Find, Copy transcript, Save as Word…, Analysis report…, Save project…,
      Open project… all still work, and clicking a speaker tag or dragging a
      run of words still reassigns speech.
- [ ] A batch of several files still runs, and the queue summary appears with a
      **Clear list** action only when there is a queue.

### A folder of recordings

- [ ] Drop a folder onto the window. Every recording in it is queued, including
      those in its subfolders, and the summary says how many and from how many
      folders.
- [ ] **Add a folder…** does the same through a folder picker.
- [ ] The summary accounts for what it left out: notes, photographs and other
      non-media files as "ignored", and a subfolder it could not read.
- [ ] A folder with no recordings in it says so plainly rather than appearing to
      do nothing.
- [ ] Put a video and a WAV of the same name in one folder (which is what a
      previous run leaves behind when *Convert video to WAV* is on). Only the
      video is queued; the summary and the Status tab both say the WAV was left
      out, and choosing that WAV directly still queues it.
- [ ] Nothing counts twice: drop a folder, then drop one of the files inside it.
- [ ] Run a folder of three or four short recordings end to end. The progress
      line reads "2 of 4 — <name>", each transcript appears as it finishes, and
      every file's output is written.
- [ ] **A recording that cannot be transcribed:** put a file with a media
      extension but rubbish content (rename a .txt to .wav) in the middle of a
      folder and run it. The run does **not** stop there — the others are still
      transcribed — and the end-of-run banner is amber, says how many of how
      many succeeded, names the one that failed and why, and the Status tab
      comes to the front with the detail.
- [ ] With a single file (not a batch), a failure still stops and reports as it
      always did.
- [ ] **Skip silence** (Advanced options > Audio and output) carries a note
      saying it can still cut very quiet speech and can be turned off.
- [ ] On a recording with long gaps, the line above the transcript says what
      share of it was listened to; on a clean recording it says nothing.
- [ ] When silence skipping passes over most of a recording, the banner left at
      the end of the run is amber, names the recording, says how many minutes
      went unheard and how to turn it off — and the same line is in the Status
      tab. It is *not* replaced a moment later by a green "complete" banner:
      there is only ever one banner, and it carries both.
- [ ] In a **batch**, a recording that lost most of its audio is reported even
      when it is not the one on screen: run a gutted file first and a clean one
      last, and the end-of-run banner still names the first. Several affected
      files are listed together.
- [ ] The completion caveat is repeated **inside the Transcript card**, in
      amber, above the tabs — so it is still visible when the transcript is in
      its own window. It clears on the next run and on Open project.
- [ ] **A recording that is not there:** queue a file, delete or move it, then
      run. The banner is amber and says nothing was transcribed and which file
      was not found — never a green "Transcription complete." In a batch of
      five with one missing, it reads "Transcribed 4 of 5" and names the fifth.
- [ ] Turning **Skip silence** off transcribes the whole recording and the
      "% listened to" note disappears.

### Reducing background noise

Only present when the build bundles the model; **System status** says which.

- [ ] *Advanced options → Audio and output* shows **Reduce steady background
      noise**, off by default, with text saying what it is for *and* that it
      does not separate conversations and can make a crowded recording worse.
- [ ] On a build without the model the option is absent entirely — not greyed
      out, not failing when pressed.
- [ ] Run a recording with it on and an output folder set. A
      `<recording>.cleaned.wav` appears beside the transcript, the original is
      untouched, and the Status tab says how much was removed.
- [ ] The status line does **not** claim the recording improved — only what was
      removed, and a warning about crowd noise.
- [ ] **Analysis report…** records that the audio was cleaned.
- [ ] Take that `.cleaned.wav` to **Compare Speakers** and choose it as the
      questioned recording: it says it is a cleaned copy and that a score from
      it is not comparable. The same on **Speaker Profiles → Add a recording**.
- [ ] Listen to both files on a genuinely noisy recording and judge for
      yourself whether it helped. On a crowded one, expect it not to.

### Making a recording easier to listen to

Present in every build — it needs no model file. **None of this has been seen
rendered:** it was built in a container without tkinter, so the layout and
wording below are from reading the code, not from looking at it. Walk it
properly and expect to find something.

- [ ] *Advanced options → Audio and output* shows **Save a copy that is easier
      to listen to**, off by default, with a **Strength** dropdown offering
      Gentle, Standard and Strong, and text saying what it is for *and* that it
      does not separate conversations.
- [ ] The dropdown sits on its own row and does not collide with the text above
      or below it. Check this at a narrow window width too.
- [ ] Run a recording with it on and an output folder set. A
      `<recording>.listening.wav` appears beside the transcript, and the
      original is byte-for-byte untouched.
- [ ] The transcript still comes from the original audio, not from the
      listening copy — the words should be identical to a run with the option
      off.
- [ ] Run it with **no** output folder set. The Status tab says no listening
      copy was written and why, and the transcription itself still completes.
- [ ] **Analysis report…** names the listening copy and lists the filters that
      were applied, including the hum frequency when one was found.
- [ ] On a recording with mains hum, the status line names the frequency it
      found (50 or 60 Hz). On a recording without hum, it must **not** claim to
      have found any.
- [ ] Take that `.listening.wav` to **Compare Speakers** as the questioned
      recording: it says it is a listening copy and that a score from it is not
      comparable. The same on **Speaker Profiles → Add a recording**.
- [ ] Put the `.listening.wav` in a folder and run **a whole folder**: it is
      skipped and counted as a derived copy, not queued for transcription.
- [ ] Listen to both files. On a recording with hum or a very quiet talker,
      expect a real difference. On a crowded one, expect none.

### Replaying a line through the filters

- [ ] With playback available, *Advanced options → Audio and output* shows
      **Use those filters when playing a line back**, off by default. On a
      machine with no player it is absent.
- [ ] Turn it on and click a transcript line. It plays, and the status line
      says `(filtered)`.
- [ ] Turn it off and click the same line. It plays raw, and the status line
      does not say filtered. **The two must sound different**; if they do not,
      the setting is not reaching the player.
- [ ] Click a line, then immediately click another: the first stops and the
      second plays. No temporary files are left behind in the system temp
      folder after closing the application.
- [ ] Change **Strength** and replay the same line: it should audibly change.

### How many people are speaking

- [ ] With **Identify who is speaking** ticked, the question sits directly under
      it in Options, reading "Choose…" on a first launch, with a note about what
      "Not sure" costs.
- [ ] Selecting **Transcribe recording** without answering does not start the
      run: the settings reopen, an amber banner asks the question, the line
      under the progress bar says what it is waiting for, and the dropdown takes
      focus.
- [ ] Answering it takes the banner down and returns the line to Idle; the same
      button then starts the run.
- [ ] Choosing a number shows that many **Speaker names** fields in Advanced
      options; "Not sure" shows none.
- [ ] Unticking **Identify who is speaking** removes the question entirely, and
      the run starts without it.
- [ ] The answer is remembered across a relaunch and travels with an operation
      profile. An operator upgrading from a build that never asked is asked once.

### Redoing the speaker split

- [ ] **Redo speaker separation…** sits under the export row. Before any run it
      is greyed out and says it becomes available after a run with speaker
      identification on.
- [ ] After a diarized run it is enabled and the line beside it names how many
      speakers were found.
- [ ] It is greyed out again while a run is in progress.
- [ ] The dialog names the recording, the answer the last run used and the count
      it came back with, and offers every count *except* "Choose…".
- [ ] With speaker tags corrected by hand, the dialog says in amber how many will
      be replaced; with none, it says only that the words stay as transcribed.
- [ ] **Cancel** changes nothing — including the count in Options and the
      **Speaker names** fields, which stay as they were. The same is true if the
      redo fails: a transcript still showing five speakers must never sit under
      an Options box claiming two.
- [ ] **Redo separation** re-splits without transcribing again — it finishes in a
      fraction of the original run's time, the progress bar names the speaker
      step, and a green banner says how many speakers came back.
- [ ] The words are identical to before; only the speaker tags have changed.
- [ ] **Names do not travel.** Type "Smith" into Speaker 1 (Advanced options),
      run, then redo with a different count: no speaker in the new transcript
      comes back named Smith. The typed fields themselves are left alone — they
      are settings for the next run — and the dialog says names have to be put
      back.
- [ ] A speaker recognised from a voiceprint *is* named again after a redo: that
      name is measured against the new turns rather than carried over.
- [ ] With **Speaker 1 = Alice, Speaker 2 = Bob** typed in and a profile that
      recognises the first speaker by voice, Bob still lands on the second
      speaker — the typed names do not shift up to fill the gap.
- [ ] With an output folder in use, the saved .txt (and .srt) are rewritten to
      match what is on screen.
- [ ] **Analysis report…** afterwards names the count the redo used, not the
      original run's.
- [ ] After a plain transcribe-only run (speaker identification off), the button
      stays greyed out.
- [ ] Starting a new transcription greys it out again until that run finishes.
- [ ] **Open project…** greys it out immediately: that transcript came from a
      file and the audio behind it is not in this session.

### The transcript in its own window

- [ ] **Open in its own window** sits at the top right of the Transcript card.
      Selecting it gives the transcript a real window — titled, resizable,
      maximisable, and movable to a second screen.
- [ ] Everything came with it: both tabs, Find, the export buttons and the redo
      button. The button now reads **Put it back on this page**.
- [ ] The page shows a stand-in card with **Bring it back here** and **Show me
      that window**; the second raises the window when it is behind something.
- [ ] A transcription run started from the main window still fills the popped-out
      transcript and Status tabs as it goes.
- [ ] Closing the window with its X puts the panel back on the page rather than
      destroying it.
- [ ] Round-trip it twice: the transcript, scroll position and speaker tags are
      unchanged, and clicking a speaker tag still reassigns speech.
- [ ] If this system refuses to give the panel a window at all, the warning says
      so and the transcript is still on the page — never floating loose with no
      way back to it.
- [ ] The same button is on the **Live** tab's transcript card, and a live feed
      keeps writing into it while it is popped out.
- [ ] On a smaller screen the window opens fully on-screen, with its buttons
      reachable.

## Saving a corrected speaker to a subject

- [ ] After a diarized run, **Save speaker to profile…** sits under the export
      row with a one-line explanation beside it. It is absent in a build with no
      speaker-embedding model.
- [ ] Correct some speaker tags first; the dialog then lists the speakers under
      the names you gave them, longest first, with how much speech each has.
- [ ] The dialog offers an existing subject *or* a new one, and says that
      samples arrive pending review. Escape closes it; Enter confirms.
- [ ] Typing the name of a subject that already exists adds to that subject
      rather than creating a second one with the same name.
- [ ] After saving, the banner names how many samples were added and that they
      need approval, and Speaker Profiles shows them under **Needs review** —
      not counted in the trusted reference speech.
- [ ] Saving the same speaker twice from the same recording adds nothing the
      second time, and the Status tab explains why.
- [ ] With no transcript, no diarized speakers, or no audio left on hand, the
      button explains what is missing instead of failing silently.

## Speaker Profiles

- [ ] **Empty:** both halves explain themselves rather than showing empty boxes.
- [ ] **Populated:** the list shows who exists; a subject with samples awaiting
      review is marked in the list as well as in the detail panel.
- [ ] Selecting a subject fills the detail panel: reference speech, trusted
      samples, awaiting review, source recordings, voice model.
- [ ] **Pending samples** are visually distinct from trusted ones, and one that
      is unlike the rest of the reference is distinct again.
- [ ] **Approve sample** is disabled when nothing is pending.
- [ ] **Add a recording** offers whole file / diarized speaker / time ranges,
      and each still enrols.
- [ ] Importing a damaged profile shows the dialog **and** leaves a warning
      banner on the page after it is dismissed.
- [ ] **Delete profile** looks destructive and asks before deleting.

## Compare Speakers

- [ ] The three stages read in order: reference, questioned recording, result.
- [ ] With no reference selected, stage 1 says where to create one.
- [ ] **High similarity:** the band is the largest thing on the result, the
      sentence reads as a lead, and the score reads `0.78 / 1.00`.
- [ ] **Low similarity** and **no sufficiently strong match** read plainly.
- [ ] **Insufficient data** visually outranks the score: the band says so and
      the sentence says the score is not meaningful, even when the number is
      high.
- [ ] **Refused** (a profile from another voice model) says so in the same
      place and gives the reason.
- [ ] **Search all profiles** on poor audio shows the ranking but states that
      it supports no conclusion.
- [ ] Nowhere does the screen show a percentage, "match", "confirmed" or
      "same person". The disclaimer is visible without expanding anything.
- [ ] **Full result text** expands to the copyable block; Export report… and
      Copy result work.

## Comparison History

- [ ] Running a comparison on Compare Speakers adds a row here without a
      restart, and the row names the recording, the subject and the score.
- [ ] Every outcome is listed, not only the interesting ones: high,
      intermediate, low, insufficient data, and a refused model mismatch.
- [ ] **Type** distinguishes a 1:1 comparison from a gallery search.
- [ ] The **Subject** and **Recording** filters both narrow the list, and the
      line underneath says how many of how many are shown.
- [ ] Selecting a row fills the detail: score against the threshold in force at
      the time, the questioned speech and the ranges it came from, the source
      SHA-256, what the reference profile held **at the time**, the voice model
      and the application version.
- [ ] A gallery row shows the whole ranking, the margin over the runner-up, and
      no reference-profile facts (there was no single reference).
- [ ] The disclaimer sits at the end of the detail, below the ranking and any
      caveats — never above them.
- [ ] Deleting a speaker profile leaves its comparisons in the history, marked
      **(deleted)**.
- [ ] Moving or removing a questioned recording shows "not at this location
      now" against the record, which is otherwise unchanged.
- [ ] **Export as CSV…** writes the filtered rows; the file has one row per
      comparison and no percentages anywhere.
- [ ] **Delete entry** is disabled with nothing selected, looks destructive, and
      asks before removing one record.
- [ ] Nowhere on the page is a score shown as a percentage, a "match", or a
      confirmation of identity.

## Live and Translate

- [ ] Each opens with its title and sentence, and has one obvious primary
      action.
- [ ] Live: Start / Stop / Test connection behave as before, and the transcript
      area fills as text arrives.
- [ ] Translate: the paste box, Extract from image/PDF…, and the file batch all
      still work.

## Dialogs

- [ ] Help and System status open themed, scroll, close on **Escape**, and open
      with the Close button focused.
- [ ] System status still leads with READY / NOT READY.
- [ ] Compare voices… (from the operation profile card) is themed and readable.
- [ ] Every dialog is dark like the rest of the application. A pale grey box
      with plain grey buttons is one that was missed.
- [ ] Every dialog closes on **Escape** and on its window X, and cancelling
      leaves the run exactly as it was.

### On more than one screen

Worth its own pass, because the failure is invisible on a single monitor and
looks like the application has frozen on two. Do this with the main window on
the secondary screen, and again with it on a monitor placed to the *left* of
the primary one if the office has such a setup.

- [ ] Move the Whispers window to the second screen. Add a recording on the
      Speaker Profiles page: **Which speech is the subject?** opens on that
      screen, over the window — not on the primary screen, and not behind
      whatever else is open there.
- [ ] The same for every other question: **Which speaker is the subject?**,
      **Which speaker is the questioned speaker?**, **Redo speaker
      separation**, **Save speaker to profile**, Help and System status.
- [ ] File pickers (Choose recording, Export…, Import…, Save transcript) open
      on the same screen as the window too.
- [ ] Send the transcript to its own window (**Open in its own window**): the
      new window appears over the application, not on the primary screen.
- [ ] Move that transcript window to the other screen, click inside it, then
      use a button on it that asks a question (**Redo speaker separation**,
      **Save speaker to profile…**, an export). The question opens on the
      screen the transcript is on, because that is where the work is.

## Scrolling

- [ ] Every page scrolls with the wheel and with the scrollbar, at 1366×768 and
      when the window is made deliberately small.
- [ ] **Hide settings** / **Show settings** on Transcribe, and expanding or
      collapsing **Advanced options**, leave the page still scrollable — with no
      resize, maximise or page switch in between.
- [ ] Starting a transcription (which puts the settings away on its own) leaves
      the page scrollable, and **Show settings** during a run does too.
- [ ] Scrolling to the bottom and then hiding the settings does not leave the
      page parked on blank space below its own content.
- [ ] The wheel scrolls over controls that appeared after the page was built
      (a result card, an expanded section), and one notch still moves one notch.
- [ ] The wheel over the transcript and Status panes scrolls those panes, not
      the page behind them.

## Layout and accessibility

- [ ] **1366×768:** every page is usable; the primary action is reachable
      without hunting, and anything below the fold scrolls with the wheel and
      the scrollbar.
- [ ] **1920×1080:** cards and columns fill the width without stranding
      controls at one edge.
- [ ] **Windows display scaling at 125%:** text is not clipped and controls do
      not overlap.
- [ ] **Tab** moves through the controls in a sensible order and the focused
      control is visibly focused.
- [ ] No state is carried by colour alone: pending samples, warnings and errors
      all say what they are in words.
- [ ] **Stock Tk** (uninstall or hide ttkbootstrap): the application still
      starts and every page is usable, if plainer.
