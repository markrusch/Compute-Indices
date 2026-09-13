# SPDX-License-Identifier: Apache-2.0
# Copyright 2026 Mark Rusch
"""METHODOLOGY.md + METHODOLOGY.lock generation.

The lock records a sha256 over every file that can change a published print
(factors.yaml, sovereign.yaml, index.py, normalise.py, weights.py) together with
the methodology version. The generator refuses to record a changed hash under an
unchanged version — unless the version carries a '-dev' suffix (pre-launch).
CI and pytest verify that the lock matches the working tree, so a methodology
change without a deliberate, versioned regeneration fails the build.
"""

from __future__ import annotations

import hashlib
from pathlib import Path

import yaml

from tci import DISCLAIMER
from tci.config import CONFIG_DIR, load_factors, load_sovereign

REPO_ROOT = Path(__file__).resolve().parents[2]
LOCK_PATH = REPO_ROOT / "METHODOLOGY.lock"
DOC_PATH = REPO_ROOT / "METHODOLOGY.md"

HASHED_FILES = (
    "config/factors.yaml",
    "config/sovereign.yaml",
    "config/methodology/succession.yaml",
    "src/tci/index.py",
    "src/tci/normalise.py",
    "src/tci/weights.py",
    "src/tci/basis.py",
)

# The files that make up one version's parameter set. The head version's live at
# config/; every earlier version is a frozen copy under config/methodology/<version>/.
PARAM_FILES = ("factors.yaml", "sovereign.yaml")


def compute_hash(repo_root: Path | None = None) -> str:
    root = repo_root or REPO_ROOT
    h = hashlib.sha256()
    for rel in HASHED_FILES:
        path = root / rel
        h.update(rel.encode("utf-8"))
        h.update(b"\x00")
        content = path.read_bytes() if path.exists() else b"<absent>"
        h.update(content.replace(b"\r\n", b"\n"))  # hash must not depend on git eol conversion
        h.update(b"\x00")
    return h.hexdigest()


def params_hash(params_dir: Path) -> str:
    """sha256 over one version's parameter files (a frozen snapshot, or the head)."""
    h = hashlib.sha256()
    for name in PARAM_FILES:
        path = params_dir / name
        h.update(name.encode("utf-8"))
        h.update(b"\x00")
        h.update(path.read_bytes().replace(b"\r\n", b"\n") if path.exists() else b"<absent>")
        h.update(b"\x00")
    return h.hexdigest()


def succession_record(repo_root: Path | None = None) -> list[dict]:
    """One entry per version: its effective date, notice, and parameter hash."""
    root = repo_root or REPO_ROOT
    succ = root / "config" / "methodology" / "succession.yaml"
    if not succ.exists():
        return []
    raw = yaml.safe_load(succ.read_text(encoding="utf-8"))
    return [
        {
            "version": str(v["version"]),
            "effective_from": str(v["effective_from"]),
            "notice": v.get("notice"),
            "params_hash": params_hash(root / str(v["params"])),
        }
        for v in raw["versions"]
    ]


def read_lock(lock_path: Path | None = None) -> dict | None:
    path = lock_path or LOCK_PATH
    if not path.exists():
        return None
    return yaml.safe_load(path.read_text(encoding="utf-8"))


def update_lock(repo_root: Path | None = None) -> dict:
    """Regenerate the lock; refuses a changed hash under an unchanged released version."""
    root = repo_root or REPO_ROOT
    version = load_factors(root / "config").methodology_version
    new_hash = compute_hash(root)
    lock_path = root / "METHODOLOGY.lock"
    lock = read_lock(lock_path) or {"current": None, "history": []}
    current = lock["current"]
    if current is not None and current["hash"] != new_hash:
        if current["version"] == version and not version.endswith("-dev"):
            raise SystemExit(
                f"methodology files changed but methodology_version is still {version!r}. "
                "Bump methodology_version in config/factors.yaml and add a CHANGELOG entry "
                "before regenerating the lock (see GOVERNANCE.md)."
            )
    # Frozen snapshots never change. The head may (under the rule above); an earlier
    # version's parameters, once recorded, are refused if they differ, because prints
    # already published under that version would stop reproducing.
    recorded = {e["version"]: e for e in lock.get("succession", [])}
    record = succession_record(root)
    head_version = record[-1]["version"] if record else version
    for entry in record:
        prior = recorded.get(entry["version"])
        if (
            prior is not None
            and entry["version"] != head_version
            and prior["params_hash"] != entry["params_hash"]
        ):
            raise SystemExit(
                f"the frozen parameters of methodology version {entry['version']} changed. "
                "A version's parameters are fixed once it is superseded; announce a new "
                "version instead (see GOVERNANCE.md)."
            )
    lock["succession"] = record
    if current is None or current["hash"] != new_hash or current["version"] != version:
        from tci.db import utc_now_iso

        entry = {"version": version, "hash": new_hash, "generated_utc": utc_now_iso()}
        lock["current"] = {"version": version, "hash": new_hash}
        lock["history"] = lock.get("history", []) + [entry]
    lock_path.write_text(
        "# AUTO-GENERATED by `python -m tci.run docs` — do not hand-edit.\n"
        + yaml.safe_dump(lock, sort_keys=False),
        encoding="utf-8",
    )
    return lock


def render_methodology(config_dir: Path | None = None) -> str:
    cfg_dir = config_dir or CONFIG_DIR
    f = load_factors(cfg_dir)
    sovereign = sorted(load_sovereign(cfg_dir))
    factors_yaml = (cfg_dir / "factors.yaml").read_text(encoding="utf-8")
    classes_table = "\n".join(
        f"| `{name}` | {mc.reference_variant} | "
        + ", ".join(f"{v} (x{factor:g})" for v, factor in mc.variants.items())
        + " |"
        for name, mc in f.model_classes.items()
    )
    series_labels = {
        "headline": "`EU-CRI-H100` (headline)",
        "marketplace": "`EU-CRI-H100-MKT`",
        "hyperscaler": "`EU-CRI-H100-HS`",
        "sovereign": "`EU-CRI-H100-SOV`",
    }
    populations_table = "\n".join(
        f"| {series_labels.get(role, role)} | "
        + ", ".join(sorted(segments))
        + (" (further filtered by config/sovereign.yaml)" if role == "sovereign" else "")
        + " |"
        for role, segments in f.series_populations.items()
    )
    trim_ladder = "; ".join(
        f"n≥{r.min_n} → k={r.k}" for r in f.aggregation.trim_k if r.min_n > 0
    )
    if f.panel is not None:
        panel_rows = "\n".join(
            f"| {provider} | {entry.segment} | "
            + "; ".join(
                f"`{source}`: {', '.join(sorted(classes))}"
                for source, classes in sorted(entry.sources.items())
            )
            + " |"
            for provider, entry in sorted(f.panel.items())
        )
        panel_section = f"""### 1.1 The panel

A row can enter a print only if its provider, the collector that observed it, and its
class are all named here. Anything else is collected and stored, and appears in the audit
set as `not_in_panel`, but moves no number. Admitting a new (provider, collector, class)
is a constituent change under GOVERNANCE.md §1.

| Provider | Segment | Collector: classes admitted |
|---|---|---|
{panel_rows}
"""
    else:
        panel_section = ""
    fx_rule = (
        "dated **strictly before** the print date, so the EUR leg is T-1 on every day,"
        " whenever the run happens"
        if f.fx.strictly_before
        else "dated **on or before** the print date. The ECB publishes ~14:00 UTC, after"
        " the 11:00 UTC cut-off, so the EUR leg is T-1 on most days; a run after the"
        " ECB publication picks up the same-day rate. The rate a print used is recorded"
        " with it and is what `reproduce` converts at"
    )
    regional_rows = "".join(
        f"\n| `{name}` | the headline's unit, estimator, weights and gate, {rs.block}"
        f" block ({', '.join(sorted(f.countries_of(rs.block)))}) |"
        for name, rs in f.regional_series.items()
    ) + "".join(
        f"\n| `{name}` | `{bs.lead}` minus `{bs.reference}`, USD per GPU-hour; a gap on any"
        " day either leg gaps |"
        for name, bs in f.basis_series.items()
    )
    if f.basis_series:
        basis_section = """
### 4.1 The US reference block and the EU-US basis

The US series prices one H100 SXM GPU-hour delivered from the United States with exactly
the rules above: the same unit definition, node floor, weighted median over offers, trim,
tier weights, concentration cap and publication gate. The basis series is the EU/EEA
headline minus the US series on the same day. Holding the method constant is what makes
the spread a regional basis rather than a comparison of two methods.

It is **not** the basis to the index on which the CME compute futures settle. That index's
methodology is not public, and a spread against it would mix a regional difference with a
methodological one that nobody outside can measure.

Region-flat prices are placed only where the seller itself says it sells: DigitalOcean's
H100 is recorded once per region on its availability page, and RunPod's US row exists only
on a day RunPod reports stock of that GPU type in a US datacentre.
"""
    else:
        basis_section = ""
    succession_rows = "\n".join(
        f"| {e['version']} | {e['effective_from']} | {e['notice'] or '—'} |"
        for e in succession_record(REPO_ROOT)
    )

    return f"""<!-- AUTO-GENERATED by `python -m tci.run docs` from config/factors.yaml.
     Do not hand-edit; edit the config or tci/methodology.py and regenerate. -->

# TCI Methodology — v{f.methodology_version}

TCI (The Compute Indices) is a daily reference price for renting AI compute
delivered from data centres physically located in the EU/EEA. Headline series:
**TCI-CRI-H100**, in USD per GPU-hour with a EUR companion at the ECB reference rate.

> **TCI is a price-transparency benchmark, not a settlement benchmark.** Every print is
> reproducible by any third party from public sources using the published code. It is not
> transaction-based and must not be referenced in a financial contract. The conditions
> that would have to be met before settlement use is credible are published in
> GOVERNANCE.md. §9 lists every methodology version and the date it takes effect.

## 1. Unit definition

One TCI-CRI-H100 unit = one NVIDIA **{f.reference_unit.gpu_model}** 80GB GPU-hour,
**{f.reference_unit.term}** (no term commitment), datacenter-hosted, delivered from the
EU/EEA, per-GPU, **ex-VAT**, excluding storage and metered egress.

A class prices its **reference variant only**. Cross-variant normalisation by assumed
factors was removed in v0.3.0: H100 SXM and H100 PCIe are different products, and
H100→H200 normalisers disagree in *sign* depending on whether you divide by BF16 PFLOPs
(+31%) or HBM bandwidth (−9%). A variant may enter a class only under a factor **measured**
from same-venue, same-day, same-SKU pairs.

| Class | Reference variant | Variants (factor) |
|---|---|---|
{classes_table}

{panel_section}
Excluded outright: variants not listed above, community/consumer hosts,
interruptible/spot tiers ({", ".join(f.filters.exclude_tiers)}), term-committed prices,
offers below **{f.filters.min_gpu_count} GPUs**, prices outside the sanity band
[${f.filters.price_floor_usd:.2f}, ${f.filters.price_ceiling_usd:.2f}] per GPU-hour.

**Why the node floor is {f.filters.min_gpu_count}, not 8.** Measured within one venue on
one day, the per-GPU discount saturates at 2 GPUs (1×=1.000, 2×=0.951, 4×=0.916,
8×=0.916), so 2/4/8-GPU offers are mutually comparable within ~4% and need no adjustment,
while the 1-GPU offer carries a ~9% small-order premium and is excluded rather than
normalised away. The former 8-GPU floor admitted marketplace inventory on 1 collection day
in 10 and discarded essentially all of the index's price discovery.

## 2. Data hierarchy and market segments (IOSCO P8)

Executable marketplace asks are preferred over list prices and carry a
**{f.weights.executable_multiplier:g}×** weight multiplier. Overlay data (power prices)
never enters the calculation. Competitor indices are never ingested.

The constituent distribution is **bimodal** — measured separation of 5.4 standard
deviations between the neocloud/marketplace cluster and the hyperscaler catalog cluster.
Averaging across that gap yields a number no one quotes, so series are segregated by
market segment and never drawn across it:

| Series | Population |
|---|---|
{populations_table}

## 3. Aggregation (exact algorithm)

Per UTC day and series. **The unit of aggregation is the offer, not the provider.**

1. Collect all observations for the day passing the unit filters above, restricted to the
   series' market-segment population.
2. Static (manually verified) entries older than {f.staleness.exclude_days} days are
   excluded as stale (warning from {f.staleness.warn_days} days).
3. **Provider weight** = {f.weights.executable_multiplier:g} if the provider has any
   executable offer, else 1. Capacity does *not* enter here: it is unobservable for every
   list source, so a capacity term at provider level is fiction that made a rate card
   disclosing nothing outrank a marketplace disclosing a real 2-GPU offer.
4. **Concentration cap**: no provider may exceed {f.weights.max_weight_share_pct:g}% of
   total weight; excess is redistributed pro-rata, iterated to a fixed point (the cap
   relaxes to 100/n when n providers cannot satisfy it). Note this cap is mathematically
   inert at n=4 — it forces exactly equal shares — and binds only for n≥5. Every print
   publishes whether it bound.
5. **Spread each provider's share across its own offers** in proportion to offer capacity.
   Capacity is genuinely observable *here*, between offers from the same venue.
6. **Trim**: clamp the k highest and k lowest offer prices to the k-th order statistic
   from each end, k by panel size ({trim_ladder}). Count-based, because nearest-rank
   percentile winsorising is inert at this panel size — at n=6 both p5/p95 and p10/p90
   resolve to (min, max) and clamp nothing.
7. **Weighted median over offers**: sort by price ascending; the value is the first price
   at which cumulative weight reaches 50%. A median over ~6 providers has a delta of 1.0
   to one constituent and 0.0 to every other; a median over many capacity-weighted offers
   is locally smooth and always lands on a price someone actually quoted.
8. **Publish gate**: fewer than {f.aggregation.min_providers} qualifying providers or
   fewer than {f.aggregation.min_offers} qualifying offers → no value is published,
   flagged `insufficient_sources` / `insufficient_offers`. There is no fallback waterfall.
   A gap is credible; a fabricated print is fatal.
9. EUR companion = USD value ÷ the most recent ECB EUR/USD reference rate {fx_rule}.
   Providers quoting natively in EUR are converted from their native amount at print time,
   at the same rate.
10. Headline companion: {f.aggregation.smoothing_days}-day mean of daily prints
    (requires ≥4 non-null days).

Constituent prices moving more than {f.jump_flag_pct:g}% day-over-day are flagged
(`jump`) for manual review but are **not** excluded. A print with no executable input is
flagged `no_executable_input` — a list-price-only print says so on its face.

### 3.1 Continuity series

The headline is the **raw daily cross-section**, not a chain-linked level. A Laspeyres
link with a same-day divisor reset contributes exactly zero return on panel entry and
exit, which makes in-panel up-moves permanent while down-moves taken via exit and re-entry
are laundered out — a ratchet worth roughly +7.8% per cycle for a constituent at the
{f.weights.max_weight_share_pct:g}% cap. A chained level is published *beside* the
headline as a labelled companion, and the divergence between them is a published health
metric with a {f.continuity.divergence_review_pct:g}% review trigger.

### 3.2 TCI-CRI-COMPUTE (chain-linked class composite)

The composite aggregates the class series into one level (base
{f.composite.base_value:g} at its first print), **chain-linked** so that reweighting
never jumps the published level:

- At each weight review, **class basket shares** = each class's share of total observed
  qualifying capacity over the window. With ≥2 eligible classes, shares are capped at
  {f.composite.max_class_share_pct:g}% and floored at {f.composite.min_class_share_pct:g}%
  (pro-rata redistribution, as in §3 step 6).
- Daily: composite(t) = composite(t−1) × Σ share × (class(t) / class(t−1)), summed over
  classes with a published value on both endpoints, shares renormalised over those
  classes. A class that gaps drops out of that day's link; if no class links, the
  composite gaps (`no_linkable_series`).
- As the observed market migrates across hardware generations (H100 → B200), the basket
  follows mechanically — no methodology change required.

## 4. Series

| Series | Constituents |
|---|---|
| `EU-CRI-H100` | all qualifying H100-class providers (headline) |
| `EU-CRI-H100-7D` | {f.aggregation.smoothing_days}-day mean of the headline |
| `EU-CRI-H100-SOV` | EU/EEA-headquartered operators: {", ".join(sovereign)} |
| `EU-CRI-H100-MKT` | marketplace segment only |
| `EU-CRI-H100-NC` | neocloud segment only |
| `EU-CRI-H100-HS` | hyperscaler catalog segment only |
| `EU-CRI-H100-PCIE` | H100 PCIe, priced as its own class (no assumed SXM factor) |
| class series (`EU-CRI-A100`, `EU-CRI-H200`, `EU-CRI-B300`, …) | one per observed class in §1; published once ≥{f.aggregation.min_providers} providers exist (gapped, with audit trail, before that) |
| `EU-CRI-COMPUTE` | chain-linked composite of class series (§3.2); a level, not a $/hr price |{regional_rows}

{basis_section}
`EU-CRI-H100-CLOUD` was **retired in v0.3.0** and is not published. Its historical
values remain in `index_history.csv` under the methodology version that produced them.

**Segment size and the publication gate.** A sub-population series can only print when
its segment holds at least `min_providers` ({f.aggregation.min_providers}) qualifying
providers. `EU-CRI-H100-MKT` and `EU-CRI-H100-HS` draw on segments smaller than that and
therefore gap by construction rather than by circumstance. This is stated here because a
permanent gap and a temporary one look identical on the dashboard, and the difference
matters to a reader.

## 5. Revisions and corrections

Raw observations and published prints are append-only (enforced by database triggers).
Errors are corrected in the next print as a **new revision** flagged `correction`; prior
revisions remain queryable forever. The full constituent set for any print is available
via `python -m tci.run constituents --date YYYY-MM-DD`, and every print is published with
its constituents and a digest in `site/data/prints/YYYY-MM-DD.json`.

`python -m tci.run reproduce --published` recomputes every stored print from the stored
observations under the version live on its date, compares value, counts, flags and the
full constituent set with what was stored, then checks each published digest against the
database. Exit 0 means every print matched.

## 6. Changes to this methodology

Any change to the parameters below or the calculation code requires a version bump, a
CHANGELOG entry, and one publication's notice before taking effect, enforced
mechanically via `METHODOLOGY.lock` in CI. See GOVERNANCE.md.

Effective dates are enforced in code. An announced version is committed on the day of its
notice and is selected for a print only from its effective date (§9); earlier versions are
frozen snapshots under `config/methodology/<version>/`, each with its own rendered copy of
this document, and the lock refuses any change to a frozen snapshot.

## 7. Current parameters (config/factors.yaml, verbatim)

```yaml
{factors_yaml.rstrip()}
```

## 8. IOSCO Principles mapping

| IOSCO principle | Implementation |
|---|---|
| Benchmark design & data sufficiency (P6–P7) | Observable, executable marketplace quotes anchored; ≥{f.aggregation.min_providers}-source rule; weights set by observed data on a fixed schedule; {f.weights.max_weight_share_pct:g}% concentration cap; no expert judgement in the calculation path |
| Hierarchy of data inputs (P8) | Executable quotes weighted {f.weights.executable_multiplier}x over list prices inside the weight review; overlay data never enters the calculation |
| Transparency of methodology (P9, P11) | This document is auto-generated from config, semver-versioned; every parameter is a visible config value; every weight review is stored and queryable |
| Changes to methodology (P12) | CHANGELOG + one-publication notice before any parameter change takes effect; hash-locked in CI. Scheduled weight reviews follow the fixed published formula and are data updates, not methodology changes |
| Quality of the administrator (P4–P5) | Named author; stated conflicts (the author may trade venues the index observes — disclosed); corrections never silent |
| Complaints & audit trail (P13, P16) | Raw observations and weight reviews immutable in SQLite; any reader can request the constituent set for a given day |

## 9. Versions and effective dates

A print is computed under the last version whose effective date is on or before the print
date (`config/methodology/succession.yaml`).

| Version | Effective from | Notice |
|---|---|---|
{succession_rows}

---

*{DISCLAIMER}*

*Author and administrator: Mark Rusch — contact via
[the contact page](contact.html). Conflicts: the author may hold positions on venues
whose prices the index observes; see GOVERNANCE.md.*
"""


def generate(repo_root: Path | None = None) -> None:
    """Regenerate the lock, the head METHODOLOGY.md, and one document per frozen version.

    Each frozen version gets its own rendered document next to its parameters, so the
    rules that produced a print on any past date can be read, not only reconstructed.
    """
    root = repo_root or REPO_ROOT
    update_lock(root)
    (root / "METHODOLOGY.md").write_text(
        render_methodology(root / "config"), encoding="utf-8", newline="\n"
    )
    for entry in succession_record(root)[:-1]:
        snap = root / "config" / "methodology" / entry["version"]
        if snap.is_dir():
            (snap / "METHODOLOGY.md").write_text(
                render_methodology(snap), encoding="utf-8", newline="\n"
            )
