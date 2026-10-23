# Scientific FAQ · Track 02

Source: <https://github.com/neural-interfaces26/2026-competition/blob/main/codabench/pages/scientific_faq_bci.md>
(Captured 2026-10-23. The Track description defines the phase specifications;
the public `objective.py` and active phase configuration are the executable
references. Packaging/upload instructions are in **Get Started → Submission
Guide** on Codabench.)

## Warm-up and sealed evaluation

### What changed, and what remains the final contract?

|  | Warm-up (previous) | Warm-up (current) | Sealed final |
|---|---|---|---|
| **Evaluation data** | Public Dreyer 2023 test participants | Public PROTEUS test participants | Private later sessions and new participants from the same programme |
| **Task** | Two-class motor imagery | Motor imagery, mental subtraction, and word generation | The same three commands |
| **Input and delivery** | Batched windows from the Dreyer montage | 41 EEG channels; one chronological window at a time within each participant-session stream | The same model-facing streaming contract |
| **Ranking metric** | Balanced accuracy pooled over windows | Balanced accuracy averaged over participant × session × interface cells | The same cell-averaged metric |

Warm-up scores are indicative only. Old Dreyer submissions must be rebuilt for
the 41-channel, three-class PROTEUS contract.

### What generalization does the sealed phase test? Is calibration provided?

It combines later sessions from the ten participants represented in the public
release with ten participants absent from it. No sealed-participant
calibration session, label, or other data is supplied through `fit`:
represented participants contribute only their already-public sessions, while
unseen participants are evaluated solely through the label-free `predict`
stream. Exact identities, session allocation, and evaluation order remain
private. The public `objective` runs submissions inference-only on Codabench.

## Public data and preprocessing

### What is in the public PROTEUS release?

NEMAR `nm000290` contains 112 runs from 14 sessions of 10 participants. Two
participants contribute their first three sessions and eight contribute their
first session. Graz and BrainHero runs use the same three commands as the
competition. Source recordings contain 41 EEG channels at 500 Hz and are
distributed in EEG-BIDS format under CC BY 4.0. The NeuralBench source
selection is public in its PROTEUS dataset config. Participant, session, task,
interface, and run entities are available in the public BIDS files for local
splitting and analysis. They are retained by the evaluator but not given to
the model during Codabench inference.

### Will EMG or EOG channels be supplied to the model?

No. The competition input contains the **41 EEG channels only**. Do not build
the submission around the earlier 47-signal description or expect auxiliary
EMG/EOG at evaluation. The exact tensor is produced by the public competition
adapter from the NeuralBench stream config.

### May resting-state recordings be used?

Yes. Eyes-open and eyes-closed runs may be used for training or analysis
under the dataset licence. They have no command cues, so the default task does
not turn them into classification examples and Codabench does not send them
to `predict`.

### What is the current warm-up split?

NeuralBench assigns participants to train, validation, and test with a
60/20/20 subject-level split and random state 33. Codabench evaluates the
test participants from that split. This public split does not reveal the
sealed allocation. The parameters are in the NeuralBench stream config, and
Codabench selects the dataset in its warm-up phase config.

### What reaches `predict(X)`?

Each example is a 4-second window beginning 1 second after cue onset. Source
signals are notch-filtered at 50 and 60 Hz, band-pass filtered at 0.1–75 Hz
at their recorded rate, resampled to 120 Hz, and expressed in microvolts. No
learned scaling or clipping is applied. Evaluation input has shape
`(1, 41, 480)`. These values are fixed in the NeuralBench stream config.

Fixed signal preprocessing happens before streaming. "Causal" refers to the
model-facing contract: the model receives no future window or label.

### May I use my own preprocessing?

Yes. You may preprocess the public training data differently and perform
additional transformations inside `predict`. Codabench nevertheless supplies
the fixed tensor above; a submission cannot request raw 500 Hz sealed data.
Any evaluation-time transformation or fitted statistic must use only the
current or earlier windows of the current session, without labels. Public-data
use remains subject to the Terms.

## Streaming and adaptation

### Where is state reset, and in what order do windows arrive?

One stream is one **participant × session**. There is no shuffling within a
stream: runs are ordered by run number and windows are strictly chronological
within each run. The order of independent session streams is not exposed as a
model signal. State may persist across Graz and BrainHero runs in the same
session. Each new session starts from a fresh copy of the submitted model and
calls its optional `reset_state()`. The public streaming evaluator implements
the one-window calls, ordering checks, model copy, and reset.

### What information does the model receive, and may it adapt?

`predict(X)` receives only the EEG tensor. Participant, session, run,
interface, and label metadata are not passed to the model. Causal, label-free
adaptation using the current and earlier windows of the current session is
allowed, including statistics-based alignment or gradient updates inside
`predict`. State, windows, statistics, and parameter updates must not cross
the session boundary. Worker time and memory limits still apply. Grouping
metadata are used internally by the `objective`.

### What must the model return?

One integer class index per window with shape `(B,)`: `0` for kinesthetic
motor imagery, `1` for mental subtraction, and `2` for word generation. The
public `objective` validates one prediction per window.

## Scoring

### How is the official score computed?

Balanced accuracy is computed separately for every participant × session ×
interface cell, then cell scores are averaged equally. Within a cell it is
the unweighted mean recall across the task classes. Pooled balanced accuracy
and plain accuracy are diagnostics only. The executable implementation is in
`objective.py` and the shared metric helpers.

### Why can NeuralBench and Codabench scores differ?

NeuralBench's `test/bal_acc_stream_mean` averages per session without
separating Graz and BrainHero. Codabench separates those interfaces before
averaging cells, so the two scores can differ even for identical predictions.

## Resources

- Track description (www.codabench.org) · PROTEUS on NEMAR (nemar.org) ·
  NeuralBench guide (facebookresearch.github.io) · Competition implementation
