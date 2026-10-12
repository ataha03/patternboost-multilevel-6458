# Model-capacity experiment

## Question

Does substantially increasing transformer capacity and the available training
archive improve the best exact score under the same wall-clock budget?

This is a practical fixed-budget check. It cannot show that larger models never
help, and it does not justify the phrase "smallest possible transformer." A
defensible conclusion is: "we retained the compact architecture because the
tested scaled setting did not improve exact scores under the same budget."

## Selected configurations

The experiment uses the three highest-scoring configurations for each of MISR,
unit-square stabbing, and guillotine hardness in the final 81-cell table. This
includes the diversity-island unit-square configuration that reached (20/13).
Exact-score ties are resolved by configuration ID.

## Compared arms

Both arms use exact scoring every 5 generations, training every 10 generations,
16 model samples, 3 training epochs, context length 128, and the same two-hour
application budget. Geometry, local search, surrogate, population, and search
operators are fixed within each comparison. The intervention deliberately
scales both the transformer and its available data: the scaled arm starts from a
larger random initial corpus and retains a larger training archive. It is
therefore a joint model-and-data capacity experiment, not an architecture-only
ablation.

| Arm | Initial pool | Training archive | Layers | Heads | Width |
|---|---:|---:|---:|---:|---:|
| compact | 32 | 48 | 2 | 4 | 96 |
| scaled | 256 | 256 | 4 | 8 | 192 |

The (20/13) unit-square configuration preserves its original diversity
mechanism in both arms: population 32, elite 12, four random immigrants per
generation, and resolution-island retention. Its compact arm uses the original
initial pool of 128 and an archive cap of 96; its scaled arm uses 256 for both.
The other eight compact rows use population 32, elite 6, initial pool 32, and
archive cap 48.

The scaled transformer has roughly eight times the encoder parameters before
small vocabulary-dependent terms. Exact parameter counts, model-training time,
training-text counts, valid sample counts, generations, and exact calls are
recorded by every row.

Each row receives a freshly generated random state at matrix-generation time.
There is no repeated-seed axis and no warm-start certificate, target score, or
known construction in either arm.

## Generate and run

```bash
python3 -m multilevel.cli model-capacity-matrix \
  --budget-seconds 7200 \
  --out runs/model_capacity_2h/matrix.jsonl

python3 -m multilevel.cli make-slurm \
  --matrix runs/model_capacity_2h/matrix.jsonl \
  --out runs/model_capacity_2h/array.slurm \
  --project-dir "$HOME/patternboost/multi-level-COMMIT" \
  --results-dir "$HOME/patternboost/multi-level-COMMIT/runs/model_capacity_2h/results" \
  --time 02:30:00 \
  --partition compute \
  --cpus-per-task 4 \
  --mem 24G \
  --runner patternboost
```

After completion, collect and audit all certificates before interpreting scores:

```bash
python3 -m multilevel.cli summary \
  --root runs/model_capacity_2h/results \
  --out runs/model_capacity_2h/summary.csv

python3 -m multilevel.cli audit \
  --root runs/model_capacity_2h/results \
  --out runs/model_capacity_2h/audit.json \
  --csv runs/model_capacity_2h/audit.csv

python3 scripts/analyze_model_capacity.py \
  --matrix runs/model_capacity_2h/matrix.jsonl \
  --results-root runs/model_capacity_2h/results \
  --out-csv runs/model_capacity_2h/capacity_results.csv \
  --out-md runs/model_capacity_2h/capacity_results.md
```

## Reporting rule

Report exact verified scores and the number of comparisons in which scaling was
better, tied, or worse. The primary outcome is the best new exact score; an
improvement is more valuable than evidence of a plateau. Also report
model-training time, completed generations, parameter counts, and valid model
samples. Do not attribute a lower score solely to representational capacity if
the scaled arm completed materially fewer search generations. Because each row
uses an independent fresh random state, treat the nine arm comparisons as
descriptive rather than paired-seed estimates.
