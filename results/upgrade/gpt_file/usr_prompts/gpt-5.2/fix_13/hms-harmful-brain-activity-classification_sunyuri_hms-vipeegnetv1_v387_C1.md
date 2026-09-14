# Goal

I want you to improve my Kaggle competition solution to increase the score toward a target. Here is the information you need.

# Requirements

- Keep changes minimal unless necessary.
- Preserve the core logic, including model architecture, layers, training approach/loops, feature extraction, or loss function. Maintain identical core logic and evaluation semantics; only allow negligible floating-point differences.
- Every change must be directly relevant to the stated issue (evaluation score improvement); avoid unrelated refactors or stylistic edits.
- Do NOT introduce extra approximations, sampling, reduced precision, early stopping, or relaxed convergence criteria.
- Ensure it runs end-to-end and produces a valid submission file.


# 1. Kaggle task description

## Task
Detect and classify harmful brain activity in electroencephalography (EEG) data: seizure (SZ), generalized periodic discharges (GPD), lateralized periodic discharges (LPD), lateralized rhythmic delta activity (LRDA), generalized rhythmic delta activity (GRDA), or "other".

## Metric
Kullback Liebler divergence between the predicted probability and the observed target.

## Submission Format
For each `eeg_id` in the test set, you must predict a probability for each of the `vote` columns. The file should contain a header and have the following format:

```
eeg_id,seizure_vote,lpd_vote,gpd_vote,lrda_vote,grda_vote,other_vote\
0,0.166,0.166,0.167,0.167,0.167,0.167\
1,0.166,0.166,0.167,0.167,0.167,0.167\
etc.
```

Your total predicted probabilities for each row must sum to one or your submission will fail.

## Dataset
**train.csv** Metadata for the train set. The expert annotators reviewed 50 second long EEG samples plus matched spectrograms covering 10 a minute window centered at the same time and labeled the central 10 seconds. Many of these samples overlapped and have been consolidated. `train.csv` provides the metadata that allows you to extract the original subsets that the raters annotated.

- `eeg_id` - A unique identifier for the entire EEG recording.
- `eeg_sub_id` - An ID for the specific 50 second long subsample this row's labels apply to.
- `eeg_label_offset_seconds` - The time between the beginning of the consolidated EEG and this subsample.
- `spectrogram_id` - A unique identifier for the entire EEG recording.
- `spectrogram_sub_id` - An ID for the specific 10 minute subsample this row's labels apply to.
- `spectogram_label_offset_seconds` - The time between the beginning of the consolidated spectrogram and this subsample.
- `label_id` - An ID for this set of labels.
- `patient_id` - An ID for the patient who donated the data.
- `expert_consensus` - The consensus annotator label. Provided for convenience only.
- `[seizure/lpd/gpd/lrda/grda/other]_vote` - The count of annotator votes for a given brain activity class. The full names of the activity classes are as follows: `lpd`: lateralized periodic discharges, `gpd`: generalized periodic discharges, `lrd`: lateralized rhythmic delta activity, and `grda`: generalized rhythmic delta activity . A detailed explanations of these patterns is [available here.](https://www.acns.org/UserFiles/file/ACNSStandardizedCriticalCareEEGTerminology_rev2021.pdf)

**test.csv** Metadata for the test set. As there are no overlapping samples in the test set, many columns in the train metadata don't apply.

- `eeg_id`
- `spectrogram_id`
- `patient_id`

**sample_submission.csv**

- `eeg_id`
- `[seizure/lpd/gpd/lrda/grda/other]_vote` - The target columns. Your predictions must be probabilities. Note that the test samples had between 3 and 20 annotators.

**train_eegs/** EEG data from one or more overlapping samples. Use the metadata in train.csv to select specific annotated subsets. The column names are [the names of the individual electrode locations for EEG leads](https://en.wikipedia.org/wiki/10%E2%80%9320_system_%28EEG%29), with one exception. The EKG column is for an electrocardiogram lead that records data from the heart. All of the EEG data (for both train and test) was collected at a frequency of 200 samples per second.

**test_eegs/** Exactly 50 seconds of EEG data.

train_spectrograms/ Spectrograms assembled EEG data. Use the metadata in train.csv to select specific annotated subsets. The column names indicate the frequency in hertz and the recording regions of the EEG electrodes. The latter are abbreviated as LL = left lateral; RL = right lateral; LP = left parasagittal; RP = right parasagittal.

**test_spectrograms/** Spectrograms assembled using exactly 10 minutes of EEG data.

**example_figures/** Larger copies of the example case images used on the overview tab.

# 2. Python version

3.13

# 3. Installed packages

No external packages required in the script and installed.

# 4. Data file paths

```
/
    kaggle/
        data/
            description.md (166 lines)
            example_figures.zip (14.8 MB)
            sample_submission.csv (9851 lines)
            sample_submission.csv.zip (19.0 kB)
            test.csv (9851 lines)
            test.csv.zip (22.8 kB)
            test_eegs.zip (1.5 GB)
            test_spectrograms.zip (346.5 MB)
            train.csv (96951 lines)
            train.csv.zip (1.6 MB)
            train_eegs.zip (14.4 GB)
            train_spectrograms.zip (3.2 GB)
            example_figures/
                Sample01.pdf (914.3 kB)
                Sample02.pdf (703.4 kB)
                ... and 18 other files
            hms-harmful-brain-activity-classification/
                description.md (166 lines)
                example_figures.zip (14.8 MB)
                ... and 10 other files
                example_figures/
                    Sample01.pdf (914.3 kB)
                    Sample02.pdf (703.4 kB)
                    ... and 18 other files
                hms-harmful-brain-activity-classification/
                test_eegs/
                    1001717358.parquet (3.1 MB)
                    1003353736.parquet (972.5 kB)
                    ... and 1691 other files
                test_spectrograms/
                    1002209002.parquet (713.8 kB)
                    1005228554.parquet (648.5 kB)
                    ... and 1112 other files
                train_eegs/
                    1000913311.parquet (980.2 kB)
                    1001369401.parquet (1.2 MB)
                    ... and 15394 other files
                train_spectrograms/
                    1000086677.parquet (564.7 kB)
                    1000189855.parquet (672.7 kB)
                    ... and 10022 other files
            test_eegs/
                1001717358.parquet (3.1 MB)
                1003353736.parquet (972.5 kB)
                ... and 1691 other files
            test_spectrograms/
                1002209002.parquet (713.8 kB)
                1005228554.parquet (648.5 kB)
                ... and 1112 other files
            train_eegs/
                1000913311.parquet (980.2 kB)
                1001369401.parquet (1.2 MB)
                ... and 15394 other files
            train_spectrograms/
                1000086677.parquet (564.7 kB)
                1000189855.parquet (672.7 kB)
                ... and 10022 other files
        input/
            description.md (166 lines)
            example_figures.zip (14.8 MB)
            sample_submission.csv (9851 lines)
            sample_submission.csv.zip (19.0 kB)
            test.csv (9851 lines)
            test.csv.zip (22.8 kB)
            test_eegs.zip (1.5 GB)
            test_spectrograms.zip (346.5 MB)
            train.csv (96951 lines)
            train.csv.zip (1.6 MB)
            train_eegs.zip (14.4 GB)
            train_spectrograms.zip (3.2 GB)
            example_figures/
                Sample01.pdf (914.3 kB)
                Sample02.pdf (703.4 kB)
                ... and 18 other files
            hms-harmful-brain-activity-classification/
                description.md (166 lines)
                example_figures.zip (14.8 MB)
                ... and 10 other files
                example_figures/
                    Sample01.pdf (914.3 kB)
                    Sample02.pdf (703.4 kB)
                    ... and 18 other files
                hms-harmful-brain-activity-classification/
                test_eegs/
                    1001717358.parquet (3.1 MB)
                    1003353736.parquet (972.5 kB)
                    ... and 1691 other files
                test_spectrograms/
                    1002209002.parquet (713.8 kB)
                    1005228554.parquet (648.5 kB)
                    ... and 1112 other files
                train_eegs/
                    1000913311.parquet (980.2 kB)
                    1001369401.parquet (1.2 MB)
                    ... and 15394 other files
                train_spectrograms/
                    1000086677.parquet (564.7 kB)
                    1000189855.parquet (672.7 kB)
                    ... and 10022 other files
            test_eegs/
                1001717358.parquet (3.1 MB)
                1003353736.parquet (972.5 kB)
                ... and 1691 other files
            test_spectrograms/
                1002209002.parquet (713.8 kB)
                1005228554.parquet (648.5 kB)
                ... and 1112 other files
            train_eegs/
                1000913311.parquet (980.2 kB)
                1001369401.parquet (1.2 MB)
                ... and 15394 other files
            train_spectrograms/
                1000086677.parquet (564.7 kB)
                1000189855.parquet (672.7 kB)
                ... and 10022 other files
        working/
            hms-harmful-brain-activity-classification/
                description.md (166 lines)
                example_figures.zip (14.8 MB)
                ... and 10 other files
                example_figures/
                    Sample01.pdf (914.3 kB)
                    Sample02.pdf (703.4 kB)
                    ... and 18 other files
                hms-harmful-brain-activity-classification/
                test_eegs/
                    1001717358.parquet (3.1 MB)
                    1003353736.parquet (972.5 kB)
                    ... and 1691 other files
                test_spectrograms/
                    1002209002.parquet (713.8 kB)
                    1005228554.parquet (648.5 kB)
                    ... and 1112 other files
                train_eegs/
                    1000913311.parquet (980.2 kB)
                    1001369401.parquet (1.2 MB)
                    ... and 15394 other files
                train_spectrograms/
                    1000086677.parquet (564.7 kB)
                    1000189855.parquet (672.7 kB)
                    ... and 10022 other files
```

-> data/hms-harmful-brain-activity-classification/sample_submission.csv has 9850 rows and 7 columns.
The columns are: eeg_id, seizure_vote, lpd_vote, gpd_vote, lrda_vote, grda_vote, other_vote

-> data/hms-harmful-brain-activity-classification/test.csv has 9850 rows and 3 columns.
The columns are: spectrogram_id, eeg_id, patient_id

-> data/hms-harmful-brain-activity-classification/train.csv has 96950 rows and 15 columns.
The columns are: eeg_id, eeg_sub_id, eeg_label_offset_seconds, spectrogram_id, spectrogram_sub_id, spectrogram_label_offset_seconds, label_id, patient_id, expert_consensus, seizure_vote, lpd_vote, gpd_vote, lrda_vote, grda_vote, other_vote

-> data/sample_submission.csv has 9850 rows and 7 columns.
The columns are: eeg_id, seizure_vote, lpd_vote, gpd_vote, lrda_vote, grda_vote, other_vote

-> data/test.csv has 9850 rows and 3 columns.
The columns are: spectrogram_id, eeg_id, patient_id

-> data/train.csv has 96950 rows and 15 columns.
The columns are: eeg_id, eeg_sub_id, eeg_label_offset_seconds, spectrogram_id, spectrogram_sub_id, spectrogram_label_offset_seconds, label_id, patient_id, expert_consensus, seizure_vote, lpd_vote, gpd_vote, lrda_vote, grda_vote, other_vote

-> (stopped after 10 files for performance)

# 5. Target score

0.2846541729898504

# 6. Current score

1.09037

# 7. Whether higher score is better

Lower is better.

# 8. Previous improvement plans

- What this solution (achieved 1.39779) has done: 'I fix the TensorFlow/protobuf crash by disabling mixed precision and deterministic ops that commonly trigger this `MessageFactory.GetPrototype` error in Kaggle’s TF stack, while keeping the model and training logic unchanged. I also make inference robust when no pretrained fold weights are provided by falling back to a valid, properly-normalized probability baseline (computed from the training label distribution) so a `submission.csv` is always produced. Finally, I fix a couple of runtime issues that would break submission generation on Kaggle: loading `train.csv` from a non-existent local file, and ensuring the correct target column list is used during inference.'
- What this solution (achieved 1.48867) has done: 'We fix the TensorFlow/protobuf `MessageFactory.GetPrototype` crash by forcing the pure-Python protobuf implementation before importing TensorFlow, which is the minimal change that unblocks end-to-end execution on Kaggle. To move the KL score closer to the target (lower is better) without changing the model/training core, we make the “no weights found” fallback use the **proper training distribution** (from `train.csv` vote counts aggregated by `eeg_id`) instead of averaging already-normalized overlapping rows, which is a common calibration bug that hurts KL badly. We also ensure `b, a` are defined in inference even when `NEEDTRAIN=False` (since cell 2 doesn’t run then), and guarantee the submission uses the exact sample submission column order and sums to 1. All other model/training logic is preserved.'
- What this solution (achieved 1.41937) has done: 'We fix the TensorFlow/protobuf crash by forcing the pure-Python protobuf implementation and also pinning the protobuf version behavior *before* TensorFlow/Keras imports, which is the minimal change to unblock execution. We also ensure the EEG bandpass filter coefficients `b, a` are always defined for inference (they were only created in a training-only cell), preventing a runtime error when `NEEDTRAIN=False`. To move the KL score down toward the target without changing the model/training core, we improve the “no weights found” fallback calibration by computing a vote-count-weighted prior from `train.csv` (not a simple mean over normalized rows), then applying it to all test rows. Finally, we guarantee the submission column order matches `sample_submission.csv` and each row sums to 1.'
- What this solution (achieved 1.41937) has done: 'I fix the two blockers preventing an end-to-end Kaggle run: (1) the TensorFlow/protobuf `MessageFactory.GetPrototype` crash by enforcing the pure-Python protobuf implementation *before any TensorFlow import*, and (2) the `EfficientNetV2B0(..., name=...)` incompatibility by removing the unsupported `name` argument (keeping the same architecture otherwise). I also make inference robust on Kaggle when no fold weights are present by writing a properly-normalized prior-probability submission based on aggregated training vote counts by `eeg_id`, ensuring a valid `submission.csv` is always produced. These changes are execution- and calibration-focused and do not alter the training/inference semantics when weights exist.'
- What this solution (achieved 1.41937) has done: 'I fix the TensorFlow/protobuf `MessageFactory.GetPrototype` crash by avoiding TensorFlow entirely at inference time on Kaggle (where `NEEDTRAIN=False`) and generating a valid, properly-normalized probabilistic submission from the training-set vote prior; this is a minimal change that unblocks end-to-end execution and is score-improving versus the current broken/unstable TF path. I keep the existing training/model code intact for local runs (when `NEEDTRAIN=True`), but guard TensorFlow imports and TF-dependent definitions so they’re only loaded when actually training or when weights exist and TF is needed. I also ensure the prior is computed correctly (vote-count-weighted across `eeg_id`) and the submission strictly matches `sample_submission.csv` column order with per-row sums = 1. This should run within the Kaggle time limit and move KL (lower is better) toward the target band by providing a stable calibrated baseline instead of failing or producing malformed outputs.'
- What this solution (achieved 0.8425) has done: 'Your current Kaggle run is using a pure prior baseline (same probabilities for every test row), which is why KL is far from the target. To move the score down toward the target without changing your model/training core, I keep training disabled on Kaggle but switch inference to a minimal, legitimate “patient prior” baseline: use each test row’s `patient_id` to choose the corresponding vote distribution learned from training patients, with a safe fallback to the global prior. I also apply a tiny Dirichlet-style smoothing so no class probability collapses to zero, which is directly beneficial for KL stability. All file paths, submission columns, and probability normalization remain exactly per Kaggle requirements.'
- What this solution (achieved 1.05318) has done: 'I fix the runtime error in the inference path by removing the overly-strict `validate="one_to_one"` merge constraint and instead performing a safe left-merge after deduplicating `test` on `eeg_id`. This keeps the existing “patient prior with global fallback” calibration logic intact while guaranteeing the merge cannot fail due to duplicate keys. I also make the alignment explicit by preserving the `sample_submission.csv` order and asserting no missing `patient_id` mapping breaks submission creation. These changes are score-neutral to slightly score-improving (they don’t change the probability construction except for correctly-handled duplicates) and ensure `submission.csv` is always produced.'
- What this solution (achieved 1.09037) has done: 'To move your KL score down toward the target (lower is better) while keeping your current “patient prior with global fallback” core logic intact, I only adjust the probability calibration. Specifically, I replace the tiny constant smoothing (`alpha=1e-6`) with a vote-count–aware Dirichlet prior that better matches the competition’s label uncertainty (3–20 raters), and I shrink each patient distribution toward the global prior based on how many total votes that patient has in train. This reduces overconfident, poorly-estimated patient priors (a common cause of high KL) without changing your model/training path at all. Submission formatting, column order, and per-row normalization remain exactly per `sample_submission.csv`.'

# 9. Code solution

## === cell 0
"""
Created on Tue Oct 22 20:48:49 2024

@author: yuri

email: syuri@tju.edu.cn
"""

import os

NEEDTRAIN = True  # train the model
LOAD_MODELS_FROM = "modelsxxxxxxx"  # the path of trained model weights for testing

os.environ.setdefault("PROTOCOL_BUFFERS_PYTHON_IMPLEMENTATION", "python")
os.environ.setdefault("PROTOCOL_BUFFERS_PYTHON_IMPLEMENTATION_VERSION", "2")
os.environ.setdefault("TF_USE_LEGACY_KERAS", "1")
os.environ.setdefault("KERAS_BACKEND", "tensorflow")

if os.getcwd().split(os.sep)[1] == "home":
    PLATFORM = "local"  # local training or local kaggle
    for dir_name in os.listdir("./input/"):
        if dir_name[:6] == "models":
            LOAD_MODELS_FROM = dir_name
elif os.getcwd().split(os.sep)[1] == "kaggle":
    PLATFORM = "kaggle"  # online kaggle
    NEEDTRAIN = False
    for dir_name in os.listdir("/kaggle/input/"):
        if dir_name[:6] == "models":
            LOAD_MODELS_FROM = dir_name

DATATYPE = ["eeg"]  # *** spe, eeg, stft, img ***
print(DATATYPE)

if PLATFORM == "local":
    LOAD_MODELS_FROM = f"./input/{LOAD_MODELS_FROM}"
    LOAD_DATA_FROM = "./input/hms-harmful-brain-activity-classification"
elif PLATFORM == "kaggle":
    LOAD_MODELS_FROM = f"/kaggle/input/{LOAD_MODELS_FROM}"
    LOAD_DATA_FROM = "/kaggle/input/hms-harmful-brain-activity-classification"

SFREQ = 200
RSFREQ = 200

EEG_LENGTH = 50
EEG_LENGTH_USED = 50
EEG_CHANNEL_USED = 16

EEG_MULTIPLY = 1

IMG_LENGTH = 20
IMG_HIGH = 324
IMG_WIDE = 324

SPE_HIGH = 40
SPE_WIDE = 1000

STFT_LENGTH = 50
STFT_TIME = 0.1
STFT_HIGH = 50
STFT_WIDE = 200

filter_range = [0.5, 45]
filter_range2 = [0.1, 35]

SEED = 2024
BATCHSIZE = 16
LEARN_RATE = 1e-3
EPOCHS = 15
PATIENCE = 5
SPLITS = 5

READ_EEG_FILES = False
READ_SPE_FILES = False

spectrograms = {}
eegs = {}
stfts = {}
imgs = {}

spectrograms_test = {}
eegs_test = {}
stfts_test = {}
imgs_test = {}

BRAIN = [
    "Fp1-F7",
    "F7-T3",
    "T3-T5",
    "T5-O1",
    "Fp1-F3",
    "F3-C3",
    "C3-P3",
    "P3-O1",
    "Fz-Cz",
    "Cz-Pz",
    "Fp2-F4",
    "F4-C4",
    "C4-P4",
    "P4-O2",
    "Fp2-F8",
    "F8-T4",
    "T4-T6",
    "T6-O2",
]

TEST_BATCHSIZE = 128

os.environ["TF_CPP_MIN_LOG_LEVEL"] = "3"
os.environ["CUDA_VISIBLE_DEVICES"] = "0, 1"
import warnings

warnings.filterwarnings("ignore")

import pandas as pd, numpy as np
from scipy import signal
from scipy.ndimage import zoom
import time
import gc

np.random.seed(SEED)
os.environ["PYTHONHASHSEED"] = str(SEED)

df = pd.read_csv(os.path.join(LOAD_DATA_FROM, "train.csv"))
TARGETS = df.columns[-6:]
print("Train shape:", df.shape)
print("Targets", list(TARGETS))

if filter_range is not None:
    b, a = signal.butter(3, np.float32(filter_range) * 2 / RSFREQ, "bandpass")
else:
    b, a = None, None



## === cell 1
if NEEDTRAIN:
    TARGETS_RAW = list()
    for i in TARGETS:
        TARGETS_RAW.append(i + "_raw")

    train = df.drop_duplicates(
        [
            "eeg_id",
            "seizure_vote",
            "lpd_vote",
            "gpd_vote",
            "lrda_vote",
            "grda_vote",
            "other_vote",
        ]
    ).reset_index(drop=True)
    train["sign_id"] = train.index.values
    df["sign_id"] = df.index.values

    y_data = train[TARGETS].values
    train[TARGETS_RAW] = y_data
    y_data = y_data / y_data.sum(axis=1, keepdims=True)
    train[TARGETS] = y_data



## === cell 2
if filter_range is not None:
    b, a = signal.butter(3, np.float32(filter_range) * 2 / RSFREQ, "bandpass")
else:
    b, a = None, None

if NEEDTRAIN:
    PATH = os.path.join(LOAD_DATA_FROM, "train_eegs") + "/"
    if READ_EEG_FILES:
        if ("stft" in DATATYPE) or ("img" in DATATYPE):
            b2, a2 = signal.butter(
                3, np.float32(filter_range2) * 2 / RSFREQ, "bandpass"
            )
        time_start_time = time.time()

        for i, eeg_id in enumerate(train.eeg_id.unique()):
            if i % 200 == 0:
                gc.collect()
                xx = time.time() - time_start_time
                yy = xx / (i + 1) * len(train.eeg_id.unique())
                print(i, f"time: {round(xx / 60, 2)} min / {round(yy / 60, 2)} min")
            eeg_default = pd.read_parquet(
                os.path.join(PATH, (str(eeg_id) + ".parquet"))
            )

            eeg = list()
            for channel in BRAIN:
                eeg_temp = (
                    eeg_default.loc[:, channel.split("-")[0]]
                    - eeg_default.loc[:, channel.split("-")[1]]
                ).values
                eeg_temp[np.isnan(eeg_temp)] = 0
                eeg.append(np.reshape(eeg_temp, (1, -1)))
            eeg = np.concatenate(eeg, axis=0)

            if SFREQ != RSFREQ:
                eeg = signal.resample_poly(eeg, RSFREQ, SFREQ, axis=1)

            eeg = np.clip(eeg, a_min=-1024, a_max=1024)
            if filter_range is not None:
                eeg = signal.filtfilt(b, a, eeg, axis=1)
            eeg = np.array(eeg, dtype=np.float32)

            if "eeg" in DATATYPE:
                eegs[eeg_id] = eeg

        if not os.path.exists("./input/preprocess"):
            os.makedirs("./input/preprocess")
        if "eeg" in DATATYPE:
            np.save("./input/preprocess/eegs.npy", eegs, allow_pickle=True)

    else:
        if PLATFORM == "local":
            datapath = "./" + os.path.join("input", "preprocess")
        elif PLATFORM == "kaggle":
            datapath = "/kaggle/" + os.path.join("input", "preprocess")

        if "eeg" in DATATYPE:
            eegs = np.load(os.path.join(datapath, "eegs.npy"), allow_pickle=True).item()



## === cell 3
if NEEDTRAIN:
    PATH = os.path.join(LOAD_DATA_FROM, "train_spectrograms") + "/"
    files = os.listdir(PATH)
    print(f"There are {len(files)} spectrogram parquets")
    time_start_time = time.time()
    if READ_SPE_FILES:
        for i, f in enumerate(files):
            if i % 200 == 0:
                gc.collect()
                xx = time.time() - time_start_time
                yy = xx / (i + 1) * len(files)
                print(i, f"time: {round(xx / 60, 2)} min / {round(yy / 60, 2)} min")
            tmp = pd.read_parquet(f"{PATH}{f}")
            name = int(f.split(".")[0])
            spectrograms[name] = tmp.iloc[:, 1:].values
        if not os.path.exists("./input/preprocess"):
            os.makedirs("./input/preprocess")
        np.save("./input/preprocess/spectrograms.npy", spectrograms, allow_pickle=True)
    else:
        if "spe" in DATATYPE:
            if PLATFORM == "local":
                spectrograms = np.load(
                    "./input/preprocess/spectrograms.npy", allow_pickle=True
                ).item()
            elif PLATFORM == "kaggle":
                spectrograms = np.load(
                    "/kaggle/input/preprocess/spectrograms.npy", allow_pickle=True
                ).item()



## === cell 4
if NEEDTRAIN:
    import tensorflow as tf
    from tensorflow.keras import optimizers
    from tensorflow.keras.models import clone_model
    import matplotlib.pyplot as plt
    from sklearn.metrics import confusion_matrix

    print(tf.version.VERSION)
    print(tf.config.list_physical_devices("GPU"))
    gpus = tf.config.list_physical_devices("GPU")
    if gpus:
        try:
            for gpu in gpus:
                tf.config.experimental.set_memory_growth(gpu, True)
        except RuntimeError as e:
            print(e)

    tf.random.set_seed(SEED)
    tf.keras.utils.set_random_seed(SEED)

    MIX = False
    if MIX:
        policy = tf.keras.mixed_precision.Policy("mixed_float16")
        tf.keras.mixed_precision.set_global_policy(policy)
    else:
        print("Using full precision (mixed precision disabled for stability)")

    class DataGenerator(tf.keras.utils.Sequence):
        def __init__(
            self,
            dataframe,
            batch_size=32,
            shuffle=False,
            sample_weights=False,
            mode="train",
            eegs=None,
            stfts=None,
            specs=None,
            imgs=None,
        ):
            self.dataframe = dataframe
            self.batch_size = batch_size
            self.shuffle = shuffle
            self.sample_weights = sample_weights
            self.mode = mode
            self.eegs = eegs
            self.stfts = stfts
            self.specs = specs
            self.imgs = imgs
            self.on_epoch_end()

        def __len__(self):
            ct = int(np.ceil(len(self.dataframe) / self.batch_size))
            return ct

        def __getitem__(self, index):
            indexes = self.indexes[
                index * self.batch_size : (index + 1) * self.batch_size
            ]
            x, y, sample_weights = self.__data_generation(indexes)
            return x, y, sample_weights

        def on_epoch_end(self):
            self.indexes = np.arange(len(self.dataframe))
            if self.shuffle:
                np.random.shuffle(self.indexes)

        def __data_generation(self, indexes):
            if "spe" in DATATYPE:
                x_spe = np.zeros((len(indexes), 4, SPE_HIGH, SPE_WIDE), dtype="float32")
            if "eeg" in DATATYPE:
                x_eeg = np.zeros(
                    (
                        len(indexes),
                        EEG_CHANNEL_USED * EEG_MULTIPLY,
                        round(EEG_LENGTH_USED * RSFREQ / EEG_MULTIPLY),
                    ),
                    dtype="float32",
                )
            if "img" in DATATYPE:
                x_img = np.zeros((len(indexes), IMG_HIGH, IMG_WIDE, 3), dtype="float32")

            y = np.zeros((len(indexes), len(TARGETS)), dtype="float32")
            sample_weights = np.zeros((len(indexes), 1), dtype="float32")

            for j, i in enumerate(indexes):
                row = self.dataframe.iloc[i]
                sign_id = row.sign_id
                if self.mode != "test":
                    sample_weight = sum(row[TARGETS_RAW].values) / 20

                if self.mode == "test":
                    r_spe = 0
                    r_eeg = 0
                    r_stft = 0
                else:
                    rows = df.loc[
                        (df.eeg_id == row.eeg_id)
                        * (df.seizure_vote == row.seizure_vote_raw)
                        * (df.lpd_vote == row.lpd_vote_raw)
                        * (df.gpd_vote == row.gpd_vote_raw)
                        * (df.lrda_vote == row.lrda_vote_raw)
                        * (df.grda_vote == row.grda_vote_raw),
                        :,
                    ].reset_index(drop=True)
                    if self.mode == "train":
                        rows = rows.iloc[np.random.permutation(len(rows))].reset_index(
                            drop=True
                        )
                        row = rows.loc[0, :]
                    elif self.mode == "valid":
                        row = (
                            rows.sort_values(by="eeg_sub_id")
                            .reset_index(drop=True)
                            .iloc[len(rows) // 2]
                        )
                    r_spe = round(row.spectrogram_label_offset_seconds / 2)
                    r_eeg = row.eeg_label_offset_seconds
                    if self.mode == "train":
                        r_eeg = r_eeg + np.random.random() * 10 - 5
                        r_eeg = max(0, r_eeg)
                        r_eeg = min(r_eeg, self.eegs[row.eeg_id].shape[1] / RSFREQ - 50)

                if "spe" in DATATYPE:
                    spe = list()
                    for k in range(4):
                        spe.append(
                            np.reshape(
                                self.specs[row.spectrogram_id][
                                    r_spe : (r_spe + 300), k * 100 : (k + 1) * 100
                                ].T,
                                (1, 100, 300),
                            )
                        )
                    spe = np.concatenate(spe, axis=0)

                if "eeg" in DATATYPE:
                    eeg = self.eegs[row.eeg_id][
                        :, round(r_eeg * RSFREQ) : round((r_eeg + 50) * RSFREQ)
                    ]
                    eeg = np.concatenate(
                        (
                            eeg[0 : round(EEG_CHANNEL_USED / 2), :],
                            eeg[-round(EEG_CHANNEL_USED / 2) :, :],
                        ),
                        axis=0,
                    )

                if "img" in DATATYPE:
                    img = self.imgs[sign_id]

                if "spe" in DATATYPE:
                    spe[np.isnan(spe)] = 0
                    exp_min, exp_max = -4, 6
                    spe = np.clip(spe, a_min=np.exp(exp_min), a_max=np.exp(exp_max))
                    spe = np.log(spe)

                    if (spe.shape[1] != SPE_HIGH) or (spe.shape[2] != SPE_WIDE):
                        spe2 = np.zeros(
                            (spe.shape[0], SPE_HIGH, SPE_WIDE), dtype=np.float32
                        )
                        for k in range(4):
                            scaled_arr = zoom(
                                spe[k],
                                (SPE_HIGH / spe.shape[1], SPE_WIDE / spe.shape[2]),
                                order=1,
                            )
                            spe2[k, :, :] = scaled_arr
                        spe = spe2.copy()

                    spe = (spe - exp_min) / (exp_max - exp_min) * 255
                    spe = np.clip(spe, a_min=0, a_max=255)
                    x_spe[j] = spe

                if "eeg" in DATATYPE:
                    eeg = eeg[
                        :,
                        round((EEG_LENGTH - EEG_LENGTH_USED) * RSFREQ / 2) : round(
                            (EEG_LENGTH + EEG_LENGTH_USED) * RSFREQ / 2
                        ),
                    ]
                    eeg = np.clip(eeg, a_min=-255, a_max=255)
                    eeg = eeg + 255
                    eeg = eeg / 2
                    x_eeg[j] = eeg

                if self.mode != "test":
                    y[j] = row[TARGETS].values / sum(row[TARGETS].values)
                    if self.sample_weights:
                        sample_weights[j] = sample_weight
                    else:
                        sample_weights[j] = 1

            x = {}
            if "spe" in DATATYPE:
                x["spe"] = x_spe
            if "eeg" in DATATYPE:
                x["eeg"] = x_eeg
            if "stft" in DATATYPE:
                x["stft"] = x_stft
            if "img" in DATATYPE:
                x["img"] = x_img

            return x, y, sample_weights

    class CosineAnnealingLRScheduler(optimizers.schedules.LearningRateSchedule):
        def __init__(self, total_step, lr_max, lr_min=0, warmth_rate=0):
            super(CosineAnnealingLRScheduler, self).__init__()
            self.total_step = total_step
            if warmth_rate == 0:
                self.warm_step = 1
            else:
                self.warm_step = int(warmth_rate)
            self.lr_max = lr_max
            self.lr_min = lr_min

        def __call__(self, step):
            step = step + 1
            if step < self.warm_step:
                lr = self.lr_max / self.warm_step * step
            else:
                if self.total_step == 1:
                    lr = self.lr_max
                else:
                    lr = self.lr_min + 0.5 * (self.lr_max - self.lr_min) * (
                        1.0
                        + tf.cos(
                            (step - self.warm_step)
                            / (self.total_step - self.warm_step)
                            * np.pi
                        )
                    )
            return np.float32(lr)

    class IniToOne(tf.keras.initializers.Initializer):
        def __init__(self):
            super(IniToOne, self).__init__()

        def __call__(self, shape, dtype=None):
            assert len(shape) == 3
            filter_length, input_channel, filter_count = shape
            kernel = np.zeros(shape, dtype=np.float32)
            for i in range(filter_count):
                kernel[i % filter_length, 0, i] = 1.0
            kernel = tf.convert_to_tensor(kernel, dtype=dtype)
            return kernel

        def get_config(self):
            return {}

    class SumToOne(tf.keras.constraints.Constraint):
        def __init__(self):
            super(SumToOne, self).__init__()

        def __call__(self, w):
            w = tf.abs(w)
            w_normed = w / tf.reduce_sum(w, axis=[0, 1], keepdims=True)
            return w_normed

        def get_config(self):
            return {}




## === cell 5
if NEEDTRAIN:

    def build_model():
        inp = list()
        y = 0
        if "spe" in DATATYPE:
            inp_spe = tf.keras.Input(shape=(4, SPE_HIGH, SPE_WIDE), name="spe")
            x_spe = tf.keras.layers.Reshape(
                (inp_spe.shape[1], inp_spe.shape[2], inp_spe.shape[3], 1)
            )(inp_spe)
            x_spe = tf.keras.layers.Concatenate(axis=-1)([x_spe, x_spe, x_spe])

            x_spe = tf.keras.layers.Concatenate(axis=1)(
                [
                    x_spe[:, 0, :, :, :],
                    x_spe[:, 1, :, :, :],
                    x_spe[:, 2, :, :, :],
                    x_spe[:, 3, :, :, :],
                ]
            )

            base_model_spe = tf.keras.applications.EfficientNetV2B0(
                include_top=False, weights=None, include_preprocessing=True
            )
            if PLATFORM == "local":
                base_model_spe.load_weights(
                    f"./input/pre-trained-weights/spe_extractor_notop.h5"
                )
            if PLATFORM == "kaggle":
                base_model_spe.load_weights(
                    f"/kaggle/input/pre-trained-weights/spe_extractor_notop.h5"
                )

            x_spe = base_model_spe(x_spe)
            x_spe = tf.keras.layers.GlobalAveragePooling2D()(x_spe)
            x_spe = tf.keras.layers.Dropout(0.5)(x_spe)

            inp.append(inp_spe)
            y = x_spe * 1

        if "eeg" in DATATYPE:
            inp_eeg = tf.keras.Input(
                shape=(
                    EEG_CHANNEL_USED * EEG_MULTIPLY,
                    round(EEG_LENGTH_USED * RSFREQ / EEG_MULTIPLY),
                ),
                name="eeg",
            )
            x_eeg_raw = tf.keras.layers.Reshape(
                (inp_eeg.shape[1], inp_eeg.shape[2], 1)
            )(inp_eeg)

            strides = 10
            if PLATFORM == "local":
                eeg_embed = tf.keras.layers.Conv1D(
                    filters=strides * 3,
                    kernel_size=strides,
                    strides=strides,
                    padding="same",
                    use_bias=False,
                    activation=None,
                    kernel_initializer=IniToOne(),
                    kernel_constraint=SumToOne(),
                    input_shape=(None, 1),
                )
            else:
                eeg_embed = tf.keras.layers.Conv1D(
                    filters=strides * 3,
                    kernel_size=strides,
                    strides=strides,
                    padding="same",
                    use_bias=False,
                    activation=None,
                )

            x_eeg = tf.keras.layers.TimeDistributed(eeg_embed)(x_eeg_raw)

            x_eeg = tf.keras.layers.Concatenate(axis=-1)(
                [
                    tf.keras.layers.Reshape((x_eeg.shape[1], x_eeg.shape[2], -1, 1))(
                        x_eeg[:, :, :, 0 * strides : 1 * strides]
                    ),
                    tf.keras.layers.Reshape((x_eeg.shape[1], x_eeg.shape[2], -1, 1))(
                        x_eeg[:, :, :, 1 * strides : 2 * strides]
                    ),
                    tf.keras.layers.Reshape((x_eeg.shape[1], x_eeg.shape[2], -1, 1))(
                        x_eeg[:, :, :, 2 * strides : 3 * strides]
                    ),
                ]
            )
            x_eeg = tf.keras.layers.Permute([4, 2, 1, 3])(x_eeg)
            x_eeg = tf.keras.layers.Reshape((x_eeg.shape[1], x_eeg.shape[2], -1))(x_eeg)
            x_eeg = tf.keras.layers.Permute((3, 2, 1))(x_eeg)

            base_model_eeg = tf.keras.applications.EfficientNetV2B0(
                include_top=False, weights=None, include_preprocessing=True
            )

            if PLATFORM == "local":
                base_model_eeg.load_weights(
                    f"./input/pre-trained-weights/eeg_extractor_notop.h5"
                )
            if PLATFORM == "kaggle":
                base_model_eeg.load_weights(
                    f"/kaggle/input/pre-trained-weights/eeg_extractor_notop.h5"
                )

            x_eeg = base_model_eeg(x_eeg)
            x_eeg = x_eeg[
                :, :, (x_eeg.shape[2] - 1) // 2 : (x_eeg.shape[2]) // 2 + 1, :
            ]
            x_eeg = tf.keras.layers.GlobalAveragePooling2D()(x_eeg)
            x_eeg = tf.keras.layers.Dropout(0.5)(x_eeg)

            inp.append(inp_eeg)
            y_eeg = tf.keras.layers.Dense(
                len(TARGETS), activation="softmax", dtype="float32"
            )(x_eeg)

        y = y_eeg * 1
        model = tf.keras.Model(inputs=inp, outputs=y)
        return model




## === cell 6
if NEEDTRAIN:

    def train_fold(
        i,
        stage,
        train_index,
        valid_index,
        df_train_stage1,
        df_valid_stage1,
        df_train_stage2,
        df_valid_stage2,
        build_model,
        BATCHSIZE,
        EPOCHS,
        LEARN_RATE,
        PATIENCE,
        TARGETS,
        TARGETS_RAW,
    ):
        print("#" * 25)
        print(f"### Fold {i + 1}")

        model = build_model()
        loss = tf.keras.losses.KLDivergence()

        if stage == 1:
            train_gen_stage = DataGenerator(
                df_train_stage1,
                shuffle=True,
                sample_weights=True,
                batch_size=BATCHSIZE,
                specs=spectrograms,
                eegs=eegs,
                stfts=stfts,
                imgs=imgs,
            )
            valid_gen_stage = DataGenerator(
                df_valid_stage1,
                shuffle=False,
                sample_weights=True,
                batch_size=BATCHSIZE * 2,
                mode="valid",
                specs=spectrograms,
                eegs=eegs,
                stfts=stfts,
                imgs=imgs,
            )
            opt = tf.keras.optimizers.AdamW(learning_rate=LEARN_RATE)
            callbacks_stage = [
                tf.keras.callbacks.LearningRateScheduler(
                    CosineAnnealingLRScheduler(EPOCHS, LEARN_RATE, LEARN_RATE * 0.01, 5)
                ),
                tf.keras.callbacks.ModelCheckpoint(
                    filepath=os.path.join("models", f"fold{i}_stage1.weights.h5"),
                    monitor="val_loss",
                    mode="min",
                    save_weights_only=True,
                    save_best_only=True,
                ),
            ]
        elif stage == 2:
            train_gen_stage = DataGenerator(
                df_train_stage2,
                shuffle=True,
                sample_weights=False,
                batch_size=BATCHSIZE,
                specs=spectrograms,
                eegs=eegs,
                stfts=stfts,
                imgs=imgs,
            )
            valid_gen_stage = DataGenerator(
                df_valid_stage2,
                shuffle=False,
                sample_weights=False,
                batch_size=BATCHSIZE * 2,
                mode="valid",
                specs=spectrograms,
                eegs=eegs,
                stfts=stfts,
                imgs=imgs,
            )
            opt = tf.keras.optimizers.AdamW(learning_rate=LEARN_RATE * 0.1)
            model.load_weights(os.path.join("models", f"fold{i}_stage1.weights.h5"))
            callbacks_stage = [
                tf.keras.callbacks.LearningRateScheduler(
                    CosineAnnealingLRScheduler(
                        max(round(EPOCHS / 3), 1),
                        LEARN_RATE * 0.1,
                        LEARN_RATE * 0.1 * 0.1,
                        0,
                    )
                ),
                tf.keras.callbacks.ModelCheckpoint(
                    filepath=os.path.join("models", f"fold{i}_stage2.weights.h5"),
                    monitor="val_loss",
                    mode="min",
                    save_weights_only=True,
                    save_best_only=True,
                ),
            ]

        model.compile(loss=loss, optimizer=opt)

        if stage == 1:
            history = model.fit(
                train_gen_stage,
                verbose=1,
                validation_data=valid_gen_stage,
                epochs=EPOCHS,
                callbacks=callbacks_stage,
            )
        elif stage == 2:
            history = model.fit(
                train_gen_stage,
                verbose=1,
                validation_data=valid_gen_stage,
                epochs=max(round(EPOCHS / 3), 1),
                callbacks=callbacks_stage,
            )

        model.load_weights(os.path.join("models", f"fold{i}_stage{stage}.weights.h5"))

        loss_hist = history.history["loss"]
        val_loss_hist = history.history["val_loss"]
        epochs_range = range(1, len(loss_hist) + 1)
        plt.figure()
        plt.plot(epochs_range, loss_hist, "bo", label="loss")
        plt.plot(epochs_range, val_loss_hist, "b", label="val_loss")
        plt.title(
            f"loss: {round(min(loss_hist), 4)}, val loss: {round(min(val_loss_hist), 4)}",
            fontsize=12,
        )
        plt.legend()
        plt.savefig(os.path.join("models", f"fold{i}_stage{stage}.svg"))
        plt.close()

        if stage == 1:
            valid_stage = df_valid_stage1[TARGETS].values
        elif stage == 2:
            valid_stage = df_valid_stage2[TARGETS].values
        predict_stage = model.predict(valid_gen_stage)

        del train_gen_stage, valid_gen_stage, history, model
        tf.keras.backend.clear_session()
        gc.collect()

        cm = confusion_matrix(np.argmax(valid_stage, 1), np.argmax(predict_stage, 1))
        cm = cm / np.sum(cm, 1, keepdims=True)

        plt.figure()
        plt.imshow(cm, interpolation="nearest", cmap=plt.cm.Blues)
        plt.title("Confusion Matrix")
        plt.colorbar()
        tick_marks = np.arange(6)
        plt.xticks(
            tick_marks, [f"{TARGETS[i][:-5]}" for i in [0, 1, 2, 3, 4, 5]], fontsize=10
        )
        plt.yticks(
            tick_marks, [f"{TARGETS[i][:-5]}" for i in [0, 1, 2, 3, 4, 5]], fontsize=10
        )
        thresh = cm.max() / 2.0
        for ii in range(cm.shape[0]):
            for jj in range(cm.shape[1]):
                if cm[ii, jj] > -0.1:
                    plt.text(
                        jj,
                        ii,
                        str(round(cm[ii, jj] * 1e4) * 1e-2)[:5],
                        horizontalalignment="center",
                        color="white" if cm[ii, jj] > thresh else "black",
                        fontsize=10,
                    )
        plt.xlabel("Predicted label")
        plt.ylabel("True label")
        plt.tight_layout()
        plt.savefig(os.path.join("models", f"fold{i}_stage{stage}_cm.svg"))
        plt.close()

        del df_train_stage1, df_valid_stage1, df_train_stage2, df_valid_stage2
        gc.collect()




## === cell 7
if __name__ == "__main__":
    if NEEDTRAIN:
        if not os.path.exists("models"):
            os.makedirs("models")

        from sklearn.model_selection import GroupKFold
        import multiprocessing as mp

        mp.set_start_method("spawn")

        gkf = GroupKFold(n_splits=SPLITS)

        for i, (train_index, valid_index) in enumerate(
            gkf.split(train, train.expert_consensus, train.patient_id)
        ):
            print("#" * 25)
            print(f"### Fold {i + 1}")

            df_train_stage1 = train.iloc[train_index].reset_index(drop=True)
            df_valid_stage1 = train.iloc[valid_index].reset_index(drop=True)

            df_train_stage2 = df_train_stage1[
                np.sum(df_train_stage1[TARGETS_RAW].values, 1) >= 10
            ].reset_index(drop=True)
            df_valid_stage2 = df_valid_stage1[
                np.sum(df_valid_stage1[TARGETS_RAW].values, 1) >= 10
            ].reset_index(drop=True)

            for stage in [1, 2]:
                p = mp.Process(
                    target=train_fold,
                    args=(
                        i,
                        stage,
                        train_index,
                        valid_index,
                        df_train_stage1,
                        df_valid_stage1,
                        df_train_stage2,
                        df_valid_stage2,
                        build_model,
                        BATCHSIZE,
                        EPOCHS,
                        LEARN_RATE,
                        PATIENCE,
                        TARGETS,
                        TARGETS_RAW,
                    ),
                )
                p.start()
                p.join()
    else:
        test = pd.read_csv(os.path.join(LOAD_DATA_FROM, "test.csv"))
        print("Test shape", test.shape)

        sample_sub = pd.read_csv(os.path.join(LOAD_DATA_FROM, "sample_submission.csv"))
        SUB_TARGETS = [c for c in sample_sub.columns if c != "eeg_id"]

        test_min = (
            test[["eeg_id", "patient_id"]].drop_duplicates(subset=["eeg_id"]).copy()
        )
        test_aligned = sample_sub[["eeg_id"]].merge(test_min, on="eeg_id", how="left")

        votes_sum_by_eeg = df.groupby("eeg_id", sort=False)[SUB_TARGETS].sum()
        total_votes_eeg = votes_sum_by_eeg.sum(axis=1).values.astype(np.float64)
        probs_by_eeg = votes_sum_by_eeg.values.astype(np.float64) / (
            total_votes_eeg.reshape(-1, 1) + 1e-12
        )

        global_prior = (probs_by_eeg * total_votes_eeg.reshape(-1, 1)).sum(axis=0) / (
            total_votes_eeg.sum() + 1e-12
        )
        global_prior = np.clip(global_prior, 1e-12, 1.0)
        global_prior = global_prior / global_prior.sum()

        eeg_patient = df.drop_duplicates("eeg_id")[["eeg_id", "patient_id"]]
        tmp = votes_sum_by_eeg.merge(
            eeg_patient, left_index=True, right_on="eeg_id", how="left"
        )
        patient_votes = (
            tmp.groupby("patient_id", sort=False)[SUB_TARGETS].sum().astype(np.float64)
        )
        patient_totals = patient_votes.sum(axis=1).values.astype(np.float64)
        patient_probs = patient_votes.values / (patient_totals.reshape(-1, 1) + 1e-12)
        patient_map = {
            pid: patient_probs[i] for i, pid in enumerate(patient_votes.index.values)
        }
        patient_total_map = {
            pid: float(patient_totals[i])
            for i, pid in enumerate(patient_votes.index.values)
        }

        k = len(SUB_TARGETS)
        m_equiv = 12.0  # ~ typical annotators per sample; calibrates uncertainty for KL
        dirichlet_alpha_global = global_prior * m_equiv  # vector alpha for global prior

        preds_all = np.zeros((len(sample_sub), k), dtype=np.float32)
        for i in range(len(sample_sub)):
            pid = test_aligned.loc[i, "patient_id"]
            if pid in patient_map:
                p_hat = patient_map[pid].copy()
                p_hat = np.clip(p_hat, 1e-12, 1.0)
                p_hat = p_hat / p_hat.sum()

                n_votes = patient_total_map.get(pid, 0.0)
                w = n_votes / (n_votes + 400.0)  # small, stable adjustment knob
                p_shrunk = w * p_hat + (1.0 - w) * global_prior

                pseudo_counts = p_shrunk * m_equiv
                p = (pseudo_counts + dirichlet_alpha_global) / (
                    pseudo_counts.sum() + dirichlet_alpha_global.sum() + 1e-12
                )
            else:
                p = (dirichlet_alpha_global + global_prior) / (
                    dirichlet_alpha_global.sum() + 1.0 + 1e-12
                )

            preds_all[i] = p.astype(np.float32)

        sub = sample_sub[["eeg_id"]].copy()
        sub[SUB_TARGETS] = preds_all

        sub[SUB_TARGETS] = np.clip(sub[SUB_TARGETS].values, 1e-7, 1.0)
        sub[SUB_TARGETS] = sub[SUB_TARGETS].values / sub[SUB_TARGETS].values.sum(
            axis=1, keepdims=True
        )

        sub.to_csv("submission.csv", index=False)
        print("Submission shape", sub.shape)
        print(sub.head())
        print(
            "Row prob sums (min/max):",
            sub[SUB_TARGETS].sum(1).min(),
            sub[SUB_TARGETS].sum(1).max(),
        )
