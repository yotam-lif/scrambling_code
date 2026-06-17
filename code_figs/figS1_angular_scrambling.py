import argparse
import os
import multiprocessing

import numpy as np
import pandas as pd
import matplotlib.pyplot as plt
import matplotlib as mpl
import seaborn as sns
from matplotlib.ticker import MaxNLocator
from scipy.stats import cramervonmises_2samp, ks_2samp, wasserstein_distance

# ----------------------------------------------------------------
# 1. VISUAL STYLE CONFIGURATION
# ----------------------------------------------------------------
plt.rcParams["font.family"] = "sans-serif"
mpl.rcParams.update({
    "axes.labelsize": 16,
    "xtick.labelsize": 12,
    "ytick.labelsize": 12,
    "legend.fontsize": 14,
})

CMR_COLORS = sns.color_palette("CMRmap", 4)
DEFAULT_SUBSET_DISTANCE_METRIC = "emd"


def apply_axis_style(ax, label):
    ax.text(
        -0.08, 1.04, label,
        transform=ax.transAxes,
        fontsize=17,
        fontweight="bold",
        va="bottom",
        ha="left",
    )
    for spine in ax.spines.values():
        spine.set_linewidth(1.4)
    ax.tick_params(width=1.4, length=5, which="major")
    ax.tick_params(width=1.2, length=3, which="minor")
    ax.grid(False)


def normalize_distance_metric(metric):
    metric_key = metric.strip().lower().replace("-", "_").replace(" ", "_")
    aliases = {
        "cvm": "cvm",
        "cramervonmises": "cvm",
        "cramer_von_mises": "cvm",
        "emd": "emd",
        "earth_movers_distance": "emd",
        "earth_mover_distance": "emd",
        "earthmovers": "emd",
        "wasserstein": "emd",
        "ks": "ks",
        "ks_2samp": "ks",
        "kolmogorov_smirnov": "ks",
    }
    if metric_key not in aliases:
        raise ValueError(f"Unsupported metric '{metric}'. Choose from cvm, emd, or ks.")
    return aliases[metric_key]


def distance_metric_label(metric):
    metric_key = normalize_distance_metric(metric)
    labels = {
        "cvm": "CvM distance",
        "emd": "Earth mover's distance",
        "ks": "KS statistic",
    }
    return labels[metric_key]


def compute_distance_metric(values_a, values_b, metric):
    metric_key = normalize_distance_metric(metric)
    if metric_key == "cvm":
        return cramervonmises_2samp(values_a, values_b).statistic
    if metric_key == "emd":
        return wasserstein_distance(values_a, values_b)
    if metric_key == "ks":
        return ks_2samp(values_a, values_b).statistic
    raise ValueError(f"Unsupported metric '{metric}'")


# ----------------------------------------------------------------
# 2. MODEL CLASSES
# ----------------------------------------------------------------
class FisherModel:
    def __init__(self, n, sigma, m, R0, seed=None):
        self.n = int(n)
        self.sigma = float(sigma)
        self.m = int(m)
        self.rng = np.random.default_rng(seed)
        self.deltas = self.rng.normal(loc=0.0, scale=self.sigma, size=(self.m, self.n))
        self.R0 = float(R0)
        self.r = np.zeros(self.n)
        self.r[0] = self.R0

    def compute_fitness(self, r):
        return np.exp(-0.5 * np.dot(r, r))

    def compute_dfe(self, r):
        w0 = self.compute_fitness(r)
        r_new = r + self.deltas
        r2_new = np.einsum("ij,ij->i", r_new, r_new)
        w_new = np.exp(-0.5 * r2_new)
        return w_new - w0

    @staticmethod
    def normalize(vec):
        norm = np.linalg.norm(vec)
        if norm <= 0:
            return np.zeros_like(vec)
        return vec / norm


class FisherConstantRadius(FisherModel):
    def step(self, epsilon):
        r_candidates = self.r + self.deltas
        dists = np.linalg.norm(r_candidates, axis=1)
        valid_mask = (dists >= (self.R0 - epsilon)) & (dists <= (self.R0 + epsilon))
        valid_indices = np.nonzero(valid_mask)[0]
        if len(valid_indices) == 0:
            return False
        choice = self.rng.choice(valid_indices)
        self.r += self.deltas[choice]
        return True


class FisherSSWM(FisherModel):
    def step(self):
        dfe = self.compute_dfe(self.r)
        beneficial_mask = dfe > 0
        if not np.any(beneficial_mask):
            return False
        ben_indices = np.nonzero(beneficial_mask)[0]
        ben_effects = dfe[ben_indices]
        probs = ben_effects / np.sum(ben_effects)
        choice = self.rng.choice(ben_indices, p=probs)
        self.r += self.deltas[choice]
        # In FGM, if a mutation fixes, the forward mutation flips sign
        self.deltas[choice] *= -1
        return True


# ----------------------------------------------------------------
# 3. SIMULATION WORKER
# ----------------------------------------------------------------
def run_single_replicate(args):
    mode, seed, n, sigma, m, R0, params, max_t, time_points = args

    R_final = params.get("R_final", 0.0)
    subset_metric = normalize_distance_metric(
        params.get("subset_metric", DEFAULT_SUBSET_DISTANCE_METRIC)
    )

    if mode == "constant":
        model = FisherConstantRadius(n, sigma, m, R0, seed=seed)
        epsilon = params["epsilon"]
    elif mode == "sswm":
        model = FisherSSWM(n, sigma, m, R0, seed=seed)
    else:
        raise ValueError(f"Unsupported mode: {mode}")

    rhat0 = FisherModel.normalize(model.r)

    # Use a static copy of the exact initial mutations generated by the model
    # to track the correlation of those same mutation fitness effects in time.
    initial_deltas = model.deltas.copy()
    delta_norms_sq = np.sum(initial_deltas ** 2, axis=1)

    def get_malthusian(r):
        return -0.5 * delta_norms_sq - np.dot(initial_deltas, r)

    def get_fitness_effects(r):
        return model.compute_fitness(r) * np.expm1(get_malthusian(r))

    dfe0 = get_fitness_effects(model.r)
    # M is fixed at t=0: the mutations that are initially beneficial.
    initial_beneficial_mask = dfe0 > 0

    def get_subset_distance(dfe_t):
        if not np.any(initial_beneficial_mask):
            return np.nan
        tracked_dfe_t = dfe_t[initial_beneficial_mask]
        return compute_distance_metric(tracked_dfe_t, dfe_t, subset_metric)

    subset_distance0 = get_subset_distance(dfe0)

    cosines = np.full(len(time_points), np.nan)
    radii = np.full(len(time_points), np.nan)
    pearsons = np.full(len(time_points), np.nan)
    integrals = np.full(len(time_points), np.nan)  # Array for the running integral
    subset_distances = np.full(len(time_points), np.nan)

    cosines[0] = 1.0
    radii[0] = np.linalg.norm(model.r)
    pearsons[0] = 1.0
    integrals[0] = 0.0
    if np.isfinite(subset_distance0):
        subset_distances[0] = 1.0

    current_t_idx = 0
    time_points_set = set(time_points)

    # Track the integral step-by-step to avoid subsampling trapezoidal errors
    running_integral = 0.0
    prev_R = radii[0]

    for t in range(1, max_t + 1):
        success = model.step(epsilon) if mode == "constant" else model.step()
        if not success:
            break

        current_R = np.linalg.norm(model.r)

        # Calculate the continuous area for this specific step (dt = 1)
        running_integral += 0.5 * (1.0 / prev_R ** 2 + 1.0 / current_R ** 2)
        prev_R = current_R

        if t in time_points_set:
            current_t_idx += 1
            rhatt = FisherModel.normalize(model.r)
            cos_val = float(np.dot(rhat0, rhatt))
            cosines[current_t_idx] = np.clip(cos_val, -1.0, 1.0)
            radii[current_t_idx] = current_R
            integrals[current_t_idx] = running_integral  # Save the running tally

            # Track Pearson correlation of the initial mutation fitness effects.
            dfe_t = get_fitness_effects(model.r)
            if np.std(dfe_t) > 1e-12 and np.std(dfe0) > 1e-12:
                pearsons[current_t_idx] = np.corrcoef(dfe0, dfe_t)[0, 1]
            if np.isfinite(subset_distance0) and subset_distance0 > 1e-12:
                subset_distance_t = get_subset_distance(dfe_t)
                if np.isfinite(subset_distance_t):
                    subset_distances[current_t_idx] = subset_distance_t / subset_distance0

        # Break after recording to ensure the final state is captured
        if mode == "sswm" and current_R < R_final:
            break

    return cosines, radii, pearsons, integrals, subset_distances


# ----------------------------------------------------------------
# 4. HELPERS
# ----------------------------------------------------------------
def stack_results(res_list):
    values = np.array([res[0] for res in res_list], dtype=float)
    radii = np.array([res[1] for res in res_list], dtype=float)
    pearsons = np.array([res[2] for res in res_list], dtype=float)
    integrals = np.array([res[3] for res in res_list], dtype=float)
    subset_distances = np.array([res[4] for res in res_list], dtype=float)
    return values, radii, pearsons, integrals, subset_distances


def summarize_log_traces(values, tiny=1e-12, log_offset=0.0):
    mean = np.nanmean(values, axis=0)
    std = np.nanstd(values, axis=0)

    mean_shift = mean + log_offset
    lower_shift = mean - std + log_offset
    upper_shift = mean + std + log_offset

    mean_clip = np.clip(mean_shift, tiny, None)
    lower_clip = np.clip(lower_shift, tiny, None)
    upper_clip = np.clip(upper_shift, tiny, None)

    return np.log(mean_clip), np.log(lower_clip), np.log(upper_clip), mean, std


def summarize_logged_positive_traces(values, tiny=1e-2):
    logged = np.log(np.clip(values, tiny, None))
    return np.nanmean(logged, axis=0), np.nanstd(logged, axis=0)


def make_long_df(values, time_points, value_name):
    rows = []
    for rep_idx in range(values.shape[0]):
        for t, val in zip(time_points, values[rep_idx]):
            if not np.isnan(val):
                rows.append({"Time": int(t), value_name: float(val), "Rep": rep_idx})
    return pd.DataFrame(rows)


# ----------------------------------------------------------------
# 5. MAIN EXPERIMENT
# ----------------------------------------------------------------
def run_experiment(subset_metric=DEFAULT_SUBSET_DISTANCE_METRIC):
    subset_metric = normalize_distance_metric(subset_metric)
    subset_metric_label = distance_metric_label(subset_metric)

    sigma = 0.05
    reps = 100

    # ------------------------------
    # Panel A
    # ------------------------------
    n_A = 20
    m_A = 8 * 10 ** 3
    R0_A_tilde = 40
    R0_A = R0_A_tilde * sigma
    epsilon_A = sigma
    max_t_A = 100
    tp_A = np.arange(0, max_t_A + 1)
    tau_A = (2 * R0_A ** 2) / ((n_A - 1) * sigma ** 2)
    log_offset_A = 1e-3

    # ------------------------------
    # Panel B
    # ------------------------------
    n_B = 20
    m_B = 8 * 10 ** 3
    R0_B_tilde = 20
    RF_B_tilde = 5
    R0_B = R0_B_tilde * sigma
    RF_B = RF_B_tilde * sigma
    V_SSWM_B = sigma * np.sqrt(np.pi / 2)
    est_steps_B = int((R0_B - RF_B) / V_SSWM_B)
    max_t_B = int(est_steps_B * 1.5)
    tp_B = np.arange(0, max_t_B + 1, max(1, max_t_B // 100))

    # ------------------------------
    # Panel C
    # ------------------------------
    n_C = 40
    m_C = 5 * 10 ** 3
    R0_C_tilde = 80
    R0_C = R0_C_tilde * sigma
    max_t_C = 50
    tp_C = np.arange(0, max_t_C + 1)
    tau_C = (2 * R0_C ** 2) / ((n_C - 1) * sigma ** 2)

    # ------------------------------
    # Panel D
    # ------------------------------
    n_D = 40
    m_D = 5 * 10 ** 3
    R0_D_tilde = 8
    R0_D = R0_D_tilde * sigma
    max_t_D = 3
    tp_D = np.arange(0, max_t_D + 1)
    tau_D = (2 * R0_D ** 2) / ((n_D - 1) * sigma ** 2)


    print("--- Configuration ---")
    print(f"Subset distance metric: {subset_metric_label} ({subset_metric})")
    print(f"A: n={n_A}, m={m_A}, R0_tilde={R0_A_tilde}, max_t={max_t_A}")
    print(f"B: n={n_B}, m={m_B}, R0_tilde={R0_B_tilde}, Rf_tilde={RF_B_tilde}, max_t={max_t_B}")
    print(f"C: n={n_C}, m={m_C}, R0_tilde={R0_C_tilde}, max_t={max_t_C}")
    print(f"D: n={n_D}, m={m_D}, R0_tilde={R0_D_tilde}, max_t={max_t_D}")

    base_seed = np.random.randint(0, 1_000_000)
    tasks = []

    # A
    start_A = len(tasks)
    for i in range(reps):
        tasks.append((
            "constant",
            base_seed + 10_000 + i,
            n_A,
            sigma,
            m_A,
            R0_A,
            {"epsilon": epsilon_A, "R_final": 0.0, "subset_metric": subset_metric},
            max_t_A,
            tp_A,
        ))
    end_A = len(tasks)

    # B
    start_B = len(tasks)
    for i in range(reps):
        tasks.append((
            "sswm",
            base_seed + 20_000 + i,
            n_B,
            sigma,
            m_B,
            R0_B,
            {"R_final": RF_B, "subset_metric": subset_metric},
            max_t_B,
            tp_B,
        ))
    end_B = len(tasks)

    # C
    start_C = len(tasks)
    for i in range(reps):
        tasks.append((
            "sswm",
            base_seed + 30_000 + i,
            n_C,
            sigma,
            m_C,
            R0_C,
            {"R_final": 0.0, "subset_metric": subset_metric},
            max_t_C,
            tp_C,
        ))
    end_C = len(tasks)

    # D
    start_D = len(tasks)
    for i in range(reps):
        tasks.append((
            "sswm",
            base_seed + 40_000 + i,
            n_D,
            sigma,
            m_D,
            R0_D,
            {"R_final": 0.0, "subset_metric": subset_metric},
            max_t_D,
            tp_D,
        ))
    end_D = len(tasks)


    num_proc = min(multiprocessing.cpu_count(), len(tasks))
    with multiprocessing.Pool(processes=num_proc) as pool:
        results = pool.map(run_single_replicate, tasks)

    # ------------------------------
    # Unpack A
    # ------------------------------
    cos_A, rad_A, pear_A, int_A, subset_A = stack_results(results[start_A:end_A])
    yA, yA_lo, yA_hi, mean_cos_A, std_cos_A = summarize_log_traces(
        cos_A, tiny=1e-12, log_offset=log_offset_A
    )
    mean_pear_A, std_pear_A = summarize_logged_positive_traces(pear_A, tiny=1e-2)
    mean_subset_A, std_subset_A = summarize_logged_positive_traces(subset_A, tiny=1e-12)

    # ------------------------------
    # Unpack B
    # ------------------------------
    cos_B, rad_B, pear_B, int_B, subset_B = stack_results(results[start_B:end_B])
    yB, yB_lo, yB_hi, mean_cos_B, std_cos_B = summarize_log_traces(
        cos_B, tiny=1e-1, log_offset=0.0
    )

    mean_integral_B = np.nanmean(int_B, axis=0)
    log_theory_B = -0.5 * (n_B - 1) * (sigma ** 2) * mean_integral_B

    mean_pear_B, std_pear_B = summarize_logged_positive_traces(pear_B, tiny=1e-2)
    mean_subset_B, std_subset_B = summarize_logged_positive_traces(subset_B, tiny=1e-12)

    # ------------------------------
    # Unpack C
    # ------------------------------
    cos_C, rad_C, pear_C, int_C, subset_C = stack_results(results[start_C:end_C])
    yC, yC_lo, yC_hi, mean_cos_C, std_cos_C = summarize_log_traces(
        cos_C, tiny=1e-12, log_offset=0.0
    )

    # ------------------------------
    # Unpack D
    # ------------------------------
    cos_D, rad_D, pear_D, int_D, subset_D = stack_results(results[start_D:end_D])
    yD, yD_lo, yD_hi, mean_cos_D, std_cos_D = summarize_log_traces(
        cos_D, tiny=1e-12, log_offset=0.0
    )


    # Optional long dataframes
    df_A = make_long_df(cos_A, tp_A, "C")
    df_B = make_long_df(cos_B, tp_B, "C")
    df_C = make_long_df(cos_C, tp_C, "C")
    df_D = make_long_df(cos_D, tp_D, "C")
    _ = (df_A, df_B, df_C, df_D, rad_A, rad_B, rad_C, rad_D)

    # ------------------------------
    # Plotting: 2 rows x 2 columns
    # ------------------------------
    fig, axes = plt.subplots(2, 2, figsize=(12, 10))
    fig.subplots_adjust(wspace=0.28, hspace=0.35)

    # A (Constant R approx)
    ax = axes[0, 0]
    apply_axis_style(ax, "A")
    ax.plot(tp_A, yA, color=CMR_COLORS[0], lw=2.4, label="Angular autocorrelation function")
    ax.fill_between(tp_A, yA_lo, yA_hi, color=CMR_COLORS[0], alpha=0.25, linewidth=0)
    step_A = max(1, len(tp_A) // 15)
    ax.errorbar(
        tp_A[::step_A],
        mean_pear_A[::step_A],
        yerr=std_pear_A[::step_A],
        fmt="o",
        color="slategray",
        markersize=4,
        capsize=3,
        label="Pearson",
    )
    ax.errorbar(
        tp_A[::step_A],
        mean_subset_A[::step_A],
        yerr=std_subset_A[::step_A],
        fmt="s",
        color="darkorange",
        markersize=4,
        capsize=3,
        label=fr"EMD",
    )
    ax.plot(tp_A, -tp_A / tau_A, color="magenta", lw=2.0, ls=":", label=r"Theory")
    ax.set_xlim(0, max_t_A)
    ax.set_xlabel("Time (steps)")
    ax.set_ylabel(r"$\log$ metric")
    ax.xaxis.set_major_locator(MaxNLocator(integer=True))
    ax.legend(frameon=False)

    # B
    ax = axes[0, 1]
    apply_axis_style(ax, "B")
    ax.plot(tp_B, yB, color=CMR_COLORS[1], lw=2.5, ls="-", label="Angular autocorrelation function")
    ax.fill_between(tp_B, yB_lo, yB_hi, color=CMR_COLORS[1], alpha=0.30, linewidth=0)

    # Overlay Pearson correlation with error bars
    step = max(1, len(tp_B) // 15)
    ax.errorbar(
        tp_B[::step],
        mean_pear_B[::step],
        yerr=std_pear_B[::step],
        fmt="o",
        color="slategray",
        markersize=4,
        capsize=3,
        label="Pearson",
    )
    ax.errorbar(
        tp_B[::step],
        mean_subset_B[::step],
        yerr=std_subset_B[::step],
        fmt="s",
        color="darkorange",
        markersize=4,
        capsize=3,
        label=fr"EMD",
    )

    ax.plot(tp_B, log_theory_B, color="black", lw=2.3, ls=":",
            label=r"Theory")

    ax.set_xlabel("Time (steps)")
    ax.xaxis.set_major_locator(MaxNLocator(integer=True))

    # Force the diffusion equation label to the bottom of the legend
    handles, labels = ax.get_legend_handles_labels()
    target_label = r"Diffusion Approximation (**)"
    if target_label in labels:
        idx = labels.index(target_label)
        order = [i for i in range(len(labels)) if i != idx] + [idx]
        ax.legend([handles[i] for i in order], [labels[i] for i in order], frameon=False)
    else:
        ax.legend(frameon=False)

    # C
    ax = axes[1, 0]
    apply_axis_style(ax, "C")
    ax.plot(tp_C, yC, color=CMR_COLORS[2], lw=2.5, ls="-", label="Simulation")
    ax.fill_between(tp_C, yC_lo, yC_hi, color=CMR_COLORS[2], alpha=0.40, linewidth=0)
    ax.plot(tp_C, -tp_C / tau_C, color="brown", lw=2.0, ls=":", label=r"Theory")
    ax.set_xlabel("Time (steps)")
    ax.set_ylabel(r"$\log C_{\boldsymbol{\hat r}}(0, t)$")
    ax.set_title(rf"$\tilde{{R}}_0 = {R0_C_tilde:g}$")
    ax.legend(frameon=False, loc="lower left")
    ax.xaxis.set_major_locator(MaxNLocator(integer=True))

    # D
    ax = axes[1, 1]
    apply_axis_style(ax, "D")
    ax.plot(tp_D, yD, color=CMR_COLORS[2], lw=2.5, ls="-", label="Simulation")
    ax.fill_between(tp_D, yD_lo, yD_hi, color=CMR_COLORS[2], alpha=0.40, linewidth=0)
    ax.plot(tp_D, -tp_D / tau_D, color="brown", lw=2.0, ls=":", label=r"Theory")
    ax.set_xlabel("Time (steps)")
    ax.set_title(rf"$\tilde{{R}}_0 = {R0_D_tilde:g}$")
    ax.legend(frameon=False, loc="lower left")
    ax.xaxis.set_major_locator(MaxNLocator(integer=True))

    out_dir = "../figs_paper"
    os.makedirs(out_dir, exist_ok=True)
    out_path = os.path.join(out_dir, "figS1_angular_scrambling.pdf")
    fig.savefig(out_path, format="pdf", bbox_inches="tight")
    print(f"Figure saved to {out_path}")


if __name__ == "__main__":
    parser = argparse.ArgumentParser(description="Plot azimuthal memory and fixed-subset DFE distances.")
    parser.add_argument(
        "--subset-metric",
        default=DEFAULT_SUBSET_DISTANCE_METRIC,
        help="Distance metric for comparing the t=0 beneficial subset to the full DFE: cvm, emd, or ks.",
    )
    args = parser.parse_args()
    run_experiment(subset_metric=args.subset_metric)
