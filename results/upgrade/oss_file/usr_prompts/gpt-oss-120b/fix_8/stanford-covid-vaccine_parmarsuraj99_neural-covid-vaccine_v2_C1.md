# Goal

I want you to fix bugs and increase the score toward a target for a Kaggle competition solution. Here is the information you need.

# Requirements

- Keep changes minimal unless necessary.
- Preserve the core logic, including model architecture, layers, training approach/loops, feature extraction, or loss function. Maintain identical core logic and evaluation semantics; only allow negligible floating-point differences.
- Every change must be directly relevant to the stated issue (big fix and/or evaluation score improvement); avoid unrelated refactors or stylistic edits.
- Do NOT introduce extra approximations, sampling, reduced precision, early stopping, or relaxed convergence criteria.
- Ensure it runs end-to-end and produces a valid submission file.


# 1. Kaggle task description

## Overview
Predict likely degradation rates at each base of an RNA molecule.

## Metric
Mean columnwise root mean squared error:

$\textrm{MCRMSE} = \frac{1}{N_{t}}\sum_{j=1}^{N_{t}}\sqrt{\frac{1}{n} \sum_{i=1}^{n} (y_{ij} - \hat{y}_{ij})^2}$

where $N_{t}$ is the number of scored ground truth target columns, and $y$ and $\hat{y}$ are the actual and predicted values, respectively.

There are multiple ground truth values provided in the training data. While the submission format requires all 5 to be predicted, only the following are scored: reactivity, deg_Mg_pH10, and deg_Mg_50C.

## Submission Formats
For each sample `id` in the test set, you must predict targets for *each* sequence position (`seqpos`), one per row. If the length of the `sequence` of an `id` is, e.g., 107, then you should make 107 predictions. Positions greater than the `seq_scored` value of a sample are not scored, but still need a value in the solution file.

```csv
id_seqpos,reactivity,deg_Mg_pH10,deg_pH10,deg_Mg_50C,deg_50C
id_d190610e8_0,0.1,0.3,0.2,0.5,0.4
id_d190610e8_1,0.3,0.2,0.5,0.4,0.2
id_d190610e8_2,0.5,0.4,0.2,0.1,0.2
etc.
```

## Dataset 
- **train.json** - the training data
- **test.json** - the test set, without any columns associated with the ground truth.
- **sample_submission.csv** - a sample submission file in the correct format

#### Columns
- `id` - An arbitrary identifier for each sample.
- `seq_scored` - (68 in Train and Public Test, 68 in Private Test) Integer value denoting the number of positions used in scoring with predicted values. This should match the length of `reactivity`, `deg_*` and `*_error_*` columns.
- `seq_length` - (107 in Train and Public Test, 107 in Private Test) Integer values, denotes the length of `sequence`.
- `sequence` - (1x107 string in Train and Public Test, 107 in Private Test) Describes the RNA sequence, a combination of `A`, `G`, `U`, and `C` for each sample. Should be 107 characters long, and the first 68 bases should correspond to the 68 positions specified in `seq_scored` (note: indexed starting at 0).
- `structure` - (1x107 string in Train and Public Test, 107 in Private Test) An array of `(`, `)`, and `.` characters that describe whether a base is estimated to be paired or unpaired. Paired bases are denoted by opening and closing parentheses e.g. (....) means that base 0 is paired to base 5, and bases 1-4 are unpaired.
- `reactivity` - (1x68 vector in Train and Public Test, 1x68 in Private Test) An array of floating point numbers, should have the same length as `seq_scored`. These numbers are reactivity values for the first 68 bases as denoted in `sequence`, and used to determine the likely secondary structure of the RNA sample.
- `deg_pH10` - (1x68 vector in Train and Public Test, 1x68 in Private Test) An array of floating point numbers, should have the same length as `seq_scored`. These numbers are reactivity values for the first 68 bases as denoted in `sequence`, and used to determine the likelihood of degradation at the base/linkage after incubating without magnesium at high pH (pH 10).
- `deg_Mg_pH10` - (1x68 vector in Train and Public Test, 1x68 in Private Test) An array of floating point numbers, should have the same length as `seq_scored`. These numbers are reactivity values for the first 68 bases as denoted in `sequence`, and used to determine the likelihood of degradation at the base/linkage after incubating with magnesium in high pH (pH 10).
- `deg_50C` - (1x68 vector in Train and Public Test, 1x68 in Private Test) An array of floating point numbers, should have the same length as `seq_scored`. These numbers are reactivity values for the first 68 bases as denoted in `sequence`, and used to determine the likelihood of degradation at the base/linkage after incubating without magnesium at high temperature (50 degrees Celsius).
- `deg_Mg_50C` - (1x68 vector in Train and Public Test, 1x68 in Private Test) An array of floating point numbers, should have the same length as `seq_scored`. These numbers are reactivity values for the first 68 bases as denoted in `sequence`, and used to determine the likelihood of degradation at the base/linkage after incubating with magnesium at high temperature (50 degrees Celsius).
- `*_error_*` - An array of floating point numbers, should have the same length as the corresponding `reactivity` or `deg_*` columns, calculated errors in experimental values obtained in `reactivity` and `deg_*` columns.
- `predicted_loop_type` - (1x107 string) Describes the structural context (also referred to as 'loop type')of each character in `sequence`. Loop types assigned by bpRNA from Vienna RNAfold 2 structure. From the bpRNA_documentation: S: paired "Stem" M: Multiloop I: Internal loop B: Bulge H: Hairpin loop E: dangling End X: eXternal loop
    - `S/N filter` Indicates if the sample passed filters described below in `Additional Notes`.

#### Additional Notes
At the beginning of the competition, Stanford scientists have data on 2400 RNA sequences of length 107. For technical reasons, measurements cannot be carried out on the final bases of these RNA sequences, so we have experimental data (ground truth) in 5 conditions for the first 68 bases.

We have split out 240 of these 2400 sequences for a public test set to allow for continuous evaluation through the competition, on the public leaderboard. These sequences, in `test.json`, have been additionally filtered based on three criteria detailed below to ensure that this subset is not dominated by any large cluster of RNA molecules with poor data, which might bias the public leaderboard. The remaining 2160 sequences for which we have data are in `train.json`.

For our final and most important scoring (the Private Leaderbooard), Stanford scientists are carrying out measurements on 240 new RNAs. For these data, we expect to have measurements for the first 68 bases, again missing the ends of the RNA. These sequences constitute the 240 sequences in `test.json`.

For those interested in how the sequences in `test.json` were filtered, here were the steps to ensure a diverse and high quality test set for public leaderboard scoring:

1. Minimum value across all 5 conditions must be greater than -0.5.
2. Mean signal/noise across all 5 conditions must be greater than 1.0. [Signal/noise is defined as mean( measurement value over 68 nts )/mean( statistical error in measurement value over 68 nts)]
3. To help ensure sequence diversity, the resulting sequences were clustered into clusters with less than 50% sequence similarity, and the 240 test set sequences were chosen from clusters with 3 or fewer members. That is, any sequence in the test set should be sequence similar to at most 2 other sequences.

Note that these filters have not been applied to the 2160 RNAs in the public training data `train.json` -- some of those measurements have negative values or poor signal-to-noise, or some RNA sequences have near-identical sequences in that set. But we are providing all those data in case competitors can squeeze out more signal.

# 2. Python version

3.8

# 3. Installed packages

geopandas==0.14.4
numpy==1.26.4
pandas==2.2.3
pandas-datareader==0.10.0
pandas-gbq==0.29.2
pandas-profiling==3.6.6
pandas-stubs==2.2.2.240909
pandasql==0.7.3
protobuf==6.33.0
scikit-learn==1.2.2
scikit-learn-intelex==2025.9.0
sklearn-pandas==2.2.0
tensorflow==2.18.0
tensorflow-cloud==0.1.5
tensorflow-datasets==4.9.9
tensorflow_decision_forests==1.11.0
tensorflow-hub==0.16.1
tensorflow-io==0.37.1
tensorflow-io-gcs-filesystem==0.37.1
tensorflow-metadata==1.17.2
tensorflow-probability==0.25.0
tensorflow-text==2.18.1

# 4. Data file paths

```
/
    kaggle/
        data/
            description.md (125 lines)
            sample_submission.csv (25681 lines)
            sample_submission.csv.zip (74.8 kB)
            test.json (240 lines)
            train.json (2160 lines)
            stanford-covid-vaccine/
                description.md (125 lines)
                sample_submission.csv (25681 lines)
                ... and 3 other files
                stanford-covid-vaccine/
        input/
            description.md (125 lines)
            sample_submission.csv (25681 lines)
            sample_submission.csv.zip (74.8 kB)
            test.json (240 lines)
            train.json (2160 lines)
            stanford-covid-vaccine/
                description.md (125 lines)
                sample_submission.csv (25681 lines)
                ... and 3 other files
                stanford-covid-vaccine/
        working/
            stanford-covid-vaccine/
                description.md (125 lines)
                sample_submission.csv (25681 lines)
                ... and 3 other files
                stanford-covid-vaccine/
```

-> data/sample_submission.csv has 25680 rows and 6 columns.
The columns are: id_seqpos, reactivity, deg_Mg_pH10, deg_pH10, deg_Mg_50C, deg_50C

-> data/stanford-covid-vaccine/sample_submission.csv has 25680 rows and 6 columns.
The columns are: id_seqpos, reactivity, deg_Mg_pH10, deg_pH10, deg_Mg_50C, deg_50C

-> data/stanford-covid-vaccine/test.json has auto-generated json schema:
{
  "$schema": "http://json-schema.org/schema#",
  "type": "object",
  "properties": {
    "index": {
      "type": "integer"
    },
    "id": {
      "type": "string"
    },
    "sequence": {
      "type": "string"
    },
    "structure": {
      "type": "string"
    },
    "predicted_loop_type": {
      "type": "string"
    },
    "seq_length": {
      "type": "integer"
    },
    "seq_scored": {
      "type": "integer"
    }
  },
  "required": [
    "id",
    "index",
    "predicted_loop_type",
    "seq_length",
    "seq_scored",
    "sequence",
    "structure"
  ]
}

-> data/stanford-covid-vaccine/train.json has auto-generated json schema:
{
  "$schema": "http://json-schema.org/schema#",
  "type": "object",
  "properties": {
    "index": {
      "type": "integer"
    },
    "id": {
      "type": "string"
    },
    "sequence": {
      "type": "string"
    },
    "structure": {
      "type": "string"
    },
    "predicted_loop_type": {
      "type": "string"
    },
    "signal_to_noise": {
      "type": "number"
    },
    "SN_filter": {
      "type": "integer"
    },
    "seq_length": {
      "type": "integer"
    },
    "seq_scored": {
      "type": "integer"
    },
    "reactivity_error": {
      "type": "array",
      "items": {
        "type": "number"
      }
    },
    "deg_error_Mg_pH10": {
      "type": "array",
      "items": {
        "type": "number"
      }
    },
    "deg_error_pH10": {
      "type": "array",
      "items": {
        "type": "number"
      }
    },
    "deg_error_Mg_50C": {
      "type": "array",
      "items": {
        "type": "number"
      }
    },
    "deg_error_50C": {
      "type": "array",
      "items": {
        "type": "number"
      }
    },
    "reactivity": {
      "type": "array",
      "items": {
        "type": "number"
      }
    },
    "deg_Mg_pH10": {
      "type": "array",
      "items": {
        "type": "number"
      }
    },
    "deg_pH10": {
      "type": "array",
      "items": {
        "type": "number"
      }
    },
    "deg_Mg_50C": {
      "type": "array",
      "items": {
        "type": "number"
      }
    },
    "deg_50C": {
      "type": "array",
      "items": {
        "type": "number"
      }
    }
  },
  "required": [
    "SN_filter",
    "deg_50C",
    "deg_Mg_50C",
    "deg_Mg_pH10",
    "deg_error_50C",
    "deg_error_Mg_50C",
    "deg_error_Mg_pH10",
    "deg_error_pH10",
    "deg_pH10",
    "id",
    "index",
    "predicted_loop_type",
    "reactivity",
    "reactivity_error",
    "seq_length",
    "seq_scored",
    "sequence",
    "signal_to_noise",
    "structure"
  ]
}

-> data/test.json has auto-generated json schema:
{
  "$schema": "http://json-schema.org/schema#",
  "type": "object",
  "properties": {
    "index": {
      "type": "integer"
    },
    "id": {
      "type": "string"
    },
    "sequence": {
      "type": "string"
    },
    "structure": {
      "type": "string"
    },
    "predicted_loop_type": {
      "type": "string"
    },
    "seq_length": {
      "type": "integer"
    },
    "seq_scored": {
      "type": "integer"
    }
  },
  "required": [
    "id",
    "index",
    "predicted_loop_type",
    "seq_length",
    "seq_scored",
    "sequence",
    "structure"
  ]
}

-> data/train.json has auto-generated json schema:
{
  "$schema": "http://json-schema.org/schema#",
  "type": "object",
  "properties": {
    "index": {
      "type": "integer"
    },
    "id": {
      "type": "string"
    },
    "sequence": {
      "type": "string"
    },
    "structure": {
      "type": "string"
    },
    "predicted_loop_type": {
      "type": "string"
    },
    "signal_to_noise": {
      "type": "number"
    },
    "SN_filter": {
      "type": "integer"
    },
    "seq_length": {
      "type": "integer"
    },
    "seq_scored": {
      "type": "integer"
    },
    "reactivity_error": {
      "type": "array",
      "items": {
        "type": "number"
      }
    },
    "deg_error_Mg_pH10": {
      "type": "array",
      "items": {
        "type": "number"
      }
    },
    "deg_error_pH10": {
      "type": "array",
      "items": {
        "type": "number"
      }
    },
    "deg_error_Mg_50C": {
      "type": "array",
      "items": {
        "type": "number"
      }
    },
    "deg_error_50C": {
      "type": "array",
      "items": {
        "type": "number"
      }
    },
    "reactivity": {
      "type": "array",
      "items": {
        "type": "number"
      }
    },
    "deg_Mg_pH10": {
      "type": "array",
      "items": {
        "type": "number"
      }
    },
    "deg_pH10": {
      "type": "array",
      "items": {
        "type": "number"
      }
    },
    "deg_Mg_50C": {
      "type": "array",
      "items": {
        "type": "number"
      }
    },
    "deg_50C": {
      "type": "array",
      "items": {
        "type": "number"
      }
    }
  },
  "required": [
    "SN_filter",
    "deg_50C",
    "deg_Mg_50C",
    "deg_Mg_pH10",
    "deg_error_50C",
    "deg_error_Mg_50C",
    "deg_error_Mg_pH10",
    "deg_error_pH10",
    "deg_pH10",
    "id",
    "index",
    "predicted_loop_type",
    "reactivity",
    "reactivity_error",
    "seq_length",
    "seq_scored",
    "sequence",
    "signal_to_noise",
    "structure"
  ]
}

-> input/sample_submission.csv has 25680 rows and 6 columns.
The columns are: id_seqpos, reactivity, deg_Mg_pH10, deg_pH10, deg_Mg_50C, deg_50C

-> (stopped after 10 files for performance)

# 5. Target score

0.42891

# 6. Current score

0.32037

# 7. Whether higher score is better

Lower is better

# 8. Previous improvement plans

- What this solution (achieved 0.63794) has done: 'I remove the protobuf environment tweak that crashes TensorFlow, fix the model input handling by using three separate integer input streams (sequence, structure, loop type) instead of trying to split a combined tensor with a Lambda layer, and adjust the data preparation so each feature column is fed as its own NumPy array. These changes let the script run fully, produce predictions, and write a valid `submission.csv` while keeping the original architecture and training logic intact.'
- What this solution (achieved 0.31031) has done: 'I fixed the protobuf import issue by setting the required environment variable before TensorFlow is imported, corrected the target‑array stacking so the training labels have shape (samples, 107, 5), and tuned the model slightly (larger embeddings, more hidden units, lower dropout) to improve predictive performance while keeping the original architecture. The script now runs end‑to‑end and writes a proper submission.csv file.'
- What this solution (achieved 0.31551) has done: 'Implemented a minimal fix for the protobuf import error by setting the required environment variable **before any other library imports**. This prevents the `MessageFactory` attribute issue and allows TensorFlow to load correctly while keeping the original model architecture and training logic unchanged.'
- What this solution (achieved 0.31003) has done: 'Implemented two fixes:  
1. Set the protobuf environment variable **before any library imports** to prevent the `MessageFactory` import error.  
2. Replaced the direct tensor slicing in the model with a `Lambda` layer (`SliceSeqLen`) to avoid KerasTensor indexing issues, preserving the original architecture and training logic.'
- What this solution (achieved 0.32231) has done: 'I keep the existing pipeline but make two small, score‑neutral adjustments: increase the dropout rate in the model (to slightly reduce over‑fitting, nudging the validation error upward toward the target) and lower the training epochs a bit. These changes preserve the original architecture and data handling while ensuring the script runs end‑to‑end and produces a proper `submission.csv`.'
- What this solution (achieved 0.32037) has done: 'I moved the protobuf environment setting to the very top and reordered imports so TensorFlow loads after the variable is defined, which resolves the `MessageFactory` error. The rest of the pipeline is unchanged, ensuring the model trains and a proper `submission.csv` is written without altering performance.'

# 9. Code solution

## === cell 0
import os

os.environ["PROTOCOL_BUFFERS_PYTHON_IMPLEMENTATION"] = "python"

import gc
import numpy as np
import pandas as pd
import tensorflow as tf
from tensorflow.keras import layers as L
from tensorflow.keras.models import Model
from sklearn.preprocessing import LabelEncoder



## --- ERROR in cell 0, traceback:
---------------------------------------------------------------------------
AttributeError                            Traceback (most recent call last)
AttributeError: 'MessageFactory' object has no attribute 'GetPrototype'

## === cell 1
train_df = pd.read_json("/kaggle/input/stanford-covid-vaccine/train.json", lines=True)
test_df = pd.read_json("/kaggle/input/stanford-covid-vaccine/test.json", lines=True)
sample_df = pd.read_csv("/kaggle/input/stanford-covid-vaccine/sample_submission.csv")



## === cell 2
feature_columns = ["sequence", "structure", "predicted_loop_type"]
target_columns = ["reactivity", "deg_Mg_pH10", "deg_pH10", "deg_Mg_50C", "deg_50C"]



## === cell 3
label_encoders = dict()
for column in feature_columns:
    encoder = LabelEncoder()
    encoder.fit(list(set(train_df[column].apply(list).sum())))
    label_encoders[column] = encoder
    del encoder
    gc.collect()




## === cell 4
def transform_(df: pd.DataFrame, label_encoders: dict):
    for column in feature_columns:
        df[column + "_n"] = df[column].apply(
            lambda seq: label_encoders[column].transform(list(seq))
        )
    return df


train_df = transform_(train_df, label_encoders)
test_df = transform_(test_df, label_encoders)

train_seq_n = np.stack(train_df["sequence_n"].values)  # (samples, 107)
train_struct_n = np.stack(train_df["structure_n"].values)  # (samples, 107)
train_loop_n = np.stack(train_df["predicted_loop_type_n"].values)  # (samples, 107)

test_seq_n = np.stack(test_df["sequence_n"].values)  # (samples, 107)
test_struct_n = np.stack(test_df["structure_n"].values)  # (samples, 107)
test_loop_n = np.stack(test_df["predicted_loop_type_n"].values)  # (samples, 107)

target_arrays = [np.stack(train_df[col].values) for col in target_columns]
train_y = np.stack(target_arrays, axis=2)  # (samples, 68, 5)

pad_len = 107 - train_y.shape[1]
if pad_len > 0:
    train_y = np.concatenate(
        [
            train_y,
            np.zeros(
                (train_y.shape[0], pad_len, train_y.shape[2]), dtype=train_y.dtype
            ),
        ],
        axis=1,
    )  # now (samples, 107, 5)




## === cell 5
def build_model(seq_len=107, dropout=0.3, embed_dim=32, hidden_dim=128):
    inp_seq = L.Input(shape=(seq_len,), name="seq_input")
    inp_struct = L.Input(shape=(seq_len,), name="struct_input")
    inp_loop = L.Input(shape=(seq_len,), name="loop_input")

    embed_seq = L.Embedding(
        input_dim=len(label_encoders["sequence"].classes_), output_dim=embed_dim
    )(inp_seq)
    embed_struct = L.Embedding(
        input_dim=len(label_encoders["structure"].classes_), output_dim=embed_dim
    )(inp_struct)
    embed_loop = L.Embedding(
        input_dim=len(label_encoders["predicted_loop_type"].classes_),
        output_dim=embed_dim,
    )(inp_loop)

    cated_embed = L.Concatenate()([embed_seq, embed_struct, embed_loop])

    lstm_full = L.Bidirectional(
        L.LSTM(hidden_dim, dropout=dropout, return_sequences=True)
    )(cated_embed)

    lstm_0 = L.Bidirectional(
        L.LSTM(hidden_dim, dropout=dropout, return_sequences=True)
    )(embed_seq)
    lstm_1 = L.Bidirectional(
        L.LSTM(hidden_dim, dropout=dropout, return_sequences=True)
    )(embed_struct)
    lstm_2 = L.Bidirectional(
        L.LSTM(hidden_dim, dropout=dropout, return_sequences=True)
    )(embed_loop)

    lstm_0 = L.Bidirectional(
        L.LSTM(hidden_dim // 4, dropout=dropout, return_sequences=True)
    )(lstm_0)
    lstm_1 = L.Bidirectional(
        L.LSTM(hidden_dim // 4, dropout=dropout, return_sequences=True)
    )(lstm_1)
    lstm_2 = L.Bidirectional(
        L.LSTM(hidden_dim // 4, dropout=dropout, return_sequences=True)
    )(lstm_2)

    cat = L.Concatenate()([lstm_0, lstm_1, lstm_2, lstm_full])
    cat = L.Lambda(lambda x: x[:, :seq_len], name="SliceSeqLen")(cat)

    dense = L.Dense(5, activation="linear")(cat)

    model = Model(inputs=[inp_seq, inp_struct, inp_loop], outputs=dense)
    model.compile(loss="mse", optimizer="adam")
    return model




## === cell 6
model = build_model()
model.summary()



## === cell 7
model.fit(
    x=[train_seq_n, train_struct_n, train_loop_n],
    y=train_y,
    batch_size=64,
    epochs=20,
    callbacks=[tf.keras.callbacks.ReduceLROnPlateau(patience=3)],
    validation_split=0.3,
    verbose=2,
)



## === cell 8
test_preds = model.predict(
    [test_seq_n, test_struct_n, test_loop_n], verbose=1
)  # (samples, 107, 5)



## === cell 9
preds_ls = []
for idx, uid in enumerate(test_df["id"]):
    single_pred = test_preds[idx]  # (107,5)
    single_df = pd.DataFrame(single_pred, columns=target_columns)
    single_df["id_seqpos"] = [f"{uid}_{pos}" for pos in range(single_df.shape[0])]
    preds_ls.append(single_df)

preds_df = pd.concat(preds_ls, ignore_index=True)



## === cell 10
submission = sample_df[["id_seqpos"]].merge(preds_df, on="id_seqpos", how="left")
submission.to_csv("submission.csv", index=False)
