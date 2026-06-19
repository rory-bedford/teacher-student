"""
Check loss when scaling factors are at target values (normalized = 1).

Same setup as train_feedforward_noisy.py but no training - just runs inference
for plot_size chunks with scaling factors initialized to targets, then plots
and logs metrics.

Weight noise is applied SEPARATELY to each cell-type pair (e.g., exc->exc,
inh->exc, mitral->inh), preserving the mean and std of each connection type.
"""

import numpy as np
import pandas as pd
import matplotlib.pyplot as plt
from dataloaders.supervised import (
    ExactFFDataset,
    CyclicSampler,
    feedforward_collate_fn,
)
from network_simulators.feedforward_conductance_based.simulator import (
    FeedforwardConductanceLIFNetwork,
)
from network_simulators.projections import FrozenProjection
import torch
from torch.utils.data import DataLoader
from training_utils.losses import VanRossumLoss
from configs import (
    DATALOADER_KWARGS,
    StudentSimulationConfig,
    StudentTrainingConfig,
    StudentHyperparameters,
)
from configs.conductance_based import RecurrentLayerConfig, FeedforwardLayerConfig
import toml
from tqdm import tqdm
from visualization.neuronal_dynamics import plot_spike_trains


def apply_weight_noise(weights, noise_frac, rng=None, preserve_statistics=True):
    """Apply multiplicative log-normal noise to weights with statistics preservation.

    Applies noise: w * exp(noise_frac * N(0,1) - noise_frac^2 / 2), then uses an
    affine transformation to exactly match the original mean and std of non-zero weights.
    The multiplier has E[m] = 1 and is strictly positive, guaranteeing non-negativity.
    """
    if rng is None:
        rng = np.random.default_rng()

    nonzero_mask = weights != 0
    orig_mean = weights[nonzero_mask].mean()
    orig_std = weights[nonzero_mask].std()

    multiplier = np.exp(
        noise_frac * rng.standard_normal(weights.shape) - noise_frac**2 / 2
    )
    noisy_weights = weights * multiplier

    if preserve_statistics and orig_std > 0:
        noisy_nz = noisy_weights[nonzero_mask]
        noisy_mean = noisy_nz.mean()
        noisy_std = noisy_nz.std()
        if noisy_std > 0:
            noisy_weights[nonzero_mask] = orig_mean + (noisy_nz - noisy_mean) * (
                orig_std / noisy_std
            )
            noisy_weights[nonzero_mask] = np.maximum(noisy_weights[nonzero_mask], 0)

    return noisy_weights


def main(
    input_dir,
    output_dir,
    params_file,
    wandb_config=None,
    resume_from=None,
):
    """Run inference with scaling factors at target values.

    Args:
        input_dir (Path): Directory containing teacher data (network_structure.npz, spike_data.zarr)
        output_dir (Path): Directory where outputs will be saved
        params_file (Path): Path to the parameters TOML file
        wandb_config (dict, optional): W&B configuration (not used)
        resume_from (Path, optional): Not used
    """

    device = "cuda" if torch.cuda.is_available() else "cpu"
    print(f"Using device: {device}")

    # Load parameters
    with open(params_file, "r") as f:
        data = toml.load(f)

    simulation = StudentSimulationConfig(**data["simulation"])
    training = StudentTrainingConfig(**data["training"])
    hyperparameters = StudentHyperparameters(**data["hyperparameters"])
    recurrent = RecurrentLayerConfig(**data["recurrent"])
    feedforward = FeedforwardLayerConfig(**data["feedforward"])
    scaling_factors = data.get("scaling_factors", {})

    weight_noise_config = data.get("weight_noise", {})
    noise_frac = weight_noise_config.get("noise_frac", 0.0)

    chunk_size = simulation.chunk_size
    seed = simulation.seed
    plot_size = training.plot_size
    weight_perturbation_variance = training.weight_perturbation_variance

    if seed is not None:
        np.random.seed(seed)
        torch.manual_seed(seed)

    weight_noise_rng = np.random.default_rng(seed)

    # Load network structure
    network_structure = np.load(input_dir / "network_structure.npz")

    weights = network_structure["recurrent_weights"]
    feedforward_weights = network_structure["feedforward_weights"]
    cell_type_indices = network_structure["cell_type_indices"]
    feedforward_cell_type_indices = network_structure["feedforward_cell_type_indices"]
    recurrent_mask = network_structure["recurrent_connectivity"]
    feedforward_mask = network_structure["feedforward_connectivity"]

    n_neurons = weights.shape[0]
    n_feedforward = feedforward_weights.shape[0]
    n_total_inputs = n_feedforward + n_neurons

    # Concatenate weights
    concatenated_weights = np.concatenate([feedforward_weights, weights], axis=0)
    concatenated_mask = np.concatenate([feedforward_mask, recurrent_mask], axis=0)

    # Build concatenated cell type indices (needed for per-pair noise)
    # Note: feedforward cell types are offset by n_ff_cell_types to distinguish from recurrent
    recurrent_cell_params = recurrent.get_cell_params()
    feedforward_cell_params = feedforward.get_cell_params()
    n_ff_cell_types = len(feedforward_cell_params)

    concatenated_cell_type_indices = np.concatenate(
        [feedforward_cell_type_indices, cell_type_indices + n_ff_cell_types]
    )
    n_input_types = concatenated_cell_type_indices.max() + 1
    n_output_types = cell_type_indices.max() + 1

    # Apply weight noise PER CELL-TYPE PAIR (preserves statistics for each pair separately)
    if noise_frac > 0:
        print(
            f"\nApplying {noise_frac * 100:.1f}% multiplicative Gaussian noise (per cell-type pair)..."
        )

        original_weights = concatenated_weights.copy()

        # Apply noise separately to each (input_type, output_type) pair
        pair_stats = []
        for in_type in range(n_input_types):
            for out_type in range(n_output_types):
                # Get mask for this cell-type pair
                in_mask = concatenated_cell_type_indices == in_type
                out_mask = cell_type_indices == out_type
                pair_mask = np.outer(in_mask, out_mask)

                # Get weights for this pair
                pair_weights = concatenated_weights[pair_mask]
                nonzero = pair_weights != 0

                if nonzero.sum() == 0:
                    continue

                # Store original stats
                orig_mean = pair_weights[nonzero].mean()
                orig_std = pair_weights[nonzero].std()

                # Apply noise to this pair
                noisy_pair = apply_weight_noise(
                    pair_weights.reshape(-1),
                    noise_frac,
                    rng=weight_noise_rng,
                    preserve_statistics=True,
                )

                # Put back into concatenated weights
                concatenated_weights[pair_mask] = noisy_pair

                # Store stats for logging
                noisy_nz = noisy_pair[nonzero]
                pair_stats.append(
                    {
                        "in_type": in_type,
                        "out_type": out_type,
                        "n_weights": nonzero.sum(),
                        "orig_mean": orig_mean,
                        "orig_std": orig_std,
                        "noisy_mean": noisy_nz.mean(),
                        "noisy_std": noisy_nz.std(),
                    }
                )

        # Print per-pair statistics
        print("\n  Per cell-type pair statistics:")
        for ps in pair_stats:
            print(
                f"    [{ps['in_type']}→{ps['out_type']}] n={ps['n_weights']:,}: "
                f"μ {ps['orig_mean']:.4f}→{ps['noisy_mean']:.4f}, "
                f"σ {ps['orig_std']:.4f}→{ps['noisy_std']:.4f}"
            )

        # Global stats for comparison
        nonzero_mask = concatenated_weights != 0
        original_weights_nz = original_weights[nonzero_mask]
        noisy_weights_nz = concatenated_weights[nonzero_mask]
        original_mean = original_weights_nz.mean()
        original_std = original_weights_nz.std()
        noisy_mean = noisy_weights_nz.mean()
        noisy_std = noisy_weights_nz.std()
        print(
            f"\n  - Global original (non-zero): mean={original_mean:.6f}, std={original_std:.6f}"
        )
        print(
            f"  - Global noisy (non-zero):    mean={noisy_mean:.6f}, std={noisy_std:.6f}"
        )

        # Create output directory early for saving plot
        output_dir.mkdir(parents=True, exist_ok=True)

        # Create scatter plot comparing original vs noisy weights
        fig, axes = plt.subplots(1, 2, figsize=(14, 6))

        # Scatter plot
        ax = axes[0]
        max_points = 50000
        if len(original_weights_nz) > max_points:
            idx = np.random.default_rng(42).choice(
                len(original_weights_nz), max_points, replace=False
            )
        else:
            idx = np.arange(len(original_weights_nz))

        ax.scatter(original_weights_nz[idx], noisy_weights_nz[idx], alpha=0.2, s=1)
        lims = [
            min(0, noisy_weights_nz.min()),
            np.percentile(np.concatenate([original_weights_nz, noisy_weights_nz]), 95),
        ]
        ax.plot(lims, lims, "k--", linewidth=1)
        ax.set_xlim(lims)
        ax.set_ylim(lims)
        ax.set_xlabel("Original Weight")
        ax.set_ylabel("Noisy Weight")
        ax.set_aspect("equal")

        corr = np.corrcoef(original_weights_nz, noisy_weights_nz)[0, 1]
        stats_text = (
            f"Original: μ={original_mean:.6f}, σ={original_std:.6f}\n"
            f"Noisy:    μ={noisy_mean:.6f}, σ={noisy_std:.6f}\n"
            f"Corr: r={corr:.4f}"
        )
        ax.text(
            0.05,
            0.95,
            stats_text,
            transform=ax.transAxes,
            fontsize=10,
            verticalalignment="top",
            fontfamily="monospace",
            bbox=dict(boxstyle="round", facecolor="white", alpha=0.8),
        )
        ax.set_title("Original vs Noisy Weights")

        # Histogram comparison
        ax = axes[1]
        min_val = min(0, noisy_weights_nz.min())
        max_val = np.percentile(
            np.concatenate([original_weights_nz, noisy_weights_nz]), 99
        )
        bins = np.linspace(min_val, max_val, 100)
        ax.hist(
            original_weights_nz,
            bins=bins,
            density=True,
            alpha=0.5,
            label="Original",
            color="blue",
        )
        ax.hist(
            noisy_weights_nz,
            bins=bins,
            density=True,
            alpha=0.5,
            label="Noisy",
            color="orange",
        )
        ax.axvline(0, color="gray", linestyle=":", alpha=0.5)
        ax.set_xlabel("Weight")
        ax.set_ylabel("Density")
        ax.set_title("Distribution Comparison")
        ax.legend()

        fig.suptitle(
            f"Weight Noise: {noise_frac * 100:.1f}% (Per Cell-Type Pair, Clip [0, ∞) + Affine Rescale)",
            fontsize=14,
            fontweight="bold",
        )
        plt.tight_layout()

        plot_path = output_dir / "weight_noise_comparison.png"
        fig.savefig(plot_path, dpi=150, bbox_inches="tight")
        plt.close(fig)
        print(f"  - Saved weight noise comparison plot to {plot_path}")
    else:
        print("\nNo weight noise applied (noise_frac = 0)")

    # Setup combined cell parameters
    combined_cell_params_FF = feedforward_cell_params.copy()
    for cell_params in recurrent_cell_params:
        offset_cell_params = cell_params.copy()
        offset_cell_params["cell_id"] = cell_params["cell_id"] + n_ff_cell_types
        combined_cell_params_FF.append(offset_cell_params)

    recurrent_synapse_params = recurrent.get_synapse_params()
    feedforward_synapse_params = feedforward.get_synapse_params()
    n_ff_synapse_types = len(feedforward_synapse_params)

    combined_synapse_params_FF = feedforward_synapse_params.copy()
    for syn_params in recurrent_synapse_params:
        offset_syn_params = syn_params.copy()
        offset_syn_params["cell_id"] = syn_params["cell_id"] + n_ff_cell_types
        offset_syn_params["synapse_id"] = syn_params["synapse_id"] + n_ff_synapse_types
        combined_synapse_params_FF.append(offset_syn_params)

    # Get base scaling factors
    sf_feedforward = np.array(scaling_factors["feedforward"])
    sf_recurrent = np.array(scaling_factors["recurrent"])
    concatenated_scaling_factors = np.concatenate(
        [sf_feedforward, sf_recurrent], axis=0
    )

    # Generate target scaling factors (same as training)
    sigma = np.sqrt(weight_perturbation_variance)
    mu = -(sigma**2) / 2.0
    target_scaling_factors_FF = np.random.lognormal(
        mean=mu, sigma=sigma, size=concatenated_scaling_factors.shape
    )

    # Perturbation is reciprocal of target
    perturbation_factors = 1.0 / target_scaling_factors_FF

    # Apply perturbation to weights
    perturbed_weights = concatenated_weights.copy()
    for input_idx in range(n_total_inputs):
        input_type = concatenated_cell_type_indices[input_idx]
        for output_idx in range(n_neurons):
            output_type = cell_type_indices[output_idx]
            perturbed_weights[input_idx, output_idx] *= perturbation_factors[
                input_type, output_type
            ]

    # Initialize scaling factors AT TARGET (so normalized = 1)
    scaling_factors_init = target_scaling_factors_FF.copy()

    # Save targets
    output_dir.mkdir(parents=True, exist_ok=True)
    targets_dir = output_dir / "targets"
    targets_dir.mkdir(parents=True, exist_ok=True)

    np.savez(
        targets_dir / "target_scaling_factors.npz",
        feedforward_scaling_factors=target_scaling_factors_FF,
    )

    np.savez(
        targets_dir / "weight_noise_config.npz",
        noise_frac=noise_frac,
        seed=seed,
    )

    # Save perturbed network structure
    np.savez(
        output_dir / "network_structure.npz",
        feedforward_weights=perturbed_weights[:n_feedforward],
        recurrent_weights=perturbed_weights[n_feedforward:],
        feedforward_connectivity=concatenated_mask[:n_feedforward],
        recurrent_connectivity=concatenated_mask[n_feedforward:],
        cell_type_indices=cell_type_indices,
        feedforward_cell_type_indices=concatenated_cell_type_indices,  # Save concatenated version
        scaling_factors_FF=scaling_factors_init,
    )
    print(f"\n✓ Saved network structure to {output_dir / 'network_structure.npz'}")
    print(f"✓ Saved targets to {targets_dir}")

    # Load dataset
    spike_dataset = ExactFFDataset(
        spike_data_path=input_dir / "spike_data.zarr",
        chunk_size=chunk_size,
        device=device,
    )
    batch_size = spike_dataset.batch_size
    dt = spike_dataset.dt

    spike_dataloader = DataLoader(
        spike_dataset,
        batch_size=None,
        sampler=CyclicSampler(spike_dataset),
        **DATALOADER_KWARGS,
        collate_fn=feedforward_collate_fn,
    )

    # Build per-pair frozen projections with mask applied and scaling factors
    # baked in. Source rows mix FF and recurrent cell types in a combined
    # namespace; targets are recurrent only.
    masked_weights = perturbed_weights * concatenated_mask.astype(np.float32)
    combined_src_names = [c["name"] for c in combined_cell_params_FF]
    rec_tgt_names = [c["name"] for c in recurrent_cell_params]
    projections: dict[tuple[str, str], FrozenProjection] = {}
    for src_id, src_name in enumerate(combined_src_names):
        src_rows = np.flatnonzero(concatenated_cell_type_indices == src_id)
        for tgt_id, tgt_name in enumerate(rec_tgt_names):
            tgt_cols = np.flatnonzero(cell_type_indices == tgt_id)
            block = masked_weights[np.ix_(src_rows, tgt_cols)].astype(np.float32)
            block = block * float(scaling_factors_init[src_id, tgt_id])
            projections[(src_name, tgt_name)] = FrozenProjection(block)

    # Initialize model
    model = FeedforwardConductanceLIFNetwork(
        dt=dt,
        projections=projections,
        cell_type_indices=cell_type_indices,
        cell_type_indices_FF=concatenated_cell_type_indices,
        cell_params=recurrent_cell_params,
        cell_params_FF=combined_cell_params_FF,
        synapse_params_FF=combined_synapse_params_FF,
        surrgrad_scale=hyperparameters.surrgrad_scale,
        batch_size=batch_size,
        track_variables=False,
    )
    model.to(device)
    model.eval()
    model.reset_state(batch_size=batch_size)

    # Loss function
    van_rossum_loss_fn = VanRossumLoss(
        tau_rise=hyperparameters.van_rossum_tau_rise,
        tau_decay=hyperparameters.van_rossum_tau_decay,
        dt=dt,
        window_size=chunk_size,
        device=device,
    )

    # Run inference chunk by chunk (2x plot_size, first half is burn-in)
    total_chunks = 2 * plot_size
    print(
        f"\nRunning inference for {total_chunks} chunks ({plot_size} burn-in + {plot_size} analysis)..."
    )

    data_iter = iter(spike_dataloader)

    # Accumulators for metrics (only after burn-in)
    losses = []
    student_spike_counts = np.zeros(n_neurons)
    teacher_spike_counts = np.zeros(n_neurons)

    # Storage for plotting (only first batch element, only after burn-in)
    plot_output_spikes = []
    plot_target_spikes = []

    with torch.no_grad():
        for chunk_idx in tqdm(range(total_chunks), desc="Inference"):
            batch = next(data_iter)
            input_spikes = batch.input_spikes.to(device)
            target_spikes = batch.target_spikes.to(device)

            output = model(input_spikes)
            spikes = output["spikes"] if isinstance(output, dict) else output

            # Only accumulate after burn-in
            if chunk_idx >= plot_size:
                # Compute loss for this chunk
                loss = van_rossum_loss_fn(spikes, target_spikes)
                losses.append(loss.item())

                # Accumulate spike counts for firing rate (first batch element only)
                student_spike_counts += spikes[0].sum(dim=0).cpu().numpy()
                teacher_spike_counts += target_spikes[0].sum(dim=0).cpu().numpy()

                # Store spikes for plotting (first batch element only)
                plot_output_spikes.append(spikes[0].cpu().numpy())
                plot_target_spikes.append(target_spikes[0].cpu().numpy())

    # Compute average loss
    mean_loss = np.mean(losses)

    # Compute firing rates
    analysis_chunks = plot_size
    duration_s = analysis_chunks * chunk_size * dt / 1000.0
    student_fr = student_spike_counts / duration_s
    teacher_fr = teacher_spike_counts / duration_s

    # Concatenate spikes for plotting
    output_spikes = np.concatenate(plot_output_spikes, axis=0)  # (time, neurons)
    target_spikes = np.concatenate(plot_target_spikes, axis=0)  # (time, neurons)

    exc_mask = cell_type_indices == 0
    inh_mask = cell_type_indices == 1

    metrics = {
        "loss": mean_loss,
        "firing_rate/student_mean": float(student_fr.mean()),
        "firing_rate/student_std": float(student_fr.std()),
        "firing_rate/teacher_mean": float(teacher_fr.mean()),
        "firing_rate/teacher_std": float(teacher_fr.std()),
        "firing_rate/student_exc_mean": float(student_fr[exc_mask].mean()),
        "firing_rate/student_inh_mean": float(student_fr[inh_mask].mean()),
        "firing_rate/teacher_exc_mean": float(teacher_fr[exc_mask].mean()),
        "firing_rate/teacher_inh_mean": float(teacher_fr[inh_mask].mean()),
    }

    # Print metrics
    print("\n" + "=" * 60)
    print("METRICS (scaling factors at target)")
    print("=" * 60)
    for key, val in metrics.items():
        print(f"  {key}: {val:.4f}")
    print("=" * 60)

    # Generate plot (spikes are now (time, neurons) from first batch element)
    n_plot = min(10, output_spikes.shape[1])
    interleaved = np.zeros((1, output_spikes.shape[0], 2 * n_plot))
    for i in range(n_plot):
        interleaved[0, :, 2 * i] = target_spikes[:, i]
        interleaved[0, :, 2 * i + 1] = output_spikes[:, i]

    cell_type_indices_plot = np.array([0, 1] * n_plot)
    cell_type_names_plot = ["Target", "Student"]

    fig = plot_spike_trains(
        spikes=interleaved,
        dt=dt,
        cell_type_indices=cell_type_indices_plot,
        cell_type_names=cell_type_names_plot,
        n_neurons_plot=2 * n_plot,
        fraction=1.0,
        random_seed=None,
        title=f"Scaling Factors at Target (loss={mean_loss:.4f})",
        ylabel="Neuron",
        figsize=(14, 8),
    )

    # Save outputs
    output_dir.mkdir(parents=True, exist_ok=True)

    fig.savefig(output_dir / "spike_comparison.png", dpi=150, bbox_inches="tight")
    plt.close(fig)

    # Save metrics as CSV (uniform with other scripts)
    metrics_df = pd.DataFrame([metrics])
    metrics_df.to_csv(output_dir / "training_metrics.csv", index=False)

    # Save plot data for later analysis (all neurons)
    n_neurons_save = output_spikes.shape[1]
    print(f"\nSaving plot data for {n_neurons_save} neurons...")
    np.savez(
        output_dir / "plot_data.npz",
        student_spikes=output_spikes,
        teacher_spikes=target_spikes,
        dt=dt,
        cell_type_indices=cell_type_indices,
        n_neurons=n_neurons_save,
    )

    print(f"\nSaved to {output_dir}")
    print(f"✓ Spike comparison plot: {output_dir / 'spike_comparison.png'}")
    print(f"✓ Metrics CSV: {output_dir / 'training_metrics.csv'}")
    print(f"✓ Plot data: {output_dir / 'plot_data.npz'}")
