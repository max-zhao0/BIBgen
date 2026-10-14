# Preprocessing and Readying Data

## File Conversion
Run ``python convert_slcio_files.py -i [inputfiles] -o [outputfile]`` on a machine with pyLCIO configured. ``inputfiles`` should be LCIO format, ``outputfile`` should end with ``.hdf5``.

## Make Training Data

```bash
python make_training_data.py [mm_file] [mp_file] -o [outfile] -s [train,val,test] -c -p [phi_window]
```

By default, the energy feature is stored as ``ln(E)`` rather than raw ``E``. Pass ``--raw-energy``
to store raw ``E`` instead. The chosen setting is stamped into the output file
(``f["transformation"].attrs["log_energy"]``) so downstream scripts can detect it automatically.

## Make Diffused Data
Run ``diffuse.py [raw_data] [noise_schedule] -o [outfile]``.

## Noise Schedule

``noise_schedule.csv`` files are generated with ``make_noise_schedule.py``:

```bash
python make_noise_schedule.py quadratic [out.csv] -T [n_timesteps] --scale [scale]
python make_noise_schedule.py cosine [out.csv] -T [n_timesteps] --target-alpha-bar-t [alpha_bar_T]
```

``quadratic`` reproduces the original ``beta(tau) = scale * tau^2`` schedule (defaults match
``config/noise_schedules/noise_schedule.csv`` exactly). ``cosine`` follows Nichol & Dhariwal's "Improved DDPM"
schedule, solved so that the cumulative ``alpha_bar`` at the final timestep matches
``--target-alpha-bar-t`` exactly. Compared to the quadratic schedule, cosine spreads noise more
evenly through the middle of the chain, but concentrates a sharp jump in the final step or two;
raise ``--target-alpha-bar-t`` to soften that jump (``--s`` has little effect on it).

Compare schedules before committing to a full diffuse+train run with:

```bash
python plot_noise_schedule.py [schedule1.csv] [schedule2.csv] ... --labels [name1] [name2] ... -o [comparison.png]
```

This prints ``beta_min``/``beta_max``/``alpha_bar_T`` for each schedule and, if ``-o`` is given,
saves a plot of ``beta(tau)`` and ``alpha_bar(tau)``.

## Model Configuration

Model architecture is specified via a JSON config, e.g. ``config/models/equivariant_denoiser.json``:

```json
{
  "name": "EquivariantDenoiser",
  "hyperparameters": {
    "tau_encoding_dimension": 32,
    "position_encoding_dimension": 64,
    "hidden_layer_size": 256,
    "n_hidden_layers": 4,
    "use_position_encoding": false
  }
}
```

``use_position_encoding`` defaults to ``false`` — hit coordinates (φ, s, z) are fed to the model
directly rather than through an additional learned Fourier encoding.

``predict_variances`` defaults to ``false``. When ``true``, the model predicts its own per-hit,
per-feature variance alongside the mean, turning the loss into a genuine Gaussian NLL rather than
a ``β_τ``-weighted MSE (the fixed noise-schedule value is used as the variance when this is
``false``). See ``config/models/equivariant_denoiser_learned_variance.json`` for an example. ``train.py``
and ``generate_like.py`` handle the wiring automatically based on ``model.predict_variances`` — no
other CLI arguments change; ``noise_schedule`` is still required by both scripts since it also
fixes ``n_timesteps``.

When ``predict_variances`` is ``true``, training automatically uses ``DecoupledGaussianNLLLoss``
(mean and variance share every hidden layer, only diverging at the final output slice — without
decoupling, the variance head tends to collapse onto a trivial solution that just reproduces
``β_τ`` instead of learning anything input-dependent). ``--variance-loss-weight`` (default ``1.0``)
weights the variance-training term relative to the mean-training term.

## Training

```bash
python train.py [diffused_data] [noise_schedule] [model_config] -e [epochs] -b [batch_size] -t [tag]
```

``-t/--tag`` names the output files for this run (``denoiser_<tag>.pth``, ``history_<tag>.csv``);
defaults to the config filename stem if omitted. ``-o/--out`` overrides the output path directly.

``submit_train.sub`` reads ``(data, config, tag, schedule)`` rows from ``experiments.txt`` and
queues one condor job per row, so multiple runs (including runs against different noise
schedules) can be submitted at once without output files clobbering each other. ``schedule`` is
a filename within ``config/noise_schedules/`` (e.g. ``noise_schedule.csv`` or ``noise_schedule_cosine.csv``) —
the whole ``config/`` directory is already transferred to the job, so no other change is needed
to use a new schedule. Likewise ``config`` is a filename within ``config/models/``.

On Della (Slurm), ``./submit_train.sh experiments.txt`` is the equivalent: one ``train.slurm`` job
per row. Run it as a program (``./submit_train.sh`` or ``bash submit_train.sh``), never with
``source``, which would close your shell when the script exits. ``*.txt`` is gitignored, so each
person keeps their own experiments file. A complete one looks like this:

```
REPO=/scratch/gpfs/<GROUP>/<netid>/BIBgen   # required: your checkout; outputs and logs go here
MAIL_USER=<netid>@princeton.edu             # optional: email when each job ends or fails
RUNTIME=12:00:00                            # optional: wall-time limit (default 12:00:00)
DATA_DIR=/scratch/gpfs/IOJALVO/mz6011/BIBgen/data   # optional: default $REPO/data

# data                                config                      tag       schedule
# schedule must be the one `data` was diffused with
diffused_cyl_phipi4_large_logE.hdf5   equivariant_denoiser.json   v1        noise_schedule.csv
diffused_cyl_phipi4_large_logE.hdf5   mlp_denoiser.json           mlp_v1    noise_schedule.csv
```

Settings are ``KEY=value`` lines; anything else that is not a comment is a row, in the same
``data config tag schedule`` order as the Condor files (commas also work). A bare ``data`` name is
looked up in ``DATA_DIR``; a path is used as given. ``config`` and ``schedule`` are bare filenames in
``config/models/`` and ``config/noise_schedules/``. Pointing ``DATA_DIR`` at the shared copy above
saves duplicating the 26 GB file. ``diffused_cyl_phipi4_large_logE.hdf5`` was diffused with
``noise_schedule.csv``.

```bash
./submit_train.sh -n experiments.txt                     # print the sbatch commands only
./submit_train.sh experiments.txt --test-only            # ask the scheduler, create no jobs
./submit_train.sh experiments.txt                        # submit
EPOCHS=51 ./submit_train.sh experiments.txt --time=04:00:00   # env knobs; extra sbatch options last
squeue -u $USER --start                                  # estimated start times
```

The defaults in ``train.slurm`` (1 GPU on a 40 GB A100 or a 40 GB MIG slice, 2 cores, 4 GB, 12 h)
are sized from a measured run: 151 epochs of ``equivariant_denoiser.json`` on the file above took
8 h 57 min and used 1.3 cores, 1.6 GB of CPU memory and 6.3 GB of GPU memory. Scale ``RUNTIME`` with
epochs, model size and dataset; a shorter limit never queues longer and sometimes much shorter.
A tag whose ``denoiser_<tag>.pth`` already exists is skipped unless you pass ``-f``.

## Generation

```bash
python generate_like.py [model.pth] [model_config] [noise_schedule] [size_file] -t [tag]
```

Produces ``<tag>_like.hdf5``. Use the same ``-t`` you trained with. ``submit_generate_like.sub``
fans this out the same way, reading ``(config, tag, schedule)`` rows from
``generate_experiments.txt``. ``schedule`` must be the same one the model with that ``tag`` was
trained with.

On Della, ``./submit_generate_like.sh generate_experiments.txt`` does the same on a MIG GPU. Its
file takes the same ``REPO=`` (required), ``MAIL_USER=`` and ``RUNTIME=`` (default ``06:00:00``)
settings, followed by ``config tag schedule`` rows:

```
REPO=/scratch/gpfs/<GROUP>/<netid>/BIBgen
MAIL_USER=<netid>@princeton.edu

# config                      tag       schedule (same as training)
equivariant_denoiser.json     v1        noise_schedule.csv
mlp_denoiser.json             mlp_v1    noise_schedule.csv
```

It reads ``$REPO/examples/training/denoiser_<tag>.pth`` and needs ``test_sizes_large.csv`` in
``$REPO/examples/generation/`` (from ``write_test_sizes.py``; the diffused file has no ``test``
group, so it must come from the matching raw file). To queue generation behind a training job:

```bash
./submit_generate_like.sh generate_experiments.txt --dependency=afterok:<train_jobid>
```

## Analysis

```bash
python plot_comparison.py [mc_file] [gen_file.hdf5],[name] ...
```

Each generated file is given as a ``path,name`` pair; ``name`` is the legend label used for that
dataset in the overlay, 2D and clustering plots. Pass more than one pair to compare several models
against the same MC on the same axes.

Output directory defaults to ``plots/<tag>``, inferred from the first generated file's name;
``-t/--tag`` overrides it. Whether the energy feature needs exponentiating back from ``ln(E)`` is
auto-detected from the MC file; override with ``-l {auto,yes,no}`` if needed.

``wasserstein_distances.csv`` is written with one row per (generated dataset, variable). Its
``tag`` column is the experiment tag inferred from each generated file's name, so the rows still
join against ``history_<tag>.csv`` when several models are plotted in one run; ``-t/--tag`` sets
that column too when there is exactly one generated file.

## Ablation Analysis

Once you've run `plot_comparison.py` for each config/energy-parameterization variant (producing
a `wasserstein_distances.csv` per tag under `plots/<tag>/`), run:

```bash
python analyze_ablation.py --plots-dir plots --history-dir training/history -o plots/analysis
```

This reads every `wasserstein_distances.csv` found under `--plots-dir` (tag comes from the file's
own `tag` column — no hardcoded list to maintain) and every `history_<tag>.csv` found under
`--history-dir`, then writes four comparison plots to `-o`:

- ``wasserstein_by_variable.png`` — one bar chart per physical variable (energy, φ, η, s, z),
  comparing all configs
- ``wasserstein_grouped.png`` — all variables and configs together, log-scale
- ``pareto_aggregate_vs_valloss.png`` — normalized aggregate Wasserstein score vs. best validation
  loss. **Faceted by energy parameterization (raw-E vs. log-E) when both are present** — validation
  loss is not comparable across the two, since ``ln(E)`` and ``E`` correspond to different
  likelihood functions (a Jacobian term separates them). Wasserstein distance itself doesn't have
  this problem, since it's always computed on the untransformed physical variable.
- ``pareto_pairwise_all_combos.png`` — pairwise Pareto fronts across all five variables; dominance
  here is unaffected by axis scale, so no normalization is needed for this plot specifically (unlike
  the aggregate score above, which does normalize before summing).

Use ``--tag-order`` to fix the tag ordering/subset shown (comma-separated); otherwise tags are
auto-sorted from whatever's present in the data.
