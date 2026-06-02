import jax.numpy as jnp
from jax import random

from config import NeuronConfig


class LINeuron:
    """Leaky integrator readout — no threshold, no reset."""

    def __init__(self, key: jnp.ndarray, n_neurons: int, n_inputs: int, config: NeuronConfig):
        self.n_neurons = n_neurons
        self.n_inputs = n_inputs
        self.config = config
        self.alpha_m = jnp.exp(-config.dt / config.tau_m)

        xavier_std = jnp.sqrt(2.0 / n_inputs)
        self.w = random.normal(key, (n_neurons, n_inputs)) * xavier_std * config.weight_scale

    def init_carry(self):
        return (
            jnp.zeros(self.n_neurons),  # v
            jnp.zeros(self.n_neurons),  # sum_v (accumulated for mean)
            jnp.zeros(self.n_inputs),   # E_readout
        )

    @staticmethod
    def forward_step(carry, spike_input, w, alpha_m):
        """Pure-function forward step for one timestep. JIT-friendly."""
        v_prev, sum_v_prev, E_prev = carry

        v = alpha_m * v_prev + spike_input @ w.T  # no threshold, no reset
        sum_v = sum_v_prev + v
        E = alpha_m * E_prev + spike_input

        new_carry = (v, sum_v, E)
        return new_carry, v, E


class LIFNeuron:
    def __init__(self, key: jnp.ndarray, n_neurons: int, n_inputs: int, config: NeuronConfig):
        self.n_neurons = n_neurons
        self.n_inputs = n_inputs
        self.config = config
        self.alpha_m = jnp.exp(-config.dt / config.tau_m)

        xavier_std = jnp.sqrt(2.0 / n_inputs)
        scale = xavier_std * config.weight_scale
        self.w = random.normal(key, (n_neurons, n_inputs)) * scale

    def init_carry(self):
        return (
            jnp.zeros(self.n_neurons),          # v
            jnp.zeros(self.n_neurons),          # readout_counts
            jnp.zeros(self.n_inputs),           # E_readout
        )

    @staticmethod
    def forward_step(carry, spike_input, w, alpha_m, v_th):
        """Pure-function forward step for one timestep. JIT-friendly."""
        v_prev, readout_counts, E_readout_prev = carry

        readout_in = spike_input @ w.T
        v = alpha_m * v_prev + readout_in
        o = jnp.where(v >= v_th, 1, 0).astype(jnp.int32)
        v_pre_reset = v
        v = v * (1 - o)
        readout_counts = readout_counts + o
        E_readout = alpha_m * E_readout_prev + spike_input

        new_carry = (v, readout_counts, E_readout)
        return new_carry, o, v_pre_reset, E_readout
