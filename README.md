# viraprime

Design PCR primers that work across a family of related sequences (strains of a virus,
variants of a gene, …). Give it your genomes and the number of amplicons you want: it tiles
the whole genome with that many overlapping amplicons in two pools, choosing primer sites that
match as many of your sequences as possible. Every primer is checked against every sequence,
not just a consensus.

```bash
viraprime -i genomes.fasta -n 10 -o out
```

Prefer not to install anything? See [Run it from the web](#run-it-from-the-web).

## Installation

```bash
conda create -n primers -c conda-forge -c bioconda python=3.11 biopython "primer3-py>=2" pytest mafft muscle
conda activate primers
pip install -e .
```

Python ≥ 3.10 is required. Python dependencies are listed in `requirements.txt`; MAFFT (default)
or MUSCLE 5 must be on `PATH` unless you pass a pre-aligned file with `--aligned`.

## Quick start: tile a genome

```bash
python examples/make_example.py                # writes examples/genomes.fasta (24 genomes, 9 kb)
viraprime -i examples/genomes.fasta -n 8 -o out
```

This aligns the genomes, then picks 8 overlapping amplicons (~1.2 kb each, at least 50 bp
overlap) covering the genome end to end. Odd amplicons go in pool 1 and even ones in pool 2,
so overlapping products never share a tube. It writes:

- `primers.tsv`: one row per amplicon: pool, primer names (`viraprime_1_LEFT`, …) and
  sequences, Tm, GC, reference coordinates, overlap with the next amplicon, coverage and the
  sequences each amplicon misses, with the reason.
- `scheme.bed`: the primer scheme in ARTIC format (`chrom start end name pool strand
  sequence`), ready for amplicon-sequencing pipelines.
- `report.txt`: settings, input and alignment statistics, the tiling, bases left uncovered at
  the genome ends, possible primer dimers within a pool, and the log.
- `alignment.fasta`: the alignment used.

### How the amplicons are chosen

1. Every position of the consensus is tried as a primer 3′ end; primers outside the Tm, GC and
   length limits, or with hairpins, self-dimers or a G/C-heavy 3′ end, are dropped.
2. The most conserved primers are kept and checked against every sequence with the matching
   rules below. Degenerate (IUPAC) bases are added where they rescue sequences, up to
   `--max-degeneracy` variants per primer.
3. A dynamic-programming search picks exactly N amplicons: it maximises the worst amplicon's
   coverage, then the total coverage, then how close the tiling reaches both genome ends, then
   primer quality. Amplicon lengths may vary ±20 % around the target; if no tiling fits, the
   tool retries at ±35 % and ±50 % and says so.
4. Primers in the same pool are checked for primer-dimers (reported, not blocking).

### Tiling options

| Option | Default | Description |
|---|---|---|
| `-n/--amplicons` | — | number of amplicons |
| `--overlap` | 50 | minimum overlap between neighbouring amplicons (bp, between the primers) |
| `--tm-min/--tm-opt/--tm-max` | 57 / 60 / 63 | primer Tm (°C) |
| `--max-tm-diff` | 2 | max Tm difference within a pair (°C) |
| `--primer-len-min/--primer-len-max` | 18 / 25 | primer length |
| `--gc-min/--gc-max` | 40 / 60 | primer GC % |
| `--max-mismatches` | 2 | max mismatches per primer |
| `--three-prime-window` | 5 | 3′ bases that must match exactly |
| `--no-degenerate` | off | plain primers only |
| `--max-degeneracy` | 4 | max variants per degenerate primer |
| `--min-coverage` | 95 | coverage target (%) |
| `-i`/`--aligned`, `--aligner`, `--reference-id`, `--length-tolerance`, `--outlier-action`, `-v` | | as below |

Exit codes: `0` every amplicon reaches `--min-coverage`, `2` at least one does not (outputs are
still written), `1` error (for example too many amplicons for the genome length; the message
says the most that fit).

## Run it from the web

The same tool runs as a web app: drop your FASTA, choose the number of amplicons, and get the
primers with a coverage map and downloads. A "Check my primers" tab tests pairs you already have.
Uploaded files are deleted 24 hours after the job finishes; for private or larger data, use the
command line.

Run it on your own computer:

```bash
pip install -e ".[web]"
viraprime web            # opens http://127.0.0.1:8000
```

Or with Docker (MAFFT included):

```bash
docker build -t viraprime-web .
docker run --rm -p 7860:7860 viraprime-web     # http://localhost:7860
```

Limits can be changed with environment variables: `VIRAPRIME_MAX_SEQS` (500),
`VIRAPRIME_MAX_SEQ_LEN` (35000), `VIRAPRIME_MAX_UPLOAD_MB` (20), `VIRAPRIME_MAX_AMPLICONS` (200),
`VIRAPRIME_WORKERS` (2), `VIRAPRIME_MAX_QUEUE` (20), `VIRAPRIME_TIMEOUT_S` (900), `VIRAPRIME_RETENTION_S` (86400) and
`VIRAPRIME_JOBS_DIR`.

### Put it online (Hugging Face Space, free)

The Space runs the same web app with the **Gradio** SDK, which is free: Hugging Face installs
MAFFT from `deploy/hf-space/packages.txt` and starts `deploy/hf-space/app.py`.

1. Create a free account at [huggingface.co](https://huggingface.co), then **New Space**: any
   name, SDK **Gradio**, template **Blank**, hardware **CPU basic** (free).
2. Create an access token with **write** permission (Settings → Access Tokens).
3. In this GitHub repository, Settings → Secrets and variables → Actions: add the secret
   `HF_TOKEN` (the token) and the variable `HF_SPACE` (`<owner>/<space name>`).
4. Run the **Deploy web app to Hugging Face** workflow once from the Actions tab (it also runs
   on every push to master that changes the app). The app appears at
   `https://huggingface.co/spaces/<owner>/<space name>`. A free Space sleeps when idle and
   takes about 30 seconds to wake up.

## Advanced: target regions

Instead of tiling the whole genome you can design pairs inside chosen regions
(`--region`, `--amplicon-min`, `--amplicon-max`), or check primers you already have
(`viraprime check`).

### Example

```bash
python examples/make_example.py          # writes examples/family.fasta (10 synthetic sequences)
viraprime -i examples/family.fasta -o out \
    --region cons:61-540 --region hv:701-1100 \
    --amplicon-min 100 --amplicon-max 300 --allow-degenerate
```

The example family has a conserved block (61–540) and a hypervariable block (701–1100). The run
finds pairs with 100 % coverage in `cons`, reports the best available (30 %) pairs for `hv` with
`below_threshold=True`, explains why in `out/report.txt`, and exits with code 2.

`python -m viraprime …` works the same as `viraprime …`.

### Checking existing primers

`viraprime check` tests primer pairs you already have (a published assay, pairs from an earlier
run, pairs from another tool) against your sequences, without designing new ones. Each primer is
placed where it fits the consensus best, then the pair is scored on every sequence with exactly
the same matching rules as design mode.

List the pairs in a tab-separated file, written 5′→3′ as you would order them (IUPAC codes
allowed; a header line, blank lines and `#` comments are optional):

```
name	forward	reverse
cons	CAGTCCCCTACGTCGCATATC	TAGTTGGGCGTCCTGAGAAAC
hv	CTCCAGTGGMGGTCTTGGTKG	GCAYKCATCCMAGTAAGCACAC
```

```bash
viraprime check -i examples/family.fasta --primers assays.tsv -o out_check
```

It writes `alignment.fasta`, `report.txt` (one section per pair, with why it misses sequences)
and `check.tsv`, one row per pair: `name, forward_seq, reverse_seq, forward_tm, reverse_tm,
forward_gc, reverse_gc, forward_len, reverse_len, degenerate, forward_tm_range,
reverse_tm_range, located, forward_site_mismatches, reverse_site_mismatches, amplicon_start,
amplicon_end, amplicon_len, coverage_pct, n_covered, n_total, below_threshold, not_covered,
note`. On the example family the two pairs above give 100 % and 30 % coverage, as in the design
run.

A pair is reported as not located (0 % coverage, reason in `note`) when a primer fits two places
equally well or the reverse primer does not bind downstream of the forward one. When a primer has
no site within `--max-mismatches`, `note` says so, and also says when the primer would fit if it
were written in the other orientation (a common copy-paste slip with reverse primers). If the
reference has no bases where the amplicon falls (for example a partial genome), the amplicon
coordinates are left empty and `note` says `amplicon not on reference <id>`. Options shared
with design mode (`-i`/`--aligned`, `--aligner`, `--reference-id`, `--length-tolerance`,
`--outlier-action`, `--max-mismatches`, `--three-prime-window`, `--min-coverage`, `-v`) work
the same; design-only options such as `--region` are rejected. Exit codes: `0` every pair meets
`--min-coverage`, `2` at least one does not (outputs are still written), `1` error.

### Pipeline (region design)

1. **Load & validate** the FASTA: errors on missing/empty files, empty records, duplicate IDs
   and non-IUPAC characters. Lowercase and `U` are accepted (converted to upper-case / `T`).
2. **Length check**: sequences whose length differs from the median by more than
   `--length-tolerance` × median are dropped, kept with a warning, or abort the run
   (`--outlier-action`).
3. **Align** with MAFFT or MUSCLE, or use `--aligned` to skip this step.
4. **Consensus**: majority base per column; columns that are gaps in ≥ 50 % of sequences are left
   out of the consensus.
5. **Design** candidate pairs with primer3 on the consensus, with the whole amplicon inside each
   region.
6. **Re-score** each pair against every sequence (see *Matching rules*), optionally adding IUPAC
   degenerate bases (`--allow-degenerate`).
7. **Rank** by coverage, then primer3 penalty, and report the top `--num-pairs` per region.

### Matching rules (all modes)

A primer matches a sequence when it has at most `--max-mismatches` mismatches **and** none in the
last `--three-prime-window` bases of its 3′ end. A pair covers a sequence when both primers match.

- A gap, `N` or any ambiguous base in the sequence counts as a mismatch.
- Each base the sequence has in addition to the primer (an insertion) counts as one mismatch.
- A degenerate primer base matches any base it stands for (`R` matches `A` and `G`).

With `--allow-degenerate`, IUPAC bases are added one at a time, each time choosing the change
that rescues the most sequences (then the one removing the most mismatches, then the one
farthest from the 3′ end), as long as the primer's fold (number of distinct oligos) stays at or
below `--max-degeneracy`. The 3′-terminal base is never made degenerate, and changes that do not
end up rescuing a sequence are undone.

### Coordinates and regions

All coordinates are 1-based, inclusive, on the reference sequence (`--reference-id`, default the
first sequence). They are converted to alignment columns internally.

- `--region START-END` or `--region NAME:START-END`, repeatable. Unnamed regions are called
  `region1`, `region2`, … in command-line order.
- `--regions-file FILE`: tab-separated `name`, `start`, `end`; an optional header line, blank lines
  and `#` comments are allowed.
- Without either, the whole reference is one region called `full`.

Regions are designed independently and may overlap.

### Region design options

| Option | Default | Description |
|---|---|---|
| `-i/--input` | — | multi-FASTA (exactly one of `-i` / `--aligned` is required) |
| `--aligned` | — | pre-aligned FASTA; skips alignment |
| `-o/--outdir` | required | output directory (created if missing) |
| `--aligner` | `mafft` | `mafft` or `muscle` |
| `--reference-id` | first sequence | reference for coordinates |
| `--region` / `--regions-file` | whole reference | target regions (see above) |
| `--amplicon-min`, `--amplicon-max` | **required** for region design | amplicon length range (bp) |
| `--tm-min/--tm-opt/--tm-max` | 57 / 60 / 63 | primer Tm (°C) |
| `--max-tm-diff` | 2 | max Tm difference within a pair (°C) |
| `--primer-len-min/--primer-len-max` | 18 / 25 | primer length |
| `--gc-min/--gc-max` | 40 / 60 | primer GC % |
| `--length-tolerance` | 0.10 | allowed deviation from median length (fraction) |
| `--outlier-action` | `drop` | `warn`, `drop` or `abort` |
| `--max-mismatches` | 2 | max mismatches per primer |
| `--three-prime-window` | 5 | 3′ bases that must match exactly |
| `--min-coverage` | 95 | minimum coverage (%) |
| `--allow-degenerate` | off | allow IUPAC bases at variable positions |
| `--max-degeneracy` | 8 | max fold per degenerate primer |
| `--candidates` | 200 | primer3 pairs re-scored per region |
| `--num-pairs` | 5 | pairs reported per region |
| `-v/--verbose` | off | debug logging and tracebacks |

### Region design outputs

- `alignment.fasta` — the alignment used (after outlier removal).
- `primers.tsv` — one row per reported pair: `region, rank, forward_seq, reverse_seq, forward_tm,
  reverse_tm, forward_gc, reverse_gc, forward_len, reverse_len, amplicon_start, amplicon_end,
  amplicon_len, coverage_pct, n_covered, n_total, degenerate, forward_tm_range, reverse_tm_range,
  penalty, below_threshold, not_covered`. Amplicon coordinates are on the reference; `rank`
  restarts at 1 for each region; `not_covered` lists `ID(reason)` for every missed sequence. Tm
  ranges are given for degenerate primers (min–max over all expansions).
- `report.txt` — parameters, input statistics, dropped outliers, alignment statistics, one section
  per region (candidates, coverage, and why the best pair misses sequences when no pair reaches
  `--min-coverage`), a summary, and the full log.

### Exit codes (region design)

| Code | Meaning |
|---|---|
| 0 | every region has at least one pair meeting `--min-coverage` |
| 1 | error (bad input or parameters, aligner missing or failed) |
| 2 | finished, but at least one region has no pair meeting `--min-coverage` (or no primer3 candidates); outputs are still written |

## Tests

```bash
pytest
```

Tests use a synthetic family (`tests/synthetic.py`); those that run MAFFT are skipped if it is not
installed.
