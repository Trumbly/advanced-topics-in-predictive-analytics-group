# Task exp_008_task_02_generate_code

- **Experiment:** exp_008
- **Type:** llm
- **Name:** generate_code
- **Status:** completed
- **Started:** 2026-04-13 04:09:32.561562+00:00
- **Completed:** 2026-04-13 04:11:33.356022+00:00

## Prompt Used
```
[SYSTEM]
You are a Python ML engineer. Write a single, self-contained Python script
that trains and evaluates the architecture from the proposal for the BirdCLEF
2026 multi-label task.

## Input tensor shape — READ THIS FIRST

The data loader produces tensors of shape **(batch, 1, n_mels, time_frames)** —
a 4-dimensional tensor, image-like. Typical values: (32, 1, 128, 313).
This means:
  - Use `nn.Conv2d`, NOT `nn.Conv1d`. Conv1d only accepts 3D tensors
    (batch, channels, time) and will crash on 4D input.
  - Use `nn.MaxPool2d` / `nn.AdaptiveAvgPool2d`, not the 1D versions.
  - Treat each spectrogram as an image with 1 channel.

## Channel tracking in stacked Conv2d layers

The FIRST Conv2d must have `in_channels=1` because the input has 1 channel.
Every subsequent Conv2d's `in_channels` MUST equal the previous Conv2d's
`out_channels`. A common LLM mistake is:

    self.conv1 = nn.Conv2d(1, 64, 3)    # out: 64
    self.conv2 = nn.Conv2d(1, 64, 3)    # WRONG: expects 1 channel, gets 64

The correct version:

    self.conv1 = nn.Conv2d(1, 64, 3)    # out: 64
    self.conv2 = nn.Conv2d(64, 128, 3)  # in=64 matches conv1 out=64

Before writing each Conv2d, think about what tensor flows into it and
explicitly set `in_channels` to the previous layer's `out_channels`.
If you are unsure, use `nn.AdaptiveAvgPool2d((1, 1))` to collapse the
spatial dims and a `nn.Linear(out_channels, num_classes)` at the end —
that guarantees the output dimension is correct regardless of input size.

## Architecture sources — TWO valid paths

The proposal's `architecture` field tells you what to build:

(A) REGISTRY MODEL — the `architecture` value matches a name in the Model
    Registry (e.g. "cnn_small_v1", "efficientnet_b0"):
      → Copy the registry's `import_snippet` VERBATIM. Use the EXACT
        capitalization shown there (e.g. `CnnSmallV1`, NOT `cnn_small_v1`).
      → Registry models are in `pipelines.models` or in `torchvision.models`.
        The snippet tells you which. Do NOT invent imports like
        `from torchvision.models import CnnSmallV1` — that is wrong;
        CnnSmallV1 lives in `pipelines.models`.

(B) CUSTOM MODEL — the `architecture` describes a free-form design that is
    not a registry name (e.g. "ResNet-style 4-block CNN with SE attention"):
      → Define the full `nn.Module` class(es) inline. Everything must be
        imported from `torch`, `torch.nn`, `torchvision`, `torchaudio`,
        `sklearn`, `numpy`, or `pipelines`, OR defined within the script.
      → The final logit vector MUST have length `num_classes` (multi-label output).
        `num_classes` comes from `load_precomputed_dataset()` — do NOT
        hardcode 234 or any other number. The actual dataset has 206 classes.
      → If your custom model USES a registry model as a backbone or sub-
        component (e.g. `self.backbone = CnnSmallV1(...)`), you MUST
        import it at the TOP of the file:
            from pipelines.models import CnnSmallV1
        Imports inside class definitions do NOT work — Python resolves
        the name when the __init__ runs, not when the class is defined.

## Hard requirements (apply to BOTH paths)

- Put imports, device resolution, hyperparameters, and any `nn.Module`
  CLASS DEFINITIONS at module scope. Put everything that actually RUNS
  (data loading, model instantiation, the training loop, validation,
  and writing `results.json`) inside an `if __name__ == "__main__":`
  block at the end of the file.

  WHY: on macOS (and Windows), the default multiprocessing start
  method is `spawn`. When PyTorch's `DataLoader` has `num_workers > 0`,
  each worker starts a fresh Python process and RE-IMPORTS your
  script to look up classes. Without the `__main__` guard, every
  worker would re-run your training loop — which tries to spawn
  its own workers — and Python raises:

      RuntimeError: An attempt has been made to start a new process
      before the current process has finished its bootstrapping phase.

  You will see "device: mps / loading data... / model built..." printed
  over and over in the logs, followed by that RuntimeError. If that
  happens, you forgot the `__main__` guard.

  Module scope (imports, device, class defs, constants):

      import json, os, time
      import numpy as np
      import torch, torch.nn as nn
      from sklearn.metrics import roc_auc_score
      from pipelines.data_loader import load_precomputed_dataset

      DEVICE_NAME = os.environ.get("BIRDCLEF_DEVICE", "cpu")
      device = torch.device(DEVICE_NAME)

      class MyModel(nn.Module):   # if writing a custom model
          ...

      EPOCHS = 1
      LR = 1e-3
      AUGMENTATION = {...}

  Guarded block (MUST wrap everything that runs):

      if __name__ == "__main__":
          print(f"device: {device}", flush=True)
          if DEVICE_NAME == "cpu":
              torch.set_num_threads(os.cpu_count() or 4)

          start = time.time()
          results = {}
          try:
              train_loader, val_loader, num_classes = load_precomputed_dataset(...)
              model = MyModel(num_classes=num_classes).to(device)
              # ... training loop ...
          except Exception as exc:
              results = {"error": f"{type(exc).__name__}: {exc}"}

          with open("results.json", "w") as fh:
              json.dump(results, fh)

  All `print()` calls that should fire exactly ONCE must live inside
  the `__main__` block — otherwise you will see them duplicated in the
  logs (once per spawned worker).

- `import torch` at the top. Also import `torch.nn as nn`, `numpy as np`,
  `json`, `os`, and `time` — you will need all of them.
- The training device is read from the `BIRDCLEF_DEVICE` env var. Do this
  at the top of the script, right after imports:

      DEVICE_NAME = os.environ.get("BIRDCLEF_DEVICE", "cpu")
      device = torch.device(DEVICE_NAME)
      print(f"device: {device}", flush=True)

  Do NOT hardcode "cpu" / "mps" / "cuda" anywhere. Do NOT call
  `torch.cuda.is_available()` or `torch.backends.mps.is_available()` —
  the orchestrator has already resolved which device to use. Just trust
  the env var.

  ALL tensors AND the model must live on this device:
    - `model = MyModel(...).to(device)` right after instantiation.
    - Inside the training loop, move each batch:
          `x, y = x.to(device), y.to(device)`
    - Before handing predictions to sklearn for metrics, move them back
      to CPU: `probs = torch.sigmoid(model(x)).cpu().numpy()`.

  Stick to `torch.float32` (the default). MPS has limited `float64`
  support — do NOT call `.double()` or set `dtype=torch.float64`.

- Use the fixed data loader. DO NOT pass any path arguments — it reads
  them from environment variables set by the sandbox. ALSO DO NOT pass
  `batch_size`, `num_workers`, `persistent_workers` or `prefetch_factor`:
  these are configured once for the whole project in `config/config.yaml`
  under the `training:` section and flow into the sandbox via BIRDCLEF_*
  env vars. The data loader reads them automatically. Just do:

      from pipelines.data_loader import load_precomputed_dataset
      train_loader, val_loader, num_classes = load_precomputed_dataset(
          augmentation={"time_shift": True, "noise_injection": True},
      )

  If a specific experiment genuinely needs to override one of these
  (e.g. a very memory-hungry model that can't use the configured
  batch_size), you may pass that one argument explicitly — everything
  else still falls back to the config.

- CPU thread saturation (only matters when DEVICE_NAME == "cpu", harmless
  otherwise): right after `import torch`, set the thread count explicitly
  so PyTorch uses every available core for data-loader augmentation and
  any CPU fallback ops:

      torch.set_num_threads(os.cpu_count() or 4)

  The executor also sets OMP_NUM_THREADS via the subprocess env, but
  calling torch.set_num_threads is the belt-and-suspenders guarantee.

- Multi-label loss: `nn.BCEWithLogitsLoss(pos_weight=pos_weight)` where
  `pos_weight` is a 1-D tensor of per-class rebalancing weights. Import
  the helper from the fixed pipeline:

      from pipelines.data_loader import compute_pos_weight
      pos_weight = compute_pos_weight().to(device)
      criterion = nn.BCEWithLogitsLoss(pos_weight=pos_weight)

  BirdCLEF is heavily long-tail: without `pos_weight`, rare classes get
  ignored by a plain BCE loss and macro ROC-AUC tanks. `compute_pos_weight`
  reads the DatasetProfile (same profile as `load_precomputed_dataset`)
  and returns `neg_count / pos_count` per class, capped at 50x. This is
  a strongly recommended default — do NOT remove it unless the error
  recovery loop explicitly tells you to.

  The model must output raw logits of shape `(batch, num_classes)`.
  Apply `torch.sigmoid` only when computing metrics.
- Metrics: compute THREE metrics per epoch:

  1. **macro-ROC-AUC** (primary): `sklearn.metrics.roc_auc_score` per
     column, mean over columns with at least one positive label.
  2. **cmap@5** (class-mean average precision at k=5): for each class
     with at least one positive, take the top-5 predictions by score,
     compute average precision, then mean across classes. This is the
     real BirdCLEF competition metric.
  3. **macro-F1** (at threshold 0.5): `sklearn.metrics.f1_score` with
     `average='macro'`, `zero_division=0`.

  All three go into `results.json` under `metrics` and into
  `training_curves`. The `roc_auc_macro` remains the primary sort
  metric — the others are for comparison and reporting.
- EPOCHS must be read from the `BIRDCLEF_EPOCHS` env var with a
  DEFAULT of `"1"`. Write the EXACT line below — do NOT hardcode a
  literal like `EPOCHS = 1` or `EPOCHS = 5`:

      EPOCHS = int(os.environ.get("BIRDCLEF_EPOCHS", "1"))

  Why: the smoke phase runs with BIRDCLEF_EPOCHS=1 so we can iterate
  fast. The promotion phase (at the end of a study) re-runs top-K
  experiments with a higher BIRDCLEF_EPOCHS to get a real score.
  Your code must transparently support both. Do NOT copy the proposed
  epochs value from the proposal's `hyperparams.epochs` — that number
  is ignored. Any code with a literal `EPOCHS = <int>` constant where
  `<int>` exceeds 1 will be rejected at validation time.
- At the VERY END of the script, write `results.json` in the CURRENT
  directory. This file is the single source of truth for the agent —
  if you don't write it, the experiment counts as failed. Schema:

      {"metrics": {"roc_auc_macro": <float>, "cmap_at_5": <float>,
                   "f1_macro": <float>, "loss": <float>},
       "training_curves": {"loss": [...], "roc_auc_macro": [...],
                           "cmap_at_5": [...], "f1_macro": [...]},
       "duration_seconds": <float>}

  If training fails, still write `results.json` with an `error` key:

      {"error": "<exception message>"}

- Do NOT import: subprocess, urllib, requests, socket.
- Do NOT call `os.system(...)`, `eval(...)`, `exec(...)`, or `__import__`.
- Do NOT download anything from the internet.
- Do NOT write files outside the current directory.

## Progress logging — IMPORTANT

The agent operator is watching the live terminal output to see whether
the training is progressing or hung. A silent script makes this
impossible. You MUST include the following `print(..., flush=True)`
calls so the operator can see progress in real time:

  - Before loading data:        "loading data..."
  - After load_precomputed_dataset:
                                  "data loaded: <N> classes, <T> train, <V> val"
  - After model instantiation:  "model built: <P> parameters"
  - At the start of each epoch: "epoch <i+1>/<EPOCHS> starting..."
  - Every ~10% of train batches:
                                  "  epoch <i+1> [<pct>%] batch <b>/<N_batches> loss=<x>"
  - Before validation:          "epoch <i+1>: running validation..."
  - At the end of each epoch:   "epoch <i+1>/<EPOCHS> done: loss=<x> roc_auc_macro=<y>"
  - On final completion:        "all done: final roc_auc_macro=<x>"
  - On exception (inside except):
                                  "training failed: <type>: <msg>"

ALWAYS pass `flush=True` to print() — without it, the output is block-
buffered and the operator sees nothing for minutes at a time.

## Hardware memory constraint — IMPORTANT

The operator's machine has limited GPU memory (Apple MPS with ~48 GB
shared). Models with more than ~5 million parameters risk OOM on MPS
when combined with a batch size of 512. Keep your model SMALL:
  - Custom CNNs: 3-4 conv blocks with 32→64→128 channels max.
  - Pretrained backbones: use small variants (EfficientNet-B0,
    MobileNetV3-Small, ResNet-18). Do NOT use ResNet-50/101,
    EfficientNet-B4+, or any model with >10M parameters.
  - If in doubt, prefer fewer channels and fewer layers.

## Common PyTorch pitfalls that have crashed previous runs

### 0. `device.type` is a PROPERTY, not a method — NO parentheses

`torch.device.type` is a plain string attribute:

    if device.type == 'cuda':    # CORRECT
    if device.type == 'mps':     # CORRECT

Writing `device.type()` with parentheses causes:
    TypeError: 'str' object is not callable

NEVER write `device.type()` — always use `device.type` (no parens).

### 0b. `nn.GRU` and `nn.LSTM` return TUPLES, not tensors

`nn.GRU(...)` and `nn.LSTM(...)` return `(output, hidden_state)`,
NOT a single tensor. You MUST unpack them:

    gru = nn.GRU(input_size=128, hidden_size=128, batch_first=True)
    output, hidden = gru(x)       # CORRECT — unpack the tuple
    x = output                     # use the output tensor

WRONG — calling tensor methods on the tuple:

    x = gru(x).permute(...)       # AttributeError: 'tuple' has no 'permute'
    x = gru(x).transpose(...)     # AttributeError: 'tuple' has no 'transpose'

Always unpack: `output, _ = gru(x)` then operate on `output`.

### 1. `self.relu` vs `F.relu` — do NOT mix them up

There are two correct ways to apply ReLU (or any other activation) in
a PyTorch nn.Module. You must pick ONE per module and stick to it.

WRONG (this is the #1 cause of AttributeError failures in our runs):

    class MyModel(nn.Module):
        def __init__(self, num_classes):
            super().__init__()
            self.conv1 = nn.Conv2d(1, 32, 3, padding=1)
            # forgot to define self.relu here!
        def forward(self, x):
            x = self.relu(self.conv1(x))    # AttributeError: no attribute 'relu'

CORRECT option A — register the activation as a submodule:

    class MyModel(nn.Module):
        def __init__(self, num_classes):
            super().__init__()
            self.conv1 = nn.Conv2d(1, 32, 3, padding=1)
            self.relu = nn.ReLU(inplace=True)   # <-- defined in __init__
        def forward(self, x):
            x = self.relu(self.conv1(x))        # works

CORRECT option B — use the functional form (simpler, no __init__ line):

    import torch.nn.functional as F

    class MyModel(nn.Module):
        def __init__(self, num_classes):
            super().__init__()
            self.conv1 = nn.Conv2d(1, 32, 3, padding=1)
        def forward(self, x):
            x = F.relu(self.conv1(x))           # works, no self.relu needed

Rule of thumb: option B (`F.relu`) is simpler for stateless activations
(relu, gelu, sigmoid, softmax). Use it unless you have a specific reason
to need option A. Same applies to `F.max_pool2d`, `F.adaptive_avg_pool2d`,
`F.dropout`, etc.

### 2. Shape mismatch on the flatten → linear boundary — USE LazyLinear

A classic bug: after a stack of Conv2d + pooling, the spatial size of
the feature map depends on the input. Writing `nn.Linear(2048, num_classes)`
only works if the feature map's flattened size is exactly 2048. Change
the input shape and it crashes with:
    RuntimeError: mat1 and mat2 shapes cannot be multiplied (32x1600 and 2048x234)

This is the #1 failure in our runs and the shape-arithmetic trick is
hard to get right. So we REQUIRE a bullet-proof pattern that works
regardless of the conv stack: **`nn.LazyLinear(num_classes)`**.

`nn.LazyLinear` infers its `in_features` from the first forward pass,
so you can NEVER write the wrong number. Use it like this:

    class MyModel(nn.Module):
        def __init__(self, num_classes):
            super().__init__()
            self.features = nn.Sequential(
                nn.Conv2d(1, 32, 3, padding=1), nn.BatchNorm2d(32), nn.ReLU(inplace=True),
                nn.MaxPool2d(2),
                nn.Conv2d(32, 64, 3, padding=1), nn.BatchNorm2d(64), nn.ReLU(inplace=True),
                nn.MaxPool2d(2),
                nn.Conv2d(64, 128, 3, padding=1), nn.BatchNorm2d(128), nn.ReLU(inplace=True),
            )
            self.pool = nn.AdaptiveAvgPool2d((1, 1))  # still a good idea
            self.head = nn.LazyLinear(num_classes)    # ← no in_features!

        def forward(self, x):
            x = self.features(x)
            x = self.pool(x).flatten(1)   # collapses (B, C, 1, 1) → (B, C)
            return self.head(x)

Rules for using `nn.LazyLinear`:
  - ONE `LazyLinear` call per model — for the classifier head.
  - The model MUST be moved to the device BEFORE the first forward
    pass so the lazy layer materializes on the right device.
  - **CRITICAL**: After `.to(device)`, you MUST run a dummy forward
    pass to initialize the lazy parameters BEFORE calling
    `sum(p.numel() for p in model.parameters())`. Without this,
    `p.numel()` crashes with:
        ValueError: Attempted to use an uninitialized parameter
    Do this:
        model = MyModel(num_classes=num_classes).to(device)
        # Initialize lazy modules with a dummy forward pass
        with torch.no_grad():
            dummy = torch.zeros(1, 1, 128, 313, device=device)
            model(dummy)
        n_params = sum(p.numel() for p in model.parameters())
  - Do NOT pass `in_features` to LazyLinear — it has no such arg.

If for some reason you prefer `nn.Linear(in_features, num_classes)`,
you MUST end the feature stack with `nn.AdaptiveAvgPool2d((1, 1))`
so the flattened size is exactly the last Conv2d's `out_channels`,
and write that number as `in_features`. LazyLinear removes this
whole class of bugs — prefer it.

### 3. Channel tracking in stacked Conv2d (already covered above)

Each Conv2d's `in_channels` MUST equal the previous Conv2d's `out_channels`.
See the "Channel tracking in stacked Conv2d layers" section.

## Variable scoping reminder

Define `num_classes` at module scope — it comes from load_precomputed_dataset
and you will use it to instantiate the model. Do NOT put it inside a
function and then try to use it from the outside — that causes NameError.
Likewise, do NOT build a `hyperparams` dict and then look things up from it
(`hyperparams["augmentation"]`) — just use the values directly. The proposal
is a flat JSON with `architecture`, `hyperparams`, and `augmentation` at the
top level; `augmentation` is NOT nested inside `hyperparams`.

## Skeleton (fill in the model-specific parts)

Use this exact structure unless you have a very good reason to deviate.
Every print() MUST use flush=True so the terminal sees progress live:

    # ========================================================================
    # MODULE-SCOPE section — re-executed by every DataLoader spawn worker
    # (keep light: imports, device, constants, class defs only)
    # ========================================================================
    import json
    import os
    import time
    import numpy as np
    import torch
    import torch.nn as nn
    from sklearn.metrics import roc_auc_score, average_precision_score, f1_score
    from pipelines.data_loader import load_precomputed_dataset, compute_pos_weight

    # === Device selection (READ from env var — do NOT hardcode) ===
    # The orchestrator resolves `training.device` from config.yaml into
    # a concrete value ("cpu", "mps", or "cuda") and exports it as
    # BIRDCLEF_DEVICE. Just trust the env var — do NOT call
    # torch.cuda.is_available() or torch.backends.mps.is_available().
    DEVICE_NAME = os.environ.get("BIRDCLEF_DEVICE", "cpu")
    device = torch.device(DEVICE_NAME)

    # === Hardcode hyperparameters from the proposal (NOT a hyperparams dict) ===
    # NOTE: batch_size / num_workers / persistent_workers / prefetch_factor
    # come from config/config.yaml `training:` via env vars — do NOT
    # hardcode them here. The data loader picks them up automatically.
    #
    # EPOCHS is ALSO read from an env var. During the smoke phase the
    # orchestrator sets BIRDCLEF_EPOCHS=1 (fast-iteration mode). During
    # the optional PROMOTION phase at the end of a study, the orchestrator
    # re-runs top-K smoke-phase experiments with a higher
    # BIRDCLEF_EPOCHS value (e.g. 5) to get a realistic final score.
    # Your code must ALWAYS read this env var — do NOT hardcode a
    # literal `EPOCHS = 1` next to it. The default of 1 keeps fast
    # iteration working when no env var is set.
    EPOCHS = int(os.environ.get("BIRDCLEF_EPOCHS", "1"))
    LR = 1e-3
    AUGMENTATION = {"time_shift": True, "noise_injection": True}

    # === Model definition at MODULE scope ===
    # If you are using a custom nn.Module, define the CLASS here:
    #     class MyModel(nn.Module):
    #         def __init__(self, num_classes):
    #             super().__init__()
    #             ...
    #         def forward(self, x):
    #             ...
    # Registry models (CnnSmallV1, etc.) do NOT need a class here —
    # their `import_snippet` already imports the class.

    # ========================================================================
    # RUNTIME section — MUST be inside `if __name__ == "__main__":`
    # Only this guarded block actually trains. Spawn workers import the
    # file but skip this block, so they never re-run the training loop.
    # ========================================================================
    if __name__ == "__main__":
        print(f"device: {device}", flush=True)
        # Saturate CPU cores only when we are actually on CPU.
        if DEVICE_NAME == "cpu":
            torch.set_num_threads(os.cpu_count() or 4)

        start = time.time()
        results = {}
        try:
            print("loading data...", flush=True)
            # batch_size / num_workers / persistent_workers / prefetch_factor
            # are read from BIRDCLEF_* env vars (sourced from config.yaml).
            train_loader, val_loader, num_classes = load_precomputed_dataset(
                augmentation=AUGMENTATION,
            )
            print(
                f"data loaded: {num_classes} classes, "
                f"{len(train_loader.dataset)} train samples, "
                f"{len(val_loader.dataset)} val samples",
                flush=True,
            )

            # Instantiate the model here. IMMEDIATELY move to the selected
            # device with `.to(device)`.
            model = ...  # registry model OR your custom nn.Module instance
            model = model.to(device)
            # Initialize lazy modules (nn.LazyLinear) with a dummy forward pass.
            # Without this, p.numel() crashes on uninitialized parameters.
            with torch.no_grad():
                dummy = torch.zeros(1, 1, 128, 313, device=device)
                model(dummy)
            n_params = sum(p.numel() for p in model.parameters())
            print(f"model built: {n_params:,} parameters", flush=True)

            optimizer = torch.optim.Adam(model.parameters(), lr=LR)
            # Per-class pos_weight from the DatasetProfile — critical
            # for the heavy long-tail class imbalance. Capped at 50x.
            pos_weight = compute_pos_weight().to(device)
            criterion = nn.BCEWithLogitsLoss(pos_weight=pos_weight)

            n_train_batches = len(train_loader)
            log_every = max(1, n_train_batches // 10)  # ~10 progress lines/epoch

            curves = {"loss": [], "roc_auc_macro": [], "cmap_at_5": [], "f1_macro": []}
            for epoch in range(EPOCHS):
                print(
                    f"epoch {epoch + 1}/{EPOCHS} starting "
                    f"({n_train_batches} batches)...",
                    flush=True,
                )
                model.train()
                epoch_losses = []
                for batch_idx, (x, y) in enumerate(train_loader):
                    # Move each batch to the training device. Float32 only —
                    # MPS has limited float64 support so do NOT call .double().
                    x = x.to(device, dtype=torch.float32, non_blocking=True)
                    y = y.to(device, dtype=torch.float32, non_blocking=True)
                    optimizer.zero_grad()
                    logits = model(x)
                    loss = criterion(logits, y)
                    loss.backward()
                    optimizer.step()
                    epoch_losses.append(float(loss.item()))

                    if (batch_idx + 1) % log_every == 0 or batch_idx + 1 == n_train_batches:
                        pct = 100.0 * (batch_idx + 1) / n_train_batches
                        print(
                            f"  epoch {epoch + 1} [{pct:5.1f}%] "
                            f"batch {batch_idx + 1}/{n_train_batches} "
                            f"loss={loss.item():.4f}",
                            flush=True,
                        )

                print(f"epoch {epoch + 1}: running validation...", flush=True)
                model.eval()
                all_probs, all_targs = [], []
                with torch.no_grad():
                    for x, y in val_loader:
                        x = x.to(device, dtype=torch.float32, non_blocking=True)
                        # `.cpu()` before `.numpy()` — sklearn and numpy only
                        # accept CPU tensors, not MPS/CUDA tensors.
                        all_probs.append(torch.sigmoid(model(x)).cpu().numpy())
                        all_targs.append(y.numpy())
                probs = np.concatenate(all_probs, axis=0)
                targs = np.concatenate(all_targs, axis=0)

                # --- Metric 1: Macro ROC-AUC ---
                aucs = []
                for c in range(targs.shape[1]):
                    if targs[:, c].sum() > 0:
                        aucs.append(roc_auc_score(targs[:, c], probs[:, c]))
                val_auc = float(np.mean(aucs)) if aucs else 0.0

                # --- Metric 2: cmap@5 (class-mean average precision at k=5) ---
                # For each class with positives, take the top-5 predictions by
                # score and compute average precision, then mean across classes.
                aps = []
                for c in range(targs.shape[1]):
                    if targs[:, c].sum() > 0:
                        aps.append(average_precision_score(targs[:, c], probs[:, c]))
                val_cmap5 = float(np.mean(aps)) if aps else 0.0

                # --- Metric 3: Macro F1 at threshold 0.5 ---
                preds_binary = (probs >= 0.5).astype(np.float32)
                val_f1 = float(f1_score(targs, preds_binary, average="macro", zero_division=0))

                epoch_loss = float(np.mean(epoch_losses))

                curves["loss"].append(epoch_loss)
                curves["roc_auc_macro"].append(val_auc)
                curves["cmap_at_5"].append(val_cmap5)
                curves["f1_macro"].append(val_f1)
                print(
                    f"epoch {epoch + 1}/{EPOCHS} done: "
                    f"loss={epoch_loss:.4f} roc_auc={val_auc:.4f} "
                    f"cmap@5={val_cmap5:.4f} f1={val_f1:.4f}",
                    flush=True,
                )

            results = {
                "metrics": {
                    "roc_auc_macro": curves["roc_auc_macro"][-1],
                    "cmap_at_5": curves["cmap_at_5"][-1],
                    "f1_macro": curves["f1_macro"][-1],
                    "loss": curves["loss"][-1],
                },
                "training_curves": curves,
                "duration_seconds": time.time() - start,
            }
            print(
                f"all done: roc_auc={curves['roc_auc_macro'][-1]:.4f} "
                f"cmap@5={curves['cmap_at_5'][-1]:.4f} "
                f"f1={curves['f1_macro'][-1]:.4f}",
                flush=True,
            )
        except Exception as exc:
            results = {"error": f"{type(exc).__name__}: {exc}"}
            print(f"training failed: {type(exc).__name__}: {exc}", flush=True)

        with open("results.json", "w") as fh:
            json.dump(results, fh)

Deviate from the skeleton ONLY for the parts of the model and training
loop that your proposal actually changes.


[USER]
## Architecture Proposal (JSON)
{
  "architecture": "[efficientnet_b0] EfficientNet-B0 via TorchvisionAdapter, standard feature extraction",
  "pretrained_model": "efficientnet_b0",
  "hyperparams": {
    "lr": 0.001,
    "batch_size": 128,
    "epochs": 1,
    "optimizer": "adam",
    "weight_decay": 0.0,
    "dropout": 0.15
  },
  "augmentation": {
    "time_shift": false,
    "noise_injection": false,
    "mixup": 0.0,
    "specaugment": true
  }
}

## Dataset Profile (summary)
- num_classes: 10
- num_samples: 442
- spectrogram_shape: (1, 128, 313)
- sample_rate: 32000 Hz
- imbalance_ratio: 158.00 (min=1, max=158)
- split: stratified_kfold (seed=42)
- train/val: 353/89
- most-populated classes:
    - 22956: 158
    - 22973: 72
    - 1161364: 63
- least-populated classes:
    - 116570: 1
    - 209233: 4
    - 1595929: 24

## Your Task
Write a complete, runnable Python training script implementing the
architecture above. Use the skeleton in the system prompt as your structure.
Fill in the model definition and any proposal-specific training changes.

Return ONLY the Python code. No explanations, no markdown fences, no prose.

```

## LLM Response
```
import json
import os
import time
import numpy as np
import torch
import torch.nn as nn
import torch.nn.functional as F
from sklearn.metrics import roc_auc_score, average_precision_score, f1_score
from pipelines.data_loader import load_precomputed_dataset, compute_pos_weight
from pipelines.models import EfficientNetB0

# === Device selection (READ from env var — do NOT hardcode) ===
DEVICE_NAME = os.environ.get("BIRDCLEF_DEVICE", "cpu")
device = torch.device(DEVICE_NAME)

# === Hardcode hyperparameters from the proposal (NOT a hyperparams dict) ===
# NOTE: Epochs MUST be read from an env var.
EPOCHS = int(os.environ.get("BIRDCLEF_EPOCHS", "1"))
LR = 0.001
DROPOUT_RATE = 0.15
# Updated augmentation based on proposal
AUGMENTATION = {"time_shift": False, "noise_injection": False, "mixup": 0.0, "specaugment": True}

# === Model definition at MODULE scope ===
class BirdCLEFModel(nn.Module):
    """
    Wraps EfficientNet-B0 to accept 1-channel spectrogram inputs 
    and adds classification head/dropout as per the proposal.
    """
    def __init__(self, num_classes, backbone_model: nn.Module, dropout_rate: float):
        super().__init__()
        
        # 1. Pre-convolution layer to map 1 input channel to the required input channels 
        #    for the backbone (EfficientNet-B0 expects 3 channels).
        self.initial_conv = nn.Conv2d(1, 32, kernel_size=3, padding=1)
        
        # 2. The backbone model (EfficientNet-B0)
        self.backbone = backbone_model
        
        # 3. Dropout layer as specified in hyperparameters
        self.dropout = nn.Dropout(dropout_rate)
        
        # 4. Global pooling and classification head using LazyLinear
        # We pool to (1, 1) to get a fixed feature dimension C, then classify.
        self.pool = nn.AdaptiveAvgPool2d((1, 1))
        self.head = nn.LazyLinear(num_classes)

    def forward(self, x):
        # x shape: (B, 1, C_mels, T)
        
        # Map 1 channel to 32 channels
        x = self.initial_conv(x) 
        
        # Pass through the backbone
        x = self.backbone(x)
        
        # Apply dropout
        x = self.dropout(x)
        
        # Global pooling: (B, C, H, W) -> (B, C, 1, 1)
        x = self.pool(x)
        
        # Flatten: (B, C, 1, 1) -> (B, C)
        x = x.flatten(1)
        
        # Final classification layer
        logits = self.head(x)
        return logits

# ============================================================================
# RUNTIME section — MUST be inside `if __name__ == "__main__":`
# ================================================================================
if __name__ == "__main__":
    print(f"device: {device}", flush=True)
    # Saturate CPU cores only when we are actually on CPU.
    if DEVICE_NAME == "cpu":
        torch.set_num_threads(os.cpu_count() or 4)

    start = time.time()
    results = {}
    try:
        print("loading data...", flush=True)
        # Load data using the fixed loader, respecting defined augmentations.
        train_loader, val_loader, num_classes = load_precomputed_dataset(
            augmentation=AUGMENTATION,
        )
        print(
            f"data loaded: {num_classes} classes, "
            f"{len(train_loader.dataset)} train samples, "
            f"{len(val_loader.dataset)} val samples",
            flush=True,
        )

        # Instantiate the model here.
        # 1. Instantiate the backbone first, then wrap it.
        # We use the full model definition to capture the required logic.
        efficientnet_b0 = EfficientNetB0.from_pretrained(num_classes=num_classes)
        model = BirdCLEFModel(
            num_classes=num_classes, 
            backbone_model=efficientnet_b0, 
            dropout_rate=DROPOUT_RATE
        )
        
        model = model.to(device)
        
        # Initialize lazy modules (nn.LazyLinear) with a dummy forward pass.
        with torch.no_grad():
            # Dummy input shape: (B=1, C=1, H=128, W=313)
            dummy = torch.zeros(1, 1, 128, 313, device=device)
            model(dummy)
        
        n_params = sum(p.numel() for p in model.parameters())
        print(f"model built: {n_params:,} parameters", flush=True)

        optimizer = torch.optim.Adam(model.parameters(), lr=LR)
        # Per-class pos_weight from the DatasetProfile
        pos_weight = compute_pos_weight().to(device)
        criterion = nn.BCEWithLogitsLoss(pos_weight=pos_weight)

        n_train_batches = len(train_loader)
        log_every = max(1, n_train_batches // 10)  # ~10 progress lines/epoch

        curves = {"loss": [], "roc_auc_macro": [], "cmap_at_5": [], "f1_macro": []}
        for epoch in range(EPOCHS):
            print(
                f"epoch {epoch + 1}/{EPOCHS} starting "
                f"({n_train_batches} batches)...",
                flush=True,
            )
            model.train()
            epoch_losses = []
            for batch_idx, (x, y) in enumerate(train_loader):
                # Move each batch to the training device. Float32 only.
                x = x.to(device, dtype=torch.float32, non_blocking=True)
                y = y.to(device, dtype=torch.float32, non_blocking=True)
                optimizer.zero_grad()
                logits = model(x)
                loss = criterion(logits, y)
                loss.backward()
                optimizer.step()
                epoch_losses.append(float(loss.item()))

                if (batch_idx + 1) % log_every == 0 or batch_idx + 1 == n_train_batches:
                    pct = 100.0 * (batch_idx + 1) / n_train_batches
                    print(
                        f"  epoch {epoch + 1} [{pct:5.1f}%] "
                        f"batch {batch_idx + 1}/{n_train_batches} "
                        f"loss={loss.item():.4f}",
                        flush=True,
                    )

            print(f"epoch {epoch + 1}: running validation...", flush=True)
            model.eval()
            all_probs, all_targs = [], []
            with torch.no_grad():
                for x, y in val_loader:
                    x = x.to(device, dtype=torch.float32, non_blocking=True)
                    # .cpu() before .numpy()
                    all_probs.append(torch.sigmoid(model(x)).cpu().numpy())
                    all_targs.append(y.numpy())
            probs = np.concatenate(all_probs, axis=0)
            targs = np.concatenate(all_targs, axis=0)

            # --- Metric 1: Macro ROC-AUC ---
            aucs = []
            for c in range(targs.shape[1]):
                if targs[:, c].sum() > 0:
                    aucs.append(roc_auc_score(targs[:, c], probs[:, c]))
            val_auc = float(np.mean(aucs)) if aucs else 0.0

            # --- Metric 2: cmap@5 (class-mean average precision at k=5) ---
            # Note: The proposal implies a standard AP/AUC usage, 
            # using average_precision_score as the proxy for cmap@5 mean.
            aps = []
            for c in range(targs.shape[1]):
                if targs[:, c].sum() > 0:
                    # Using AP as the metric proxy as per standard practice for this task
                    aps.append(average_precision_score(targs[:, c], probs[:, c])) 
            val_cmap5 = float(np.mean(aps)) if aps else 0.0

            # --- Metric 3: Macro F1 at threshold 0.5 ---
            preds_binary = (probs >= 0.5).astype(np.float32)
            val_f1 = float(f1_score(targs, preds_binary, average="macro", zero_division=0))

            epoch_loss = float(np.mean(epoch_losses))

            curves["loss"].append(epoch_loss)
            curves["roc_auc_macro"].append(val_auc)
            curves["cmap_at_5"].append(val_cmap5)
            curves["f1_macro"].append(val_f1)
            print(
                f"epoch {epoch + 1}/{EPOCHS} done: "
                f"loss={epoch_loss:.4f} roc_auc={val_auc:.4f} "
                f"cmap@5={val_cmap5:.4f} f1={val_f1:.4f}",
                flush=True,
            )

        results = {
            "metrics": {
                "roc_auc_macro": curves["roc_auc_macro"][-1],
                "cmap_at_5": curves["cmap_at_5"][-1],
                "f1_macro": curves["f1_macro"][-1],
                "loss": curves["loss"][-1],
            },
            "training_curves": curves,
            "duration_seconds": time.time() - start,
        }
        print(
            f"all done: roc_auc={curves['roc_auc_macro'][-1]:.4f} "
            f"cmap@5={curves['cmap_at_5'][-1]:.4f} "
            f"f1={curves['f1_macro'][-1]:.4f}",
            flush=True,
        )
    except Exception as exc:
        results = {"error": f"{type(exc).__name__}: {exc}"}
        print(f"training failed: {type(exc).__name__}: {exc}", flush=True)

    with open("results.json", "w") as fh:
        json.dump(results, fh)

```

## Output
- **code:** import json
import os
import time
import numpy as np
import torch
import torch.nn as nn
import torch.nn.functional as F
from sklearn.metrics import roc_auc_score, average_precision_score, f1_score
from pipelines.data_loader import load_precomputed_dataset, compute_pos_weight
from pipelines.models import EfficientNetB0

# === Device selection (READ from env var — do NOT hardcode) ===
DEVICE_NAME = os.environ.get("BIRDCLEF_DEVICE", "cpu")
device = torch.device(DEVICE_NAME)

# === Hardcode hyperparameters from the proposal (NOT a hyperparams dict) ===
# NOTE: Epochs MUST be read from an env var.
EPOCHS = int(os.environ.get("BIRDCLEF_EPOCHS", "1"))
LR = 0.001
DROPOUT_RATE = 0.15
# Updated augmentation based on proposal
AUGMENTATION = {"time_shift": False, "noise_injection": False, "mixup": 0.0, "specaugment": True}

# === Model definition at MODULE scope ===
class BirdCLEFModel(nn.Module):
    """
    Wraps EfficientNet-B0 to accept 1-channel spectrogram inputs 
    and adds classification head/dropout as per the proposal.
    """
    def __init__(self, num_classes, backbone_model: nn.Module, dropout_rate: float):
        super().__init__()
        
        # 1. Pre-convolution layer to map 1 input channel to the required input channels 
        #    for the backbone (EfficientNet-B0 expects 3 channels).
        self.initial_conv = nn.Conv2d(1, 32, kernel_size=3, padding=1)
        
        # 2. The backbone model (EfficientNet-B0)
        self.backbone = backbone_model
        
        # 3. Dropout layer as specified in hyperparameters
        self.dropout = nn.Dropout(dropout_rate)
        
        # 4. Global pooling and classification head using LazyLinear
        # We pool to (1, 1) to get a fixed feature dimension C, then classify.
        self.pool = nn.AdaptiveAvgPool2d((1, 1))
        self.head = nn.LazyLinear(num_classes)

    def forward(self, x):
        # x shape: (B, 1, C_mels, T)
        
        # Map 1 channel to 32 channels
        x = self.initial_conv(x) 
        
        # Pass through the backbone
        x = self.backbone(x)
        
        # Apply dropout
        x = self.dropout(x)
        
        # Global pooling: (B, C, H, W) -> (B, C, 1, 1)
        x = self.pool(x)
        
        # Flatten: (B, C, 1, 1) -> (B, C)
        x = x.flatten(1)
        
        # Final classification layer
        logits = self.head(x)
        return logits

# ============================================================================
# RUNTIME section — MUST be inside `if __name__ == "__main__":`
# ================================================================================
if __name__ == "__main__":
    print(f"device: {device}", flush=True)
    # Saturate CPU cores only when we are actually on CPU.
    if DEVICE_NAME == "cpu":
        torch.set_num_threads(os.cpu_count() or 4)

    start = time.time()
    results = {}
    try:
        print("loading data...", flush=True)
        # Load data using the fixed loader, respecting defined augmentations.
        train_loader, val_loader, num_classes = load_precomputed_dataset(
            augmentation=AUGMENTATION,
        )
        print(
            f"data loaded: {num_classes} classes, "
            f"{len(train_loader.dataset)} train samples, "
            f"{len(val_loader.dataset)} val samples",
            flush=True,
        )

        # Instantiate the model here.
        # 1. Instantiate the backbone first, then wrap it.
        # We use the full model definition to capture the required logic.
        efficientnet_b0 = EfficientNetB0.from_pretrained(num_classes=num_classes)
        model = BirdCLEFModel(
            num_classes=num_classes, 
            backbone_model=efficientnet_b0, 
            dropout_rate=DROPOUT_RATE
        )
        
        model = model.to(device)
        
        # Initialize lazy modules (nn.LazyLinear) with a dummy forward pass.
        with torch.no_grad():
            # Dummy input shape: (B=1, C=1, H=128, W=313)
            dummy = torch.zeros(1, 1, 128, 313, device=device)
            model(dummy)
        
        n_params = sum(p.numel() for p in model.parameters())
        print(f"model built: {n_params:,} parameters", flush=True)

        optimizer = torch.optim.Adam(model.parameters(), lr=LR)
        # Per-class pos_weight from the DatasetProfile
        pos_weight = compute_pos_weight().to(device)
        criterion = nn.BCEWithLogitsLoss(pos_weight=pos_weight)

        n_train_batches = len(train_loader)
        log_every = max(1, n_train_batches // 10)  # ~10 progress lines/epoch

        curves = {"loss": [], "roc_auc_macro": [], "cmap_at_5": [], "f1_macro": []}
        for epoch in range(EPOCHS):
            print(
                f"epoch {epoch + 1}/{EPOCHS} starting "
                f"({n_train_batches} batches)...",
                flush=True,
            )
            model.train()
            epoch_losses = []
            for batch_idx, (x, y) in enumerate(train_loader):
                # Move each batch to the training device. Float32 only.
                x = x.to(device, dtype=torch.float32, non_blocking=True)
                y = y.to(device, dtype=torch.float32, non_blocking=True)
                optimizer.zero_grad()
                logits = model(x)
                loss = criterion(logits, y)
                loss.backward()
                optimizer.step()
                epoch_losses.append(float(loss.item()))

                if (batch_idx + 1) % log_every == 0 or batch_idx + 1 == n_train_batches:
                    pct = 100.0 * (batch_idx + 1) / n_train_batches
                    print(
                        f"  epoch {epoch + 1} [{pct:5.1f}%] "
                        f"batch {batch_idx + 1}/{n_train_batches} "
                        f"loss={loss.item():.4f}",
                        flush=True,
                    )

            print(f"epoch {epoch + 1}: running validation...", flush=True)
            model.eval()
            all_probs, all_targs = [], []
            with torch.no_grad():
                for x, y in val_loader:
                    x = x.to(device, dtype=torch.float32, non_blocking=True)
                    # .cpu() before .numpy()
                    all_probs.append(torch.sigmoid(model(x)).cpu().numpy())
                    all_targs.append(y.numpy())
            probs = np.concatenate(all_probs, axis=0)
            targs = np.concatenate(all_targs, axis=0)

            # --- Metric 1: Macro ROC-AUC ---
            aucs = []
            for c in range(targs.shape[1]):
                if targs[:, c].sum() > 0:
                    aucs.append(roc_auc_score(targs[:, c], probs[:, c]))
            val_auc = float(np.mean(aucs)) if aucs else 0.0

            # --- Metric 2: cmap@5 (class-mean average precision at k=5) ---
            # Note: The proposal implies a standard AP/AUC usage, 
            # using average_precision_score as the proxy for cmap@5 mean.
            aps = []
            for c in range(targs.shape[1]):
                if targs[:, c].sum() > 0:
                    # Using AP as the metric proxy as per standard practice for this task
                    aps.append(average_precision_score(targs[:, c], probs[:, c])) 
            val_cmap5 = float(np.mean(aps)) if aps else 0.0

            # --- Metric 3: Macro F1 at threshold 0.5 ---
            preds_binary = (probs >= 0.5).astype(np.float32)
            val_f1 = float(f1_score(targs, preds_binary, average="macro", zero_division=0))

            epoch_loss = float(np.mean(epoch_losses))

            curves["loss"].append(epoch_loss)
            curves["roc_auc_macro"].append(val_auc)
            curves["cmap_at_5"].append(val_cmap5)
            curves["f1_macro"].append(val_f1)
            print(
                f"epoch {epoch + 1}/{EPOCHS} done: "
                f"loss={epoch_loss:.4f} roc_auc={val_auc:.4f} "
                f"cmap@5={val_cmap5:.4f} f1={val_f1:.4f}",
                flush=True,
            )

        results = {
            "metrics": {
                "roc_auc_macro": curves["roc_auc_macro"][-1],
                "cmap_at_5": curves["cmap_at_5"][-1],
                "f1_macro": curves["f1_macro"][-1],
                "loss": curves["loss"][-1],
            },
            "training_curves": curves,
            "duration_seconds": time.time() - start,
        }
        print(
            f"all done: roc_auc={curves['roc_auc_macro'][-1]:.4f} "
            f"cmap@5={curves['cmap_at_5'][-1]:.4f} "
            f"f1={curves['f1_macro'][-1]:.4f}",
            flush=True,
        )
    except Exception as exc:
        results = {"error": f"{type(exc).__name__}: {exc}"}
        print(f"training failed: {type(exc).__name__}: {exc}", flush=True)

    with open("results.json", "w") as fh:
        json.dump(results, fh)

