"""Render the HTML write-up from artifacts/. No number is typed by hand.

Usage: uv run python -m scripts.report
"""
from __future__ import annotations

import json
from datetime import date
from pathlib import Path

import polars as pl

from scripts.svgkit import Box, esc, fmt, hbar_chart, heatmap, line_chart, table_view

ART = Path("artifacts")
OUT = Path("role_clustering_report.html")
M = json.loads((ART / "meta.json").read_text())
K = M["k"]

PRETTY = {
    "r_fg3a_share": "3PA share",
    "r_ftr": "FT rate",
    "r_fga_per_min": "FGA / min",
    "r_ast_per_min": "AST / min",
    "r_ast_pct": "AST %",
    "r_ast_ratio": "AST ratio",
    "r_tov_pct": "TOV %",
    "r_oreb_pct": "OREB %",
    "r_dreb_pct": "DREB %",
    "r_stl_per_min": "STL / min",
    "r_blk_per_min": "BLK / min",
    "r_pf_per_min": "PF / min",
    "r_start_rate": "start rate",
    "r_min": "minutes",
    "usg_last5": "usage, last 5",
    "usg_last20": "usage, last 20",
    "usg_season_to_date": "usage, season to date",
    "min_last5": "minutes, last 5",
}
def nice(c: str) -> str:
    return PRETTY.get(c, c.replace("role_", "role ").replace("r_", ""))


# ---------------------------------------------------------------------------
# Role naming, derived from each role's own z-score signature
# ---------------------------------------------------------------------------
prof = pl.read_parquet(ART / "role_profiles.parquet")
feat_cols = [c for c in prof.columns if c.startswith("r_")]


def name_role(row: dict) -> str:
    z = {c: row[c] for c in feat_cols}
    big = z.get("r_blk_per_min", 0) + z.get("r_oreb_pct", 0)
    out = z.get("r_fg3a_share", 0)
    cre = z.get("r_ast_pct", 0) + z.get("r_ast_per_min", 0)
    vol = z.get("r_fga_per_min", 0)
    mins = z.get("r_min", 0)
    if big > 1.2 and out < -0.5:
        return "Interior big"
    if big > 0.6 and out > 0.3:
        return "Stretch big"
    if cre > 1.4:
        return "Primary creator"
    if cre > 0.5 and vol > 0.2:
        return "Secondary creator"
    if out > 0.8 and cre < 0.3:
        return "Off-ball shooter"
    if vol > 0.6:
        return "Volume scorer"
    if mins < -0.6:
        return "Low-minute reserve"
    return "Connective wing"


names_by_label: dict[int, str] = {}
used: dict[str, int] = {}
for row in prof.iter_rows(named=True):
    base = name_role(row)
    used[base] = used.get(base, 0) + 1
    names_by_label[row["role_label"]] = base if used[base] == 1 else f"{base} {used[base]}"


def rl(label: int) -> str:
    return f"{label} &middot; {names_by_label.get(label, '')}"


# ---------------------------------------------------------------------------
# Sections
# ---------------------------------------------------------------------------
parts: list[str] = []


def section(title: str, body: str, sub: str = "") -> None:
    s = f'<p class="sub">{sub}</p>' if sub else ""
    parts.append(f'<section><h2>{title}</h2>{s}{body}</section>')


# --- Headline -------------------------------------------------------------
usage = pl.read_parquet(ART / "usage_models.parquet")
best_base = usage.filter(pl.col("model").str.starts_with("baseline")).sort("mae")
best_model = usage.filter(~pl.col("model").str.starts_with("baseline")).sort("mae")
bb, bm = best_base.row(0, named=True), best_model.row(0, named=True)

with_roles = usage.filter(pl.col("model").str.contains("soft roles")).sort("mae")
without_roles = usage.filter(
    pl.col("model").str.contains("usage history only")
    | pl.col("model").str.contains("usage history \\+ role features$")
).sort("mae")
delta_pct = (
    (without_roles["mae"][0] - with_roles["mae"][0]) / without_roles["mae"][0] * 100
    if with_roles.height and without_roles.height
    else 0.0
)

hero = f"""
<div class="tiles">
  <div class="tile"><div class="tile-k">Roles found</div><div class="tile-v">{K}</div>
    <div class="tile-n">chosen on held-out likelihood, not a silhouette score</div></div>
  <div class="tile"><div class="tile-k">Player-games</div><div class="tile-v">{M['design_rows']:,}</div>
    <div class="tile-n">{M['players']:,} players, {M['date_min']} to {M['date_max']}</div></div>
  <div class="tile"><div class="tile-k">Best MAE on usage</div><div class="tile-v">{bm['mae']:.4f}</div>
    <div class="tile-n">vs {bb['mae']:.4f} for the best naive baseline</div></div>
  <div class="tile {'good' if delta_pct > 0.5 else 'flat'}"><div class="tile-k">Gain from adding roles</div>
    <div class="tile-v">{delta_pct:+.2f}%</div>
    <div class="tile-n">MAE change when soft roles join the same model</div></div>
</div>"""

# --- 1. Why positions fail ------------------------------------------------
spread = pl.read_parquet(ART / "position_spread.parquet")
spread_chart = hbar_chart(
    spread["position"].to_list(),
    spread["roles_spanned"].to_list(),
    label="Effective number of roles each listed position spans",
    value_label="roles spanned",
    dp=2,
    label_w=170,
)
spread_table = table_view(
    ["Listed position", "Player-games", "Entropy (nats)", "Effective roles spanned"],
    [[r["position"], f"{r['n']:,}", f"{r['entropy']:.3f}", f"{r['roles_spanned']:.2f}"]
     for r in spread.iter_rows(named=True)],
    "roles spanned per listed position",
)
section(
    "1. The premise, measured",
    f"""<p>Listed position is not just coarse &mdash; across much of the data it is
    <em>absent</em>. In <code>player_box_score</code>, <code>start_position</code> takes only
    <code>G</code>/<code>F</code>/<code>C</code> and is blank for 361,992 of 589,082 rows, because
    only starters get a value. <code>player_info.position</code> adds hyphenates but 4,946 of
    5,630 player-seasons are still a bare <em>Guard</em>, <em>Forward</em> or <em>Center</em>.</p>
    <p>The chart below is the quantitative form of your intuition: for each listed position,
    the effective number of distinct roles its players actually occupy (the exponential of the
    entropy of its role distribution). A label that described play would sit near 1.0.</p>
    {spread_chart}{spread_table}""",
    "If a position label spans four roles, it is discarding four-fifths of what it could say.",
)

# --- 2. Data and defects --------------------------------------------------
defects = table_view(
    ["#", "Defect", "Evidence", "Handling"],
    [
        [1, "DNPs encoded as zero usage, not missing",
         "105,394 of 589,082 rows (17.9%) have usg_pct = 0.0 with a null min. Naive mean usage 0.1510 vs played-only 0.1839.",
         "box_scores() flags played and blanks the fabricated targets"],
        [2, "statyx.advanced_stats duplicated ~2x by a bad season join",
         "116,972 rows collapse to 57,255 unique (player, game); both season labels span the identical date range over the same 2,600 game ids. 163 keys conflict on touches, 24 on usage_percentage.",
         "season discarded and rebuilt from the game map; conflicting copies averaged"],
        [3, "No shared identifiers between the nba and statyx schemas",
         "game 21501032 vs 900034932; player 200811 vs 1253150. Direct join yields zero matches.",
         "players bridged via util.player_id_map_vw (605 pairs); games rematched on (date, home, away), recovering 5,229 of 5,289"],
        [4, "period column is always 0 in advanced_stats",
         "Single distinct value across 116,972 rows.",
         "treated as whole-game rows, despite the name"],
    ],
    "defects found in the raw dumps",
)
section(
    "2. The data, and what was wrong with it",
    f"""<p>Four defects had to be fixed before any clustering was meaningful. The first is the
    dangerous one: a model trained without it learns that a fifth of all appearances have zero
    usage, which is not a fact about basketball but an artefact of how the dump encodes a
    healthy scratch.</p>{defects}
    <p>Coverage is lopsided across schemas. <code>player_box_score</code> runs 2009&ndash;2026;
    statyx <code>game_stats</code> and <code>schedule</code> cover four seasons;
    <code>advanced_stats</code> two; and <code>play_types</code>, the richest role signal of all
    (spot-up / iso / pick-and-roll handler / roll man / post-up / cut / off-screen), exists for
    <strong>2025-26 only, at season grain</strong>. That last point decided the design: play-type
    data cannot be a model input without leaking within-season information, so the backbone is
    box-score rates across the full history and statyx is an enrichment layer.</p>""",
    "Everything here is reproducible with uv run python -m scripts.audit.",
)

# --- 3. Methodology -------------------------------------------------------
section(
    "3. Method",
    f"""<ul class="method">
    <li><strong>Rates, not volumes.</strong> Role is a mix of activities, so counting stats are
      per-minute and shot types are shares of the player's own attempts. The same shot diet at
      12 or 36 minutes is the same role.</li>
    <li><strong>Usage excluded from the inputs.</strong> <code>usg_pct</code> and
      <code>e_usg_pct</code> are the downstream target; letting them define the roles would make
      any later "roles predict usage" result circular.</li>
    <li><strong>Efficiency excluded.</strong> <code>ts_pct</code>, <code>fg_pct</code> measure how
      well, not what. A cold-shooting spot-up shooter is still a spot-up shooter. The flag
      <code>include_efficiency=True</code> exists to test that claim.</li>
    <li><strong>Team context excluded.</strong> Ratings, <code>pace</code> and <code>poss</code>
      describe the five on the floor, not the individual.</li>
    <li><strong>Strictly prior games.</strong> Every feature is <code>shift(1)</code> then rolled
      over the previous 20 games per player, so a label is knowable before tip-off. Rows with
      fewer than 5 prior games are dropped.</li>
    <li><strong>Soft assignment.</strong> A Gaussian mixture returns responsibilities, not a hard
      id. A hard id would reimpose exactly the discreteness that makes listed position a poor
      description of the modern game.</li>
    </ul>
    <p>The resulting design matrix is {M['design_rows']:,} player-games by
    {M['n_features']} features, covering {M['players']:,} players from {M['date_min']} to
    {M['date_max']}. Mixtures are fitted on a 120,000-row sample of the pre-cutoff period
    (14 dimensions; the sample is ample and makes the k sweep tractable), and the cutoff for
    every fit is {M['cutoff']}.</p>""",
    "Each choice below is a decision that could have gone the other way; the flags to reverse them are in the code.",
)

# --- 4. Choosing k --------------------------------------------------------
ksweep = pl.read_parquet(ART / "k_sweep.parquet")
ll_chart = line_chart(
    ksweep["k"].to_list(),
    ksweep["heldout_loglik"].to_list(),
    label="Held-out log-likelihood by number of roles",
    x_label="number of roles (k)",
    y_label="held-out log-likelihood",
    highlight=K,
    highlight_note=f"k = {K} selected",
    y_dp=2,
)
share_chart = hbar_chart(
    [f"k = {k}" for k in ksweep["k"].to_list()],
    ksweep["min_cluster_share"].to_list(),
    label="Smallest cluster share by k",
    value_label="smallest cluster share",
    dp=3,
    label_w=80,
    row_h=24,
)
k_table = table_view(
    ["k", "BIC (fit)", "Log-lik (fit)", "Log-lik (held out)", "Smallest cluster share", "Fit seconds"],
    [[r["k"], f"{r['bic']:,.0f}", f"{r['fit_loglik']:.4f}", f"{r['heldout_loglik']:.4f}",
      f"{r['min_cluster_share']:.4f}", r["secs"]] for r in ksweep.iter_rows(named=True)],
    "k sweep",
)
section(
    "4. How many roles?",
    f"""<p>Held-out log-likelihood is the honest criterion here. BIC is computed on data the
    mixture has already seen, and with 409,320 training rows it will keep paying for extra
    components almost indefinitely. The sweep therefore scores each k on a period the model
    never saw &mdash; games from {M['cutoff']} onward.</p>
    {ll_chart}
    <p>Likelihood alone still creeps upward with k, so the selection rule is the smallest k
    within 1% of the best held-out likelihood that also leaves no cluster holding under 2% of
    held-out games. The second condition matters: past a point the mixture starts spending
    components on tiny pockets rather than real roles.</p>
    {share_chart}{k_table}""",
    "Chosen on out-of-sample likelihood with a floor on cluster size, not on a silhouette score.",
)

# --- 5. Stability ---------------------------------------------------------
stab = pl.read_parquet(ART / "stability.parquet")
seed = pl.read_parquet(ART / "seed_stability.parquet")
eras = sorted({*stab["cutoff_a"].to_list(), *stab["cutoff_b"].to_list()})
mat = [[None if a == b else next(
    (r["ari"] for r in stab.iter_rows(named=True)
     if {r["cutoff_a"], r["cutoff_b"]} == {a, b}), None)
    for b in eras] for a in eras]
stab_chart = heatmap(
    [e[:4] for e in eras], [e[:4] for e in eras], mat,
    label="Adjusted Rand Index between models fitted on different eras",
    diverging=False, value_dp=3, label_w=120,
)
stab_table = table_view(
    ["Fitted before", "vs fitted before", "ARI on common rows"],
    [[r["cutoff_a"], r["cutoff_b"], f"{r['ari']:.4f}"] for r in stab.iter_rows(named=True)]
    + [[f"seed {r['seed_a']}", f"seed {r['seed_b']}", f"{r['ari']:.4f}"] for r in seed.iter_rows(named=True)],
    "stability, across eras and across seeds",
)
section(
    "5. Do the roles survive refitting?",
    f"""<p>This is the test a position replacement has to pass and a purely predictive feature
    does not. If the taxonomy reshuffles whenever the fitting window moves, it is describing the
    sample rather than the game, and it cannot be the vocabulary of future analysis.</p>
    <p>Four mixtures were fitted on data before 2014, 2018, 2021 and {M['cutoff'][:4]}, then all four
    labelled the same recent rows. Adjusted Rand Index compares those labellings &mdash; 1.0 is
    identical partitions, 0.0 is chance.</p>
    {stab_chart}
    <p>Across eras, ARI ranges {stab['ari'].min():.3f} to {stab['ari'].max():.3f}. Across random
    seeds at fixed k it ranges {seed['ari'].min():.3f} to {seed['ari'].max():.3f}.</p>
    {stab_table}""",
    "Era-to-era agreement matters more than seed-to-seed: the former tests the concept, the latter only the optimiser.",
)

# --- 6. The roles themselves ---------------------------------------------
rows = prof.sort("role_label")
zmat = [[row[c] for c in feat_cols] for row in rows.iter_rows(named=True)]
prof_chart = heatmap(
    [rl(r["role_label"]).replace("&middot;", "·") for r in rows.iter_rows(named=True)],
    [nice(c) for c in feat_cols],
    zmat,
    label="Role signatures as feature z-scores",
    diverging=True, value_dp=2, label_w=215, cell=36,
)
sig_rows = []
for r in rows.iter_rows(named=True):
    top = sorted(((c, r[c]) for c in feat_cols), key=lambda kv: abs(kv[1]), reverse=True)[:4]
    sig_rows.append([
        r["role_label"], names_by_label[r["role_label"]], f"{r['n']:,}",
        ", ".join(f"{nice(c)} {v:+.2f}" for c, v in top),
    ])
sig_table = table_view(
    ["Role", "Name", "Player-games", "Signature (largest |z|)"], sig_rows, "role signatures")

ex = pl.read_parquet(ART / "exemplars.parquet")
ex_html = []
for label in range(K):
    who = (ex.filter(pl.col("role_label") == label).sort("conf", descending=True)
             .head(6)["player_name"].to_list())
    if who:
        ex_html.append(
            f'<div class="rolecard"><div class="rolename">{rl(label)}</div>'
            f'<div class="rolewho">{esc(", ".join(who))}</div></div>')
section(
    "6. What the roles are",
    f"""<p>Each role is described by how far its members sit from the league average on every
    feature, in standard deviations. Red is above average, blue below; the neutral midpoint is
    genuinely "league average", not a hue.</p>
    {prof_chart}{sig_table}
    <p class="sub">Highest-confidence members in 2025-26 (minimum 20 games). These names are the
    real test of whether the roles mean anything &mdash; the labels above were assigned from the
    z-score signatures, not from who landed in them.</p>
    <div class="rolegrid">{''.join(ex_html)}</div>""",
    "Names are derived from each role's own signature by rule, so they cannot flatter the result.",
)

# --- 7. vs position ------------------------------------------------------
ct = pl.read_parquet(ART / "position_crosstab.parquet")
positions = (ct.group_by("position").agg(pl.col("n").sum().alias("t"))
               .sort("t", descending=True)["position"].to_list())
ctm = []
for p in positions:
    tot = ct.filter(pl.col("position") == p)["n"].sum()
    ctm.append([
        float(ct.filter((pl.col("position") == p) & (pl.col("role_label") == l))["n"].sum()) / tot * 100
        for l in range(K)])
ct_chart = heatmap(
    positions, [rl(l).replace("&middot;", "·") for l in range(K)], ctm,
    label="Share of each listed position's player-games falling in each role",
    diverging=False, value_dp=1, unit="%", label_w=150, cell=40,
)
section(
    "7. Roles against listed position",
    f"""<p>Reading across a row shows how one listed position scatters across roles. If position
    carried the same information as role, each row would be a single dark cell.</p>
    {ct_chart}
    {table_view(["Listed position"] + [f"role {l}: {names_by_label[l]}" for l in range(K)],
                [[p] + [f"{v:.1f}%" for v in rowv] for p, rowv in zip(positions, ctm)],
                "position to role, row-normalised")}""",
    "Rows are percentages of that position's player-games.",
)

# --- 8. Downstream test --------------------------------------------------
u = usage.sort("mae")
groups = ["Naive baseline" if m.startswith("baseline") else
          ("Model with roles" if "roles" in m else "Model without roles")
          for m in u["model"].to_list()]
model_chart = hbar_chart(
    [m.replace("baseline: ", "").replace("lightgbm: ", "LGBM · ").replace("ridge: ", "Ridge · ")
     for m in u["model"].to_list()],
    u["mae"].to_list(),
    label="Mean absolute error predicting next-game usage",
    value_label="MAE",
    groups=groups,
    group_colors={"Naive baseline": "var(--series-2)",
                  "Model without roles": "var(--series-3)",
                  "Model with roles": "var(--series-1)"},
    dp=5, label_w=310, row_h=25,
)
imp_html = ""
if (ART / "feature_importance.parquet").exists():
    imp = pl.read_parquet(ART / "feature_importance.parquet").head(14)
    imp_html = hbar_chart(
        [nice(c) for c in imp["feature"].to_list()],
        [float(g) for g in imp["gain"].to_list()],
        label="LightGBM gain by feature",
        value_label="gain", dp=0, label_w=190, row_h=24,
    ) + table_view(
        ["Feature", "Gain"],
        [[nice(r["feature"]), f"{r['gain']:,.0f}"] for r in
         pl.read_parquet(ART / "feature_importance.parquet").iter_rows(named=True)],
        "feature importance, full model")
section(
    "8. Do the roles help predict usage?",
    f"""<p>The clustering is only worth keeping if it earns its place downstream. Every model is
    trained on games before {M['cutoff']} ({M['panel_train']:,} player-games) and evaluated on
    games after it ({M['panel_test']:,}), never on a random shuffle. The naive baselines come
    first, as they should.</p>
    {model_chart}
    {table_view(["Model", "MAE", "RMSE"],
                [[r["model"], f"{r['mae']:.5f}", f"{r['rmse']:.5f}"] for r in u.iter_rows(named=True)],
                "usage model comparison")}
    <p>The comparison that answers the question is the pair that differs only by the role
    columns: adding soft roles to the same feature set moves MAE by
    <strong>{delta_pct:+.2f}%</strong>.</p>
    {imp_html}""",
    "Time-based split, prior-game features only, baselines included.",
)

# --- 9. Softness ---------------------------------------------------------
section(
    "9. Why the assignment stays soft",
    f"""<p>Mean assignment confidence is {M['mean_confidence']:.3f}, and
    <strong>{M['frac_ambiguous'] * 100:.1f}%</strong> of player-games have a top responsibility
    below 0.6 &mdash; genuinely split between two roles. That share is exactly what a hard label
    would misrepresent, and it is the quantitative reason to carry responsibilities forward
    rather than an integer id.</p>
    <p>For downstream use, the recommended representation is the {K} responsibility columns plus
    <code>role_entropy</code>. The <code>role_label</code> column exists for plots and prose.</p>""",
)

# --- 10. Limits ----------------------------------------------------------
section(
    "10. Limits, and what I would not yet claim",
    """<ul class="method">
    <li><strong>The features are box-score shaped.</strong> Without tracking data over the full
      history, "role" here is a shot-and-activity diet. It cannot see screening, gravity, or
      off-ball defensive assignment. <code>statyx.advanced_stats</code> has
      <code>screen_assists</code>, <code>box_outs</code>, <code>contested_shots</code> and
      <code>touches</code>, but only for two seasons.</li>
    <li><strong>play_types is the obvious next input and is unusable as-is.</strong> One season,
      season-level grain. Its value would be as a <em>validation target</em>: do the clusters
      recover the play-type mix they were never shown?</li>
    <li><strong>The 2x duplication in advanced_stats is averaged, not resolved.</strong> 163
      keys genuinely disagree on touches. If the upstream dump can be fixed, fix it there.</li>
    <li><strong>Minutes are in the feature set.</strong> <code>r_min</code> is rotation role, but
      it also correlates with usage, so part of any downstream gain may be a minutes proxy
      rather than role. <code>include_volume=False</code> runs the ablation.</li>
    <li><strong>One cutoff, not rolling-origin folds.</strong> The split is a single
      train/test boundary. Repeating it across several origins would give error bars.</li>
    </ul>""",
)

# ---------------------------------------------------------------------------
# Shell
# ---------------------------------------------------------------------------
css = """
:root{color-scheme:light;
--page:#f9f9f7;--surface-1:#fcfcfb;--text-primary:#0b0b0b;--text-secondary:#52514e;
--muted:#898781;--gridline:#e1e0d9;--baseline:#c3c2b7;--border:rgba(11,11,11,.10);
--series-1:#2a78d6;--series-2:#eb6834;--series-3:#1baf7a;
--pole-pos:#e34948;--pole-neg:#2a78d6;--mid-neutral:#f0efec;
--seq-lo:#e8eef5;--seq-hi:#184f95;--good:#006300;}
@media (prefers-color-scheme:dark){:root:not([data-theme="light"]){color-scheme:dark;
--page:#0d0d0d;--surface-1:#1a1a19;--text-primary:#fff;--text-secondary:#c3c2b7;
--muted:#898781;--gridline:#2c2c2a;--baseline:#383835;--border:rgba(255,255,255,.10);
--series-1:#3987e5;--series-2:#d95926;--series-3:#199e70;
--pole-pos:#e66767;--pole-neg:#3987e5;--mid-neutral:#383835;
--seq-lo:#22262b;--seq-hi:#86b6ef;--good:#0ca30c;}}
:root[data-theme="dark"]{color-scheme:dark;
--page:#0d0d0d;--surface-1:#1a1a19;--text-primary:#fff;--text-secondary:#c3c2b7;
--muted:#898781;--gridline:#2c2c2a;--baseline:#383835;--border:rgba(255,255,255,.10);
--series-1:#3987e5;--series-2:#d95926;--series-3:#199e70;
--pole-pos:#e66767;--pole-neg:#3987e5;--mid-neutral:#383835;
--seq-lo:#22262b;--seq-hi:#86b6ef;--good:#0ca30c;}
*{box-sizing:border-box}
body{margin:0;background:var(--page);color:var(--text-primary);
font:16px/1.6 system-ui,-apple-system,"Segoe UI",sans-serif;}
.wrap{max-width:860px;margin:0 auto;padding:48px 16px 80px}
header h1{font-size:30px;line-height:1.22;margin:0 0 8px;letter-spacing:-.02em}
header .lede{color:var(--text-secondary);font-size:17px;margin:0 0 4px}
header .meta{color:var(--muted);font-size:13px;margin-top:14px}
section{background:var(--surface-1);border:1px solid var(--border);border-radius:12px;
padding:26px 24px;margin:22px 0}
h2{font-size:19px;margin:0 0 6px;letter-spacing:-.01em}
.sub{color:var(--text-secondary);font-size:14px;margin:0 0 16px}
p{margin:0 0 14px}
code{font-family:ui-monospace,SFMono-Regular,Menlo,monospace;font-size:.88em;
background:color-mix(in oklab,var(--text-primary) 7%,transparent);padding:1px 5px;border-radius:4px}
.chart{width:100%;height:auto;display:block;margin:6px 0 2px;overflow:visible}
.tick{fill:var(--muted);font-size:11px}
.axislabel{fill:var(--text-secondary);font-size:12px}
.catlabel{fill:var(--text-secondary);font-size:12px}
.vallabel{fill:var(--text-secondary);font-size:11.5px;font-variant-numeric:tabular-nums}
.cellval{fill:#fff;font-size:10.5px;font-variant-numeric:tabular-nums}
.annot{fill:var(--series-2);font-size:11.5px;font-weight:600}
.hit{cursor:crosshair}
.legend{display:flex;gap:16px;flex-wrap:wrap;margin:2px 0 6px;font-size:12.5px;color:var(--text-secondary)}
.chip{display:inline-flex;align-items:center;gap:6px}
.chip i{width:10px;height:10px;border-radius:3px;display:inline-block}
.tiles{display:grid;grid-template-columns:repeat(auto-fit,minmax(170px,1fr));gap:12px;margin:18px 0 4px}
.tile{background:var(--surface-1);border:1px solid var(--border);border-radius:12px;padding:16px}
.tile-k{color:var(--text-secondary);font-size:12.5px}
.tile-v{font-size:27px;letter-spacing:-.02em;margin:4px 0 2px}
.tile-n{color:var(--muted);font-size:11.5px;line-height:1.4}
.tile.good .tile-v{color:var(--good)}
.tile.flat .tile-v{color:var(--text-secondary)}
.tableview{margin:10px 0 2px;border-top:1px solid var(--border);padding-top:10px}
.tableview summary{cursor:pointer;color:var(--text-secondary);font-size:13px}
.scroll{overflow-x:auto;margin-top:12px}
table{border-collapse:collapse;width:100%;font-size:13px}
th,td{text-align:left;padding:7px 10px;border-bottom:1px solid var(--border);vertical-align:top}
th{color:var(--text-secondary);font-weight:600;white-space:nowrap}
td{font-variant-numeric:tabular-nums}
ul.method{margin:0 0 14px;padding-left:20px}
ul.method li{margin-bottom:9px}
.rolegrid{display:grid;grid-template-columns:repeat(auto-fit,minmax(240px,1fr));gap:10px;margin-top:10px}
.rolecard{border:1px solid var(--border);border-radius:10px;padding:12px 14px}
.rolename{font-size:13px;font-weight:600;margin-bottom:4px}
.rolewho{color:var(--text-secondary);font-size:12.5px;line-height:1.5}
#tip{position:fixed;pointer-events:none;opacity:0;transition:opacity .1s;
background:var(--text-primary);color:var(--surface-1);font-size:12px;padding:6px 9px;
border-radius:6px;z-index:9;white-space:nowrap;font-variant-numeric:tabular-nums}
footer{color:var(--muted);font-size:12.5px;margin-top:28px;text-align:center}
@media(max-width:640px){.wrap{padding:28px 16px 60px}header h1{font-size:24px}}
"""

js = """
const tip=document.getElementById('tip');
document.addEventListener('mouseover',e=>{const t=e.target.closest('.hit');
if(!t||!t.dataset.tip)return;tip.innerHTML=t.dataset.tip;tip.style.opacity='1';});
document.addEventListener('mousemove',e=>{if(tip.style.opacity!=='1')return;
const p=12;let x=e.clientX+p,y=e.clientY+p;const r=tip.getBoundingClientRect();
if(x+r.width>innerWidth-8)x=e.clientX-r.width-p;
if(y+r.height>innerHeight-8)y=e.clientY-r.height-p;
tip.style.left=x+'px';tip.style.top=y+'px';});
document.addEventListener('mouseout',e=>{if(e.target.closest('.hit'))tip.style.opacity='0';});
"""

html_doc = f"""<!doctype html>
<html lang="en"><head><meta charset="utf-8">
<meta name="viewport" content="width=device-width,initial-scale=1">
<title>Role Clusters</title>
<style>{css}</style></head>
<body><div id="tip"></div><div class="wrap">
<header>
  <h1>Role clusters: a data-driven replacement for listed position</h1>
  <p class="lede">Listed position describes where a player stood in 1985. This fits roles from
  what players actually do &mdash; measured only from games already played, so a role is known
  before tip-off &mdash; and tests whether those roles survive refitting and whether they earn
  their place in a usage model.</p>
  <p class="meta">{M['design_rows']:,} player-games &middot; {M['players']:,} players &middot;
  {M['date_min']} to {M['date_max']} &middot; fit cutoff {M['cutoff']} &middot;
  generated {date.today().isoformat()}</p>
</header>
{hero}
{''.join(parts)}
<footer>Reproduce: <code>uv run python -m scripts.audit</code> &middot;
<code>uv run python -m scripts.experiment</code> &middot;
<code>uv run python -m scripts.report</code></footer>
</div><script>{js}</script></body></html>
"""
OUT.write_text(html_doc)
print(f"wrote {OUT} ({len(html_doc):,} bytes), k={K}")
