import jax.numpy as jnp
import jax
from jax import random
from jax import lax
from functools import partial
import numpy as np
from dataclasses import dataclass, field, replace
from typing import Dict, Optional
from layout_utils import infer_layout
from prng import make_keys
import hmc
import metropolis_mc as mmc
import prng
import params
import energetics as eng
import numbers
import observables
jax.config.update("jax_enable_x64", True)  # 64 bit


@dataclass
class Phi4Lattice:
    '''Core class to handle and create the lattice.

    This class has methods to handle:
    - Lattice geometry.
    - Model parameters for phi-4 theory.
    - Initialization of phi and momentum fields.
    - HMC evolution of the field.
    - PRNG key management.

    Parameters
    ----------
    model : params.Phi4Params or None
        Frozen dataclass containing coupling constant and
        hopping parameter. If not provided, the
        parameters `kappa` and `lam` must be supplied.
    geom : params.LatticeGeometry or None
        Frozen dataclass describing lattice spacing and shape. If not provided,
        the parameters `spacing_arr` and `length_arr` must be supplied.
    hmc_config : params.HMCConfig or None
        Optional default HMC configuration.
    spacing_arr, length_arr : array-like, optional
        geometry parameters.
    kappa, lam : float, optional
        phi-4 model parameters if not initializing Phi4Params.
    phi_dist, phi_mu, phi_sigma, phi_seed : various
        Distribution parameters for phi initialization.
    mom_dist, mom_mu, mom_sigma, mom_seed : various
        Distribution parameters for momentum initialization.
    n_keys : int
        Number of independent field configurations (PRNG batch size).
    valid_dists : tuple
        Allowed string values for PRNG distributions ("normal", "uniform").

    Attributes
    ----------
    phi_x : jnp.ndarray
        Current field.
    mom_x : jnp.ndarray
        Current momentum field.
    spatial_axes : tuple[int]
        Axes as spatial dimensions.
    shift : int
        Lattice shift parameter.
    trajectory_history : dict[str, jnp.ndarray]
        Dictionary storing HMC trajectory measurements.
    hmc_master_key : jnp.ndarray
        Master PRNG key for HMC sampling.
    '''
    # ===============================================
    # ------- defining param defaults and types -----
    # ===============================================
    # of user-settable parameters
    # using field() for those set in post_init
    # -----------------------------------------------
    # Physical Parameters ---------------------------
    # --- new API uses model param class ---
    model: Optional[params.Phi4Params] = None  # frozen, hashable
    # Field Geometry --------------------------------
    geom: Optional[params.LatticeGeometry] = None  # frozen, hashable
    # hmc configuration ------------------------------
    hmc_config: Optional[params.HMCConfig] = None  # frozen, hashable
    # --- Legacy API (for tests / old code) ---
    spacing_arr: Optional[jnp.ndarray] = None
    length_arr: Optional[jnp.ndarray] = None
    kappa: Optional[float] = None
    lam: Optional[float] = None

    # mutable parameters/state
    # Field/State Configurations --------------------------
    phi_x: jnp.ndarray = field(init=False)
    mom_x: jnp.ndarray = field(init=False)
    spatial_axes: tuple = field(init=False)
    shift: int = field(init=False)

    # H_history: jnp.ndarray = field(init=False)  # Hamiltonian history
    # measure_history: Dict[str, jnp.ndarray] = field(init=False,
    #                                                 default_factory=dict)
    trajectory_history: Dict[str, jnp.ndarray] = field(init=False,
                                                       default_factory=dict)
    # default prng (distribution) parameters --------
    valid_dists: tuple = field(init=False,
                               default=('normal', 'uniform'))
    # phi field defaults to normal distribution
    phi_dist: str = 'normal'
    phi_mu: float | None = None
    phi_sigma: float | None = None
    phi_seed: int | jnp.ndarray | None = 0
    n_keys: int = 1  # batch size (independent field configs)

    # momentum field defaults to normal distribution
    mom_dist: str = 'normal'
    mom_mu: float | None = None
    mom_sigma: float | None = None
    mom_seed: int | jnp.ndarray | None = 1

    hmc_master_key: jnp.ndarray = field(init=False)

    # ===============================================
    # ------ post init computations -------
    # ===============================================
    # Post init to compute derived quantities
    def __post_init__(self):
        '''
        Post-initialization tasks for lattice specific
        quantities and RNG parameters.
        '''
        # legacy API support
        if self.model is None:
            if self.kappa is None or self.lam is None:
                raise ValueError("Either provide model params "
                                 "or kappa and lam.")
            self.model = params.Phi4Params(lam=self.lam, kappa=self.kappa)
        if self.geom is None:
            if self.spacing_arr is None or self.length_arr is None:
                raise ValueError("Either provide geometry params "
                                 "or spacing_arr and length_arr.")
            self.geom = params.LatticeGeometry(spacing_arr=self.spacing_arr,
                                               length_arr=self.length_arr)

        # initialize phi field configuration
        # single sample field configuration by default (seed = 0, n_keys =1)
        if not isinstance(self.n_keys, numbers.Integral) or self.n_keys <= 0:
            raise ValueError("n_keys must be positive integer.")

        phi_master_key, phi_keys = make_keys(
                                        self.n_keys, self.phi_seed,
                                        randomize_keys=(self.phi_seed is None))
        phi_x = self._rand_field_core(phi_keys,
                                      self.geom.lat_shape,
                                      mu=self.phi_mu,
                                      sigma=self.phi_sigma,
                                      dist=self.phi_dist)
        object.__setattr__(self, 'phi_master_key', phi_master_key)
        object.__setattr__(self, 'phi_keys', phi_keys)
        object.__setattr__(self, "phi_x", phi_x)

        # initialize momentum field
        mom_master_key, mom_keys = make_keys(
                                        self.n_keys, self.mom_seed,
                                        randomize_keys=(self.mom_seed is None))
        mom_x = self._rand_field_core(mom_keys,
                                      self.geom.lat_shape,
                                      mu=self.mom_mu,
                                      sigma=self.mom_sigma,
                                      dist=self.mom_dist)
        object.__setattr__(self, 'mom_master_key', mom_master_key)
        object.__setattr__(self, 'mom_keys', mom_keys)
        object.__setattr__(self, "mom_x", mom_x)

        # infer layout
        spatial_axes, shift = infer_layout(self.phi_x, self.geom.D)
        object.__setattr__(self, 'spatial_axes',
                           tuple(int(x) for x in spatial_axes))
        object.__setattr__(self, 'shift', shift)

    # ===========================================================
    # --------- Field Initialization Methods --------
    # other than _rand_field_core, these return self for chaining
    # ===========================================================
    # ----- phi field methods ------------
    @staticmethod
    def _rand_field_core(keys,
                         lat_shape,
                         mu=None,
                         sigma=None,
                         dist='normal') -> jnp.ndarray:
        ''' Wrapper for PRNG randomization cores.

        Parameters
        ----------
        keys : jnp.ndarray
            Array of PRNG keys (one per independent configuration).
        lat_shape : tuple[int]
            Lattice shape.
        mu, sigma : float or None
            Mean and standard deviation for normal distributions.
        dist : {'normal', 'uniform'}
            Choice of PRNG distribution.

        Returns
        -------
        jnp.ndarray
            Random field array with shape (len(keys), *lat_shape).
        '''
        # valid_dists = ['normal', 'uniform']
        if dist == 'normal':
            return prng.randomize_normal_core(keys,
                                              lat_shape,
                                              mu,
                                              sigma)
        elif dist == 'uniform':
            return prng.randomize_uniform_core(keys, lat_shape)
        # elif dist not in valid_dists:
        #     raise ValueError(f"dist must be one of {valid_dists}; "
        #                      f"got {dist}.")

    def randomize_phi(self,
                      N_fields: int,
                      seed_or_key: int | jnp.ndarray | None = None,
                      randomize_keys: bool = True,
                      dist: str = 'normal',
                      mu: int | float | None = None,
                      sigma: int | float | None = None):
        """Re-initializes the phi-field.

        Generates N new keys, calls the JIT'd kernel,
        then mutates phi_x on the Python side. Also resizes the
        momentum field to match the new phi shape. This is a
        host-side operation.

        Parameters
        ----------
        N_fields : int
            Number of independent configurations.
        seed_or_key : int or jnp.ndarray or None
            Seed or PRNG key for reproducibility. If None and
            `randomize_keys=True`, fresh random keys are drawn.
        randomize_keys : bool
            Whether to generate new keys even when a seed is provided.
        dist : {'normal','uniform'}
            Distribution for initialization.
        mu, sigma : float or None
            Parameters for the normal distribution.

        Returns
        -------
        Phi4Lattice
            Self, with updated phi and momentum fields.
        """

        if not isinstance(N_fields, numbers.Integral) or N_fields <= 0:
            raise ValueError("N_fields must be positive integer.")
        if dist not in self.valid_dists:
            raise ValueError(f"dist must be one of {self.valid_dists}; "
                             f"got {dist}.")
        object.__setattr__(self, "phi_dist", dist)
        object.__setattr__(self, "phi_mu", mu)
        object.__setattr__(self, "phi_sigma", sigma)
        object.__setattr__(self, "n_keys", N_fields)
        object.__setattr__(self, "phi_seed", seed_or_key)

        master_key, keys = make_keys(N_fields, seed_or_key, randomize_keys)
        # update master_key and keys
        object.__setattr__(self, "phi_master_key", master_key)
        object.__setattr__(self, "phi_keys", keys)

        # selecting dist type
        rand_phi_xs = self._rand_field_core(keys,
                                            self.geom.lat_shape,
                                            self.phi_mu,
                                            self.phi_sigma,
                                            dist)
        object.__setattr__(self, 'phi_x', rand_phi_xs)

        # infer layout
        spatial_axes, shift = infer_layout(self.phi_x, self.geom.D)
        # update spatial_axes and shift
        object.__setattr__(self, 'spatial_axes',
                           tuple(int(x) for x in spatial_axes))
        object.__setattr__(self, 'shift', shift)

        # force momentum update to match new phi shape
        self.randomize_mom(seed_or_key=self.mom_seed,
                           randomize_keys=(self.mom_seed is None),
                           dist=self.mom_dist,
                           mu=self.mom_mu,
                           sigma=self.mom_sigma)
        return self

    # use for constant fields for simple magnetization expectations
    def constant_phi(self, constant):
        """Set the phi field to a uniform constant value.

        Parameters
        ----------
        constant : float
            Value to broadcast across the entire phi lattice.

        Returns
        -------
        Phi4Lattice
            Self, with updated phi.
        """
        if constant is None:
            raise ValueError("constant must be provided.")
        if not isinstance(constant, numbers.Real):
            raise TypeError("constant must be a real number.")
        phi_x = jnp.full_like(self.phi_x, constant, dtype=np.float64)
        object.__setattr__(self, 'phi_x', phi_x)
        return self

    # --- mom field methods --------------------
    def randomize_mom(self,
                      seed_or_key: int | jnp.ndarray | None = None,
                      randomize_keys=True,
                      dist='normal',
                      mu=None,
                      sigma=None):
        '''Randomize the momentum field.

        Asymmetric to randomize_phi since n_keys is not changed here.
        This is to force momentum sizes to match phi sizes. It will
        always match the shape of the phi field.

        Parameters
        ----------
        seed_or_key : int or jnp.ndarray or None
            PRNG seed or key.
        randomize_keys : bool
            Whether to generate fresh keys even when a seed is supplied.
        dist : {'normal','uniform'}
            Distribution to use.
        mu, sigma : float or None
            Parameters for the normal distribution.

        Returns
        -------
        Phi4Lattice
            Self, with updated momentum field.
        '''
        if dist not in self.valid_dists:
            raise ValueError(f"dist must be one of {self.valid_dists}; "
                             f"got {dist}.")
        object.__setattr__(self, "mom_dist", dist)
        object.__setattr__(self, "mom_mu", mu)
        object.__setattr__(self, "mom_sigma", sigma)
        object.__setattr__(self, "mom_seed", seed_or_key)

        if not isinstance(self.n_keys, numbers.Integral) or self.n_keys <= 0:
            raise ValueError("n_keys must be positive integer.")
        mom_master_key, mom_keys = make_keys(self.n_keys,
                                             seed_or_key,
                                             randomize_keys)
        object.__setattr__(self, "mom_master_key", mom_master_key)
        object.__setattr__(self, "mom_keys", mom_keys)
        mom_xs = self._rand_field_core(mom_keys,
                                       self.geom.lat_shape,
                                       mu=self.mom_mu,
                                       sigma=self.mom_sigma,
                                       dist=self.mom_dist)
        object.__setattr__(self, 'mom_x', mom_xs)
        return self

    def constant_momentum(self, constant):
        """Set the momentum field to a uniform constant value.

        Parameters
        ----------
        constant : float
            Constant value across the momentum field.

        Returns
        -------
        Phi4Lattice
            Self, with updated momentum field.
        """
        if constant is None:
            raise ValueError("constant must be provided.")
        if not isinstance(constant, numbers.Real):
            raise TypeError("constant must be a real number.")
        mom_x = jnp.full_like(self.mom_x, constant, dtype=np.float64)
        object.__setattr__(self, 'mom_x', mom_x)
        return self

    # ===========================================================
    # ------------- HMC field evolution -------------------------
    # returns in self for chaining
    # ===========================================================
    def run_HMC(self,
                cfg: params.HMCConfig,
                seed: int = None,
                randomize_keys: bool = False,
                measure_fns_dict: Dict[str, callable] = None
                ):
        """Run HMC trajectories to evolve the field.

        This updates phi_x and mom_x using the provided HMC
        configuration and returns self.

        Parameters
        ----------
        cfg : params.HMCConfig
            Configuration object specifying leapfrog steps, step size,
            trajectory count, and acceptance parameters.
        seed : int or None
            Seed used for PRNG key generation.
        randomize_keys : bool
            Whether to generate new keys.
        measure_fns_dict : dict[str, callable], optional
            Optional dictionary of measurement functions called during HMC
            evolution.

        Returns
        -------
        Phi4Lattice
            Self, with updated field, momentum, and trajectory history.
        """
        phi0 = self.phi_x
        mom0 = self.mom_x
        if not isinstance(cfg, params.HMCConfig):
            raise ValueError("cfg must be an instance of HMCConfig.")
        if seed is None:
            seed = cfg.seed
        if measure_fns_dict is not None:
            if not isinstance(measure_fns_dict, dict):
                raise TypeError("measure_fns_dict must be a "
                                "dict[str, Callable].")
            for name, fn in measure_fns_dict.items():
                if not callable(fn):
                    raise TypeError(f"measure_fns_dict[{name}] "
                                    "is not callable.")

        traj_master_key, traj_keys = prng._make_traj_keys(
                                                cfg.N_trajectories,
                                                seed_or_key=seed,
                                                randomize_keys=randomize_keys
                                                )
        object.__setattr__(self, 'hmc_master_key', traj_master_key)

        energy_fns = eng.make_phi4_energy_fns
        S_Fn, grad_S_Fn, H_kinetic_Fn = energy_fns(self.model,
                                                   self.geom,
                                                   self.shift,
                                                   self.spatial_axes)

        result = hmc.run_HMC_trajectories(phi0=phi0,
                                          mom0=mom0,
                                          traj_keys=traj_keys,
                                          cfg=cfg,
                                          S_Fn=S_Fn,
                                          grad_S_Fn=grad_S_Fn,
                                          H_kinetic_Fn=H_kinetic_Fn,
                                          measure_fns_dict=measure_fns_dict)
        (mom_final, phi_final), traj_outs_dict = result
        object.__setattr__(self, 'phi_x', phi_final)
        object.__setattr__(self, 'mom_x', mom_final)
        object.__setattr__(self, 'trajectory_history', traj_outs_dict)
        return self

    def thermalize(self,
                   cfg: params.HMCConfig,
                   seed: int = None,
                   randomize_keys: bool = False,
                   threshold: float = 1,
                   max_loops: int = 10,
                   minimum_consecutive: int = 3):
        """
        Run repeated HMC evolutions until observables stabilize.
        Currently only written for single configuration (n_keys=1) for simplicity of diagnostics.
        """
        measure_fns_dict = {"magnetization": lambda phi:
                            observables.magnetization(
                                        phi,
                                        spatial_axes=self.spatial_axes,
                                        volume=self.geom.V),
                            "action": lambda phi: eng.phi4_action_core(
                                                                phi,
                                                                self.model,
                                                                self.geom,
                                                                self.shift,
                                                                self.spatial_axes)[0]}
        if self.n_keys != 1:
            raise NotImplementedError("thermalize currently only implemented for n_keys=1 for simplicity of diagnostics.")
        if cfg.N_trajectories < 3:
            raise ValueError("cfg.N_trajectories must be at least 3 for "
                             "thermalization to compute std.")

        if seed is None:
            seed = cfg.seed

        # --- first pass
        # initial run to populate trajectory history for error calculations
        self.run_HMC(cfg=cfg,
                     seed=seed,
                     randomize_keys=randomize_keys,
                     measure_fns_dict=measure_fns_dict)
        summary = self.trajectory_history

        # magnetization history of fields during trajectory
        mag_hist = summary["magnetization"]

        # average magnetization over trajectory
        abs_mag_hist = jnp.abs(mag_hist)
        abs_mag_mean = abs_mag_hist.mean()
        abs_mag_std = abs_mag_hist.std()
        mag_error = jnp.full_like(mag_hist, jnp.inf)  # inf error for first loop

        # action history of fields during trajectory
        action_hist = summary["action"]
        action_mean = action_hist.mean()
        action_std = action_hist.std()
        action_error = jnp.full_like(action_hist, jnp.inf)  # inf error for first loop

        # set as old values for error calculation
        old_mag_mean = abs_mag_mean
        old_action_mean = action_mean

        n_loops = 1
        n_consecutive = 0
        # require at least 3 consecutive loops below threshold for thermalization
        # minimum_consecutive = 3
        current_seed = seed

        loop_history_dict = {"abs_mag_mean": [abs_mag_mean],
                            "abs_mag_std": [abs_mag_std],
                            "mag_error": [mag_error],
                            "action_mean": [action_mean],
                            "action_std": [action_std],
                            "action_error": [action_error]}
        while n_loops < max_loops:
            current_seed = current_seed + 1

            self.run_HMC(cfg=cfg,
                         seed=current_seed,
                         randomize_keys=randomize_keys,
                         measure_fns_dict=measure_fns_dict)
            mag_hist = self.trajectory_history["magnetization"]
            abs_mag_hist = jnp.abs(mag_hist)
            abs_mag_mean = abs_mag_hist.mean()
            abs_mag_std = abs_mag_hist.std()
            action_hist = self.trajectory_history["action"]
            action_mean = action_hist.mean()
            action_std = action_hist.std()

            # calculate relative errors compared to previous loop
            # normalize by std so that we can use same threshold
            # considering scaling by min(old,new std), more strict but less stable
            mag_error = jnp.abs(abs_mag_mean - old_mag_mean) / jnp.maximum(abs_mag_std, 1e-8)
            action_error = jnp.abs(action_mean - old_action_mean) / jnp.maximum(action_std, 1e-8)

            # update old values for next loop's error calculation
            old_mag_mean = abs_mag_mean
            old_action_mean = action_mean

            n_loops += 1
            # store loop history
            loop_history_dict["abs_mag_mean"].append(abs_mag_mean)
            loop_history_dict["abs_mag_std"].append(abs_mag_std)
            loop_history_dict["mag_error"].append(mag_error)
            loop_history_dict["action_mean"].append(action_mean)
            loop_history_dict["action_std"].append(action_std)
            loop_history_dict["action_error"].append(action_error)
            


            # check if both errors are below the threshold
            if bool(jnp.all((mag_error <= threshold) & (action_error <= threshold))):
                n_consecutive += 1
            else:                
                n_consecutive = 0  # reset if either error exceeds threshold

            if n_consecutive >= minimum_consecutive:
                # early exit if thermalization criteria met
                break

        diagnostic_msg = {"thermalized": (n_consecutive >= minimum_consecutive),
                          "n_trajectories": n_loops * cfg.N_trajectories,
                          "mag_error": mag_error,
                          "action_error": action_error,
                          "loop_history": loop_history_dict}
        object.__setattr__(self, 'thermalization_diagnostics', diagnostic_msg)
        return self

        
    
# --------- Ising model -------


@dataclass
class IsingLattice:
    model: Optional[params.IsingParams] = None
    geom: Optional[params.LatticeGeometry] = None
    metrop_config: Optional[params.MetropMCConfig] = None

    # mutable parameters/state
    sigma_x: jnp.ndarray = field(init=False)
    spatial_axes: tuple = field(init=False)
    shift: int = field(init=False)

    trajectory_history: Dict[str, jnp.ndarray] = field(
                                                init=False,
                                                default_factory=dict)

    valid_dists: tuple = field(init=False, default=('all-up',
                                                    'all-down',
                                                    'checkerboard',
                                                    'uniform',
                                                    'zero-action'))

    sigma_seed: int | jnp.ndarray | None = 0
    n_keys: int = 1  # batch size (independent field configs)
    sigma_dist: str = 'uniform'

    mc_master_key: jnp.ndarray = field(init=False)

    def __post_init__(self):
        if self.model is None:
            raise ValueError("model parameters must be provided.")
        if self.geom is None:
            raise ValueError("geometry parameters must be provided.")

        # initialize sigma field configuration
        if not isinstance(self.n_keys, numbers.Integral) or self.n_keys <= 0:
            raise ValueError("n_keys must be positive integer.")
        mc_master_key, mc_keys = make_keys(
                                    self.n_keys,
                                    self.sigma_seed,
                                    randomize_keys=(self.sigma_seed is None))
        sigma_x = self._generate_field_core(mc_keys,
                                            self.geom.lat_shape,
                                            distribution=self.sigma_dist)
        object.__setattr__(self, 'mc_master_key', mc_master_key)
        object.__setattr__(self, 'mc_keys', mc_keys)
        object.__setattr__(self, "sigma_x", sigma_x)

        # infer layout
        spatial_axes, shift = infer_layout(self.sigma_x, self.geom.D)
        object.__setattr__(self, 'spatial_axes',
                           tuple(int(x) for x in spatial_axes))
        object.__setattr__(self, 'shift', shift)

    # field initialization methods
    @staticmethod
    def _generate_field_core(keys,
                             lat_shape,
                             distribution='uniform') -> jnp.ndarray:
        if distribution in ('uniform', 'all-up', 'all-down'):
            return prng.create_ising_field(keys,
                                           lat_shape,
                                           distribution=distribution)

    def generate_field(self,
                       N_fields: int,
                       seed_or_key: int | jnp.ndarray | None = None,
                       randomize_keys: bool = True,
                       distribution: str = 'uniform'):
        if distribution not in self.valid_dists:
            raise ValueError(f"distribution must be one of {self.valid_dists};"
                             f" got {distribution}.")
        if N_fields <= 0 or not isinstance(N_fields, numbers.Integral):
            raise ValueError("N_fields must be a positive integer.")
        object.__setattr__(self, "sigma_dist", distribution)
        object.__setattr__(self, "sigma_seed", seed_or_key)
        object.__setattr__(self, "n_keys", N_fields)

        master_key, keys = make_keys(N_fields, seed_or_key, randomize_keys)
        object.__setattr__(self, "mc_master_key", master_key)
        object.__setattr__(self, "mc_keys", keys)

        sigma_xs = self._generate_field_core(keys,
                                             self.geom.lat_shape,
                                             distribution=distribution)
        object.__setattr__(self, 'sigma_x', sigma_xs)

        # infer layout
        spatial_axes, shift = infer_layout(self.sigma_x, self.geom.D)
        object.__setattr__(self, 'spatial_axes',
                           tuple(int(x) for x in spatial_axes))
        object.__setattr__(self, 'shift', shift)
        return self

# ----- metropolis MC evolution -------
    def run_Metropolis_MC(self,
                          cfg: params.MetropMCConfig,
                          seed: int = None,
                          randomize_keys: bool = False,
                          measure_fns_dict: Dict[str, callable] = None,
                          store_proposal_history: bool = False,
                          thermalization_summary: bool = False):
        if not isinstance(cfg, params.MetropMCConfig):
            raise ValueError("cfg must be an instance of MetropMCConfig.")
        if seed is None:
            seed = cfg.seed
        if measure_fns_dict is not None:
            if not isinstance(measure_fns_dict, dict):
                raise TypeError("measure_fns_dict must be a "
                                "dict[str, Callable].")
            for name, fn in measure_fns_dict.items():
                if not callable(fn):
                    raise TypeError(f"measure_fns_dict[{name}] "
                                    "is not callable.")

        sweep_master_key, sweep_keys = prng._make_traj_keys(
                                                cfg.N_steps,
                                                seed_or_key=seed,
                                                randomize_keys=randomize_keys)
        object.__setattr__(self, 'mc_master_key', sweep_master_key)

        energy_fns = eng.make_ising_energy_fns
        S_Fn, propose_flip_Fn, local_delta_S_Fn = energy_fns(self.model,
                                           self.geom,
                                           self.shift,
                                           self.spatial_axes)

        result = mmc.run_Metropolis_MC(sigma_x0=self.sigma_x,
                                       sweep_keys=sweep_keys,
                                       cfg=cfg,
                                       S_Fn=S_Fn,
                                       propose_flip_Fn=propose_flip_Fn,
                                       local_delta_S_Fn=local_delta_S_Fn,
                                       measure_fns_dict=measure_fns_dict,
                                       store_proposal_history=store_proposal_history,
                                       thermalization_summary=thermalization_summary)
        sigma_final, traj_outs_dict = result
        object.__setattr__(self, 'sigma_x', sigma_final)
        object.__setattr__(self, 'trajectory_history', traj_outs_dict)
        return self
    

    def thermalize(self,
                cfg: params.MetropMCConfig,
                seed: int = None,
                randomize_keys: bool = False,
                threshold: float = 1,
                max_loops: int = 10,
                minimum_consecutive: int = 3,
                store_proposal_history: bool = False,
                store_loop_history: bool = True,
                store_error_history: bool = False):
        """
        Run repeated Metrop-MC evolutions until observables stabilize
        -- no monotonic drift in magnetization or action.
        """
        # measure_fns_dict = {"magnetization": lambda phi:
        #                     observables.magnetization(
        #                                 phi,
        #                                 spatial_axes=self.spatial_axes,
        #                                 volume=self.geom.V),
        #                     "action": lambda phi: eng.ising_action_core(
        #                                                         phi,
        #                                                         self.model,
        #                                                         self.geom,
        #                                                         self.shift,
        #                                                         self.spatial_axes)[0]}
        if seed is None:
            seed = cfg.seed
        # initial error values set to infinity to ensure at least one trajectory runs
        # mag_error = jnp.inf
        # action_error = jnp.inf

        # --- first pass
        # initial run to populate trajectory history for error calculations
        self.run_Metropolis_MC(cfg=cfg,
                     seed=seed,
                     randomize_keys=randomize_keys,
                    #  measure_fns_dict=measure_fns_dict,
                     store_proposal_history=store_proposal_history,
                     thermalization_summary=True)
            # magnetization history of fields during trajectory
        summary = self.trajectory_history
        # mag_hist = self.trajectory_history["magnetization"]
        # abs_mag_hist = jnp.abs(mag_hist)
        # average magnetization over trajectory
        # abs_mag_mean = abs_mag_hist.mean()
        # abs_mag_std = abs_mag_hist.std()

        abs_mag_mean = summary["abs_mag_mean"]/self.geom.V
        abs_mag_std = summary["abs_mag_std"]/self.geom.V
        mag_error = jnp.full_like(abs_mag_mean, jnp.inf)  # set initial error to inf for first loop
        # action history of fields during trajectory
        # action_hist = self.trajectory_history["action"]
        action_mean = summary["action_mean"]
        action_std = summary["action_std"]
        action_error = jnp.full_like(action_mean, jnp.inf)  # set initial error to inf for first loop

        # set as old values for error calculation
        old_mag_mean = abs_mag_mean
        # old_mag_std = abs_mag_std

        old_action_mean = action_mean
        # old_action_std = action_std
        if store_loop_history:
            loop_history_dict = {"abs_mag_mean": [abs_mag_mean],
                                "abs_mag_std": [abs_mag_std],
                                "action_mean": [action_mean],
                                "action_std": [action_std]}
            if store_error_history:
                loop_history_dict["mag_error"] = [mag_error]
                loop_history_dict["action_error"] = [action_error]
        else:
            loop_history_dict = {}

        n_loops = 1
        n_consecutive = 0
        # require at least 3 consecutive loops below threshold for thermalization
        current_seed = seed
        # swap to jax.lax.while_loop
        while n_loops < max_loops:
            current_seed = current_seed + 1

            self.run_Metropolis_MC(cfg=cfg,
                         seed=current_seed,
                         randomize_keys=randomize_keys,
                        #  measure_fns_dict=measure_fns_dict,
                         store_proposal_history=store_proposal_history,
                         thermalization_summary=True)
            # mag_hist = self.trajectory_history["magnetization"]
            # abs_mag_hist = jnp.abs(mag_hist)
            # abs_mag_mean = abs_mag_hist.mean()
            # abs_mag_std = abs_mag_hist.std()
            # action_hist = self.trajectory_history["action"]
            # action_mean = action_hist.mean()
            # action_std = action_hist.std()

            summary = self.trajectory_history
            abs_mag_mean = summary["abs_mag_mean"]/self.geom.V
            abs_mag_std = summary["abs_mag_std"]/self.geom.V
            action_mean = summary["action_mean"]
            action_std = summary["action_std"]

            # calculate relative errors compared to previous loop
            # normalize by std so that we can use same threshold
            # considering scaling by min(old,new std), more strict but less stable
            mag_error = jnp.abs(abs_mag_mean - old_mag_mean) / jnp.maximum(abs_mag_std, 1e-8)
            action_error = jnp.abs(action_mean - old_action_mean) / jnp.maximum(action_std, 1e-8)

            # update old values for next loop's error calculation
            old_mag_mean = abs_mag_mean
            # old_mag_std = abs_mag_std
            old_action_mean = action_mean
            # old_action_std = action_std

            n_loops += 1
            if store_loop_history:
                loop_history_dict["action_mean"].append(action_mean)
                loop_history_dict["action_std"].append(action_std)
                loop_history_dict["abs_mag_mean"].append(abs_mag_mean)
                loop_history_dict["abs_mag_std"].append(abs_mag_std)
                if store_error_history:
                    loop_history_dict["mag_error"].append(mag_error)
                    loop_history_dict["action_error"].append(action_error)


            # check if both errors are below the threshold
            if bool(jnp.all((mag_error<= threshold) & (action_error <= threshold))):
                n_consecutive += 1
            else:                
                n_consecutive = 0  # reset if either error exceeds threshold

            if n_consecutive >= minimum_consecutive:
                # early exit if thermalization criteria met
                break
        
        # convert loop history lists to arrays for easier analysis downstream
        if store_loop_history:
            loop_history_dict = {key: jnp.stack(value)
                                for key, value in loop_history_dict.items()}
        thermalization_diagnostics = {"thermalized": (n_consecutive >= minimum_consecutive),
                                      "n_loops": n_loops,
                                      "final_mag_error": mag_error,
                                      "final_action_error": action_error,
                                      "history": loop_history_dict}
        object.__setattr__(self, 'thermalization_diagnostics', thermalization_diagnostics)
        return self

