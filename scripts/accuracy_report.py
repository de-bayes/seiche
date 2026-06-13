"""Build reports/accuracy_report.pdf: a four-page plain-language accuracy
report on the SISH forecaster, from the 131k out-of-sample pairs dumped
by report_pairs.py. Style matches the site: white, serif, one accent."""

import pathlib
import sys

import numpy as np
import pandas as pd
import matplotlib
matplotlib.use("Agg")
import matplotlib.pyplot as plt
from matplotlib.backends.backend_pdf import PdfPages

sys.path.insert(0, str(pathlib.Path(__file__).resolve().parent.parent))

ACCENT = "#1257a0"
INK = "#16181d"
MUTED = "#5b6470"
FAINT = "#aab2bb"
AMBER = "#b45309"
RULE = "#e7e7e7"
CF = 1.8
F = lambda c: c * 1.8 + 32

plt.rcParams.update({
    "font.family": "serif",
    "font.serif": ["Lora", "Georgia", "Times New Roman", "DejaVu Serif"],
    "text.color": INK, "axes.edgecolor": RULE, "axes.labelcolor": MUTED,
    "xtick.color": MUTED, "ytick.color": MUTED, "axes.titlecolor": INK,
    "figure.facecolor": "white", "axes.facecolor": "white",
    "axes.grid": True, "grid.color": RULE, "grid.linewidth": 0.6,
    "axes.spines.top": False, "axes.spines.right": False,
    "font.size": 8.5, "axes.titlesize": 9.5, "axes.labelsize": 8,
})

d = pd.read_csv("data/report_pairs.csv", parse_dates=["t"])
d["fold"] = d["fold"].astype(str)  # csv round-trip turns the year names into ints
d["err"] = (d.p50 - d.y) * CF                  # signed error, deg F
d["aerr"] = d.err.abs()
d["aerr_p"] = (d.persist - d.y).abs() * CF
d["month"] = d.t.dt.month
HS = sorted(d.h.unique())
A4 = (8.27, 11.69)
M = 0.085  # page margin as figure fraction


def page(pdf, title, kicker):
    fig = plt.figure(figsize=A4)
    fig.text(M, 0.955, kicker.upper(), fontsize=7.5, color=ACCENT,
             family="serif", weight="bold")
    fig.text(M, 0.925, title, fontsize=17, weight="bold", color=INK)
    fig.add_artist(plt.Line2D([M, 1 - M], [0.912, 0.912], color=RULE, lw=0.8,
                              transform=fig.transFigure))
    return fig


def foot(fig, n):
    fig.text(M, 0.03, "SISH accuracy report", fontsize=7, color=FAINT)
    fig.text(1 - M, 0.03, str(n), fontsize=7, color=FAINT, ha="right")


def by_h(frame, col="aerr", fn="mean"):
    g = frame.groupby("h")[col]
    return getattr(g, fn)().reindex(HS)


pdf = PdfPages("reports/accuracy_report.pdf")

# ---------------------------------------------------------------- page 1
fig = page(pdf, "How accurate is the water forecast?", "SISH · accuracy report")
gen = pd.Timestamp.now().strftime("%B %d, %Y")
n_pairs = len(d)
mae24 = d[d.h == 24].aerr.mean()
mae168 = d[d.h == 168].aerr.mean()
p24 = d[d.h == 24].aerr_p.mean()
p168 = d[d.h == 168].aerr_p.mean()

fig.text(M, 0.885, f"{gen} · Wilmette buoy 45174, Lake Michigan", fontsize=8.5, color=MUTED)
abstract = (
    "SISH forecasts the water temperature off the Evanston and Wilmette shoreline, "
    "hour by hour, up to seven days ahead. This report measures how good those forecasts "
    "actually are. The test is strict: the model was retrained nine separate times, once "
    "for each season from 2018 to 2026, and each time it was scored only on weeks of data "
    f"it had never seen. That gives {n_pairs:,} forecast-versus-reality pairs. Every number "
    "in this report comes from those held-out pairs, never from data the model trained on.\n\n"
    f"The short version: one day ahead, the forecast is typically off by about "
    f"{mae24:.1f} °F. Seven days ahead, by about {mae168:.1f} °F. The honest "
    "competitor is persistence, the assumption that the water simply stays the temperature "
    f"it is right now. Persistence is off by {p24:.1f} °F at one day and {p168:.1f} "
    "°F at seven days. So at one day the model and persistence are close, because "
    "water temperature genuinely does not move much in a day. From two days out the model "
    "pulls away, and by a week it is roughly twice as accurate as assuming nothing changes."
)
fig.text(M, 0.872, abstract, fontsize=9, color=INK, va="top", wrap=True,
         linespacing=1.55, ha="left",
         bbox=dict(boxstyle="square,pad=0", fc="none", ec="none"),
         transform=fig.transFigure, figure=fig)

ax = fig.add_axes([M, 0.405, 1 - 2 * M, 0.27])
for fold, g in d.groupby("fold"):
    ax.plot(HS, g.groupby("h").aerr.mean().reindex(HS), color=ACCENT, alpha=0.18, lw=0.9)
ax.plot(HS, by_h(d), color=ACCENT, lw=2.4, marker="o", ms=3.5, label="model, all-season mean")
ax.plot(HS, by_h(d, "aerr_p"), color=MUTED, lw=1.8, ls="--", label="persistence (no change)")
ax.set_xticks([1, 24, 48, 72, 96, 120, 144, 168])
ax.set_xlabel("lead time (hours ahead)")
ax.set_ylabel("mean absolute error (°F)")
ax.set_title("Figure 1 · Average miss by lead time: the model vs assuming no change", loc="left")
ax.legend(frameon=False, fontsize=8)
fig.text(M, 0.355,
         "Thin lines are the nine individual seasons; the bold line is their average. The model's "
         "error grows slowly and almost levels off, while persistence keeps getting worse: the "
         "longer the horizon, the more the lake drifts from where it started.",
         fontsize=8, color=MUTED, va="top", linespacing=1.5, wrap=True)

stats_y = 0.25
for i, (label, val) in enumerate([
        ("HELD-OUT PAIRS", f"{n_pairs:,}"),
        ("SEASONS REPLAYED", "9"),
        ("+24 H TYPICAL MISS", f"{mae24:.2f} °F"),
        ("+168 H TYPICAL MISS", f"{mae168:.2f} °F"),
        ("EDGE VS PERSISTENCE, +168 H", f"{(1 - mae168 / p168) * 100:.0f}%"),
]):
    x = M + i * (1 - 2 * M) / 5
    fig.text(x, stats_y, label, fontsize=6.2, color=MUTED)
    fig.text(x, stats_y - 0.03, val, fontsize=13, color=INK, weight="bold")
fig.add_artist(plt.Line2D([M, 1 - M], [stats_y + 0.025, stats_y + 0.025],
                          color=RULE, lw=0.8, transform=fig.transFigure))
foot(fig, 1)
pdf.savefig(fig); plt.close(fig)

# ---------------------------------------------------------------- page 2
fig = page(pdf, "When is it accurate?", "Seasons, months, and the hard days")

# (a) by season
ax = fig.add_axes([M, 0.63, 0.40, 0.235])
folds = sorted(d.fold.unique())
fm = [d[d.fold == f].aerr.mean() for f in folds]
fp = [d[d.fold == f].aerr_p.mean() for f in folds]
xs = np.arange(len(folds))
ax.bar(xs - 0.19, fm, 0.38, color=ACCENT, label="model")
ax.bar(xs + 0.19, fp, 0.38, color="#c6cdd4", label="persistence")
ax.set_xticks(xs); ax.set_xticklabels(folds, rotation=45, fontsize=7)
ax.set_ylabel("mean absolute error (°F)")
ax.set_title("Figure 2a · Error by season (all leads pooled)", loc="left")
ax.legend(frameon=False, fontsize=7.5)

# (b) by month
ax = fig.add_axes([0.57, 0.63, 0.36, 0.235])
mm = d.groupby("month").aerr.mean()
mp = d.groupby("month").aerr_p.mean()
labels = {5: "May", 6: "Jun", 9: "Sep", 10: "Oct", 11: "Nov"}
ax.bar(np.arange(len(mm)) - 0.19, mm.values, 0.38, color=ACCENT)
ax.bar(np.arange(len(mm)) + 0.19, mp.values, 0.38, color="#c6cdd4")
ax.set_xticks(np.arange(len(mm)))
ax.set_xticklabels([labels.get(m, str(m)) for m in mm.index], fontsize=7.5)
ax.set_ylabel("MAE (°F)")
ax.set_title("Figure 2b · Error by calendar month", loc="left")

fig.text(M, 0.585,
         "The test windows fall at the end of each season (mostly October and November) plus the "
         "live weeks of 2026 (May and June). 2019 stands out: a violent series of autumn wind events "
         "made it the hardest season in the record, and the only one where the model failed to beat "
         "persistence. Spring weeks are friendlier: the water is stratified gently and moves slowly.",
         fontsize=8, color=MUTED, va="top", linespacing=1.5, wrap=True)

# (c) typical vs bad-day error growth
ax = fig.add_axes([M, 0.27, 0.40, 0.235])
ax.plot(HS, d.groupby("h").aerr.median().reindex(HS), color=ACCENT, lw=2, label="median miss")
ax.plot(HS, d.groupby("h").aerr.quantile(0.9).reindex(HS), color=AMBER, lw=2, label="90th percentile (bad day)")
ax.set_xticks([1, 24, 72, 120, 168])
ax.set_xlabel("lead time (hours)"); ax.set_ylabel("absolute error (°F)")
ax.set_title("Figure 2c · Typical day vs bad day", loc="left")
ax.legend(frameon=False, fontsize=7.5)

# (d) coverage by lead
ax = fig.add_axes([0.57, 0.27, 0.36, 0.235])
cov = d.assign(inb=(d.y >= d.p05) & (d.y <= d.p95)).groupby("h").inb.mean().reindex(HS)
ax.plot(HS, cov * 100, color=ACCENT, lw=2, marker="o", ms=3)
ax.axhline(90, color=MUTED, ls="--", lw=1)
ax.text(165, 90.8, "target 90%", fontsize=7, color=MUTED, ha="right")
ax.set_ylim(60, 100)
ax.set_xticks([1, 24, 72, 120, 168])
ax.set_xlabel("lead time (hours)"); ax.set_ylabel("% of outcomes inside raw band")
ax.set_title("Figure 2d · Raw band coverage before calibration", loc="left")

fig.text(M, 0.225,
         "Figure 2c separates the ordinary from the painful: half of all one-day forecasts miss by "
         "under half a degree, but the worst tenth miss by two degrees or more, and bad days grow "
         "faster with lead time than typical ones. Figure 2d is why the published forecast does not "
         "trust the model's own confidence: the band the model learns directly is too narrow, "
         "covering 75 to 85 percent instead of 90. The live site therefore widens the band using "
         "exactly these nine seasons of misses (a procedure called conformal calibration), which "
         "makes 90 percent coverage hold by construction on this record.",
         fontsize=8, color=MUTED, va="top", linespacing=1.5, wrap=True)
foot(fig, 2)
pdf.savefig(fig); plt.close(fig)

# ---------------------------------------------------------------- page 3
fig = page(pdf, "How does it miss?", "Bias, conditions, and the worst events")

# (a) residual distributions
ax = fig.add_axes([M, 0.63, 0.40, 0.235])
for hh, color, alpha in [(24, ACCENT, 0.85), (72, AMBER, 0.75), (168, "#7a8b9c", 0.65)]:
    sub = d[d.h == hh].err
    ax.hist(sub, bins=np.arange(-6, 6.1, 0.25), density=True,
            histtype="step", lw=1.8, color=color, alpha=alpha, label=f"+{hh} h")
ax.axvline(0, color=RULE, lw=1)
ax.set_xlim(-6, 6)
ax.set_xlabel("forecast minus outcome (°F)"); ax.set_ylabel("density")
ax.set_title("Figure 3a · Where the misses fall", loc="left")
ax.legend(frameon=False, fontsize=7.5)

# (b) bias by lead
ax = fig.add_axes([0.57, 0.63, 0.36, 0.235])
ax.plot(HS, d.groupby("h").err.mean().reindex(HS), color=ACCENT, lw=2, marker="o", ms=3)
ax.axhline(0, color=MUTED, ls="--", lw=1)
ax.set_xticks([1, 24, 72, 120, 168])
ax.set_xlabel("lead time (hours)"); ax.set_ylabel("mean signed error (°F)")
ax.set_title("Figure 3b · Bias: does it run warm or cold?", loc="left")

fig.text(M, 0.585,
         "Misses are roughly symmetric and centered near zero at every lead: the model runs slightly "
         "warm at long leads (under half a degree) because the violent events it underestimates are "
         "mostly sudden cooling. The long left tail in Figure 3a is upwelling: wind pushes the warm "
         "surface water offshore and cold deep water surfaces in hours. Those events are the single "
         "hardest thing this model has to predict.",
         fontsize=8, color=MUTED, va="top", linespacing=1.5, wrap=True)

# (c) conditional on wind
ax = fig.add_axes([M, 0.27, 0.40, 0.235])
sub = d[d.h == 24].copy()
bins = [0, 3, 5, 7, 9, 12, 25]
sub["wbin"] = pd.cut(sub.wspd_fut, bins)
g = sub.groupby("wbin", observed=True).aerr.agg(["mean", "count"])
labels = [f"{int(iv.left)}-{int(iv.right)}" if iv.right <= 12 else f"{int(iv.left)}+"
          for iv in g.index]
ax.bar(range(len(g)), g["mean"], 0.62, color=ACCENT)
ax.set_xticks(range(len(g)))
ax.set_xticklabels(labels, fontsize=7.5)
ax.set_xlabel("forecast-window wind speed (m/s)")
ax.set_ylabel("+24 h MAE (°F)")
ax.set_title("Figure 3c · Wind makes it hard", loc="left")

# (d) worst events table
ax = fig.add_axes([0.55, 0.27, 0.40, 0.235]); ax.axis("off")
worst = d[d.h == 24].nlargest(400, "aerr").copy()
worst["date"] = worst.t.dt.date
ev = worst.groupby("date").agg(miss=("aerr", "max"), obs=("y", "mean")).nlargest(6, "miss")
rows = [["date", "worst +24 h miss", "water temp"]]
for date, r in ev.iterrows():
    rows.append([str(date), f"{r.miss:.1f} °F", f"{F(r.obs):.0f} °F"])
tab = ax.table(cellText=rows[1:], colLabels=rows[0], loc="center", cellLoc="center")
tab.auto_set_font_size(False); tab.set_fontsize(8); tab.scale(1, 1.5)
for k, cell in tab.get_celld().items():
    cell.set_edgecolor(RULE)
    if k[0] == 0:
        cell.set_text_props(color=MUTED, fontsize=7)
        cell.set_facecolor("#f7f7f5")
ax.set_title("Figure 3d · The six worst forecast days", loc="left", y=1.02)

fig.text(M, 0.225,
         "Figure 3c conditions the one-day error on how windy the forecast window was: under calm "
         "conditions the typical miss is small, and it roughly triples in the strongest wind bin. "
         "The worst single days (3d) are all autumn wind events, several of them textbook upwelling. "
         "This is the honest boundary of the model's skill: it knows wind matters, but the exact "
         "timing and depth of an overturn is chaotic, which is precisely what the forecast band "
         "exists to express.",
         fontsize=8, color=MUTED, va="top", linespacing=1.5, wrap=True)
foot(fig, 3)
pdf.savefig(fig); plt.close(fig)

# ---------------------------------------------------------------- page 4
fig = page(pdf, "Can you trust the band?", "Calibration, a case study, and the verdict")

# (a) band width vs achieved spread
ax = fig.add_axes([M, 0.64, 0.40, 0.225])
w = d.assign(width=(d.p95 - d.p05) * CF).groupby("h").width.mean().reindex(HS)
ax.plot(HS, w, color=ACCENT, lw=2, label="raw learned band width")
q90 = d.groupby("h").aerr.quantile(0.9).reindex(HS) * 2
ax.plot(HS, q90, color=AMBER, lw=2, ls="--", label="width needed for 90%")
ax.set_xticks([1, 24, 72, 120, 168])
ax.set_xlabel("lead time (hours)"); ax.set_ylabel("90% band width (°F)")
ax.set_title("Figure 4a · The learned band vs what 90% actually takes", loc="left")
ax.legend(frameon=False, fontsize=7.5)

# (b) coverage by fold at +24h
ax = fig.add_axes([0.57, 0.64, 0.36, 0.225])
cv = d[d.h == 24].assign(inb=lambda x: (x.y >= x.p05) & (x.y <= x.p95)).groupby("fold").inb.mean()
ax.scatter(range(len(cv)), cv * 100, color=ACCENT, s=28, zorder=3)
ax.axhline(90, color=MUTED, ls="--", lw=1)
ax.set_xticks(range(len(cv))); ax.set_xticklabels(cv.index, rotation=45, fontsize=7)
ax.set_ylim(50, 100)
ax.set_ylabel("% inside raw band, +24 h")
ax.set_title("Figure 4b · Raw coverage season by season", loc="left")

# (c) case study: the hardest stretch (2019 fold, +24h)
ax = fig.add_axes([M, 0.30, 1 - 2 * M, 0.255])
cs = d[(d.fold == "2019") & (d.h == 24)].sort_values("t")
tt = cs.t + pd.Timedelta(hours=24)
ax.fill_between(tt, F(cs.p05), F(cs.p95), color=ACCENT, alpha=0.13, label="raw 90% band")
ax.plot(tt, F(cs.p50), color=ACCENT, lw=1.6, label="+24 h forecast")
ax.plot(tt, F(cs.y), color=INK, lw=1.2, label="what the water did")
ax.set_ylabel("water temperature (°F)")
ax.set_title("Figure 4c · The hardest stretch in the record: autumn 2019, one-day-ahead forecasts", loc="left")
ax.legend(frameon=False, fontsize=7.5, ncol=3)
ax.tick_params(axis="x", labelsize=7)

verdict = (
    "Figure 4a is the report's most important honesty check. The band the model learns on its own "
    "(blue) is consistently narrower than what nine seasons of reality demanded (amber). That gap is "
    "why the published site recalibrates the band on these misses before showing it. Figure 4c shows "
    "the system at its worst: October 2019, when repeated wind events dropped the nearshore water "
    "several degrees in single days. The forecast tracks each crash with a few hours of lag and the "
    "raw band is breached repeatedly, which is exactly the behavior the calibrated band is sized to "
    "absorb.\n\n"
    "Verdict, in plain words: within a day or two, trust the median to about a degree. Across a week, "
    "trust the direction and the band, not the exact number. The forecast is most reliable in calm, "
    "warming weather and least reliable when sustained north winds blow along the shore in fall, and "
    "it tells you so in real time, because those are precisely the conditions under which its "
    "published band visibly widens."
)
fig.text(M, 0.245, verdict, fontsize=9, color=INK, va="top", linespacing=1.55, wrap=True)
foot(fig, 4)
pdf.savefig(fig); plt.close(fig)

info = pdf.infodict()
info["Title"] = "SISH accuracy report"
info["Author"] = "Ryan McComb"
pdf.close()
print("wrote reports/accuracy_report.pdf")
