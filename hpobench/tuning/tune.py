import pandas as pd
import optuna
import logging
import warnings
from datetime import datetime, timedelta
from hpobench.config.types import TunerConfig
from hpobench.config.types import IntRange, FloatRange, CategoricalRange
from typing import Union, Optional, Any, Dict

logger = logging.getLogger(__name__)


def _calculate_search_space_size(
    search_space: dict[str, Union[IntRange, FloatRange, CategoricalRange]],
) -> int:
    """Calculate approximate total combinations in a search space."""
    if len(search_space) == 0:
        return 0
    
    total_combos = 1
    for param_range in search_space.values():
        if isinstance(param_range, CategoricalRange):
            total_combos *= len(param_range.choices)
        elif isinstance(param_range, IntRange):
            total_combos *= max(1, param_range.upper - param_range.lower + 1)
        else:  # FloatRange
            total_combos *= 10
    
    return total_combos


from optuna.samplers import TPESampler, RandomSampler, CmaEsSampler, GPSampler
from hpobench.tuning.optuna_gp_integration import (
    StrippedGPSampler,
    ExpandedAcquisitionFunction,
)
from hpobench.config.types import (
    ConfOptModel,
    SkOptModel,
    OptunaModel,
    SMACModel,
    CustomGPModel,
)
from skopt import forest_minimize, gbrt_minimize, gp_minimize
from skopt.space import Real, Integer as SKInteger, Categorical as SKCategorical

try:
    from confopt.tuning import ConformalTuner
    from hpobench.generation.generate import ObjectiveMetricGenerator
    from confopt.selection.sampling.bound_samplers import (
        LowerBoundSampler,
        PessimisticLowerBoundSampler,
    )
    from confopt import wrapping as ranges
except ImportError:
    raise ImportError(
        "confopt is a core dependency of this repository, but it is not automatically installed via pyproject.toml, please refer to the README.md for instructions on how to install this separately"
    )
from copy import deepcopy
from functools import partial
from hpobench.tuning.syne_tune_integration import syne_tune_cqr_tune
from ConfigSpace import (
    ConfigurationSpace,
    Configuration,
)
from ConfigSpace.hyperparameters import (
    UniformFloatHyperparameter,
    UniformIntegerHyperparameter,
    CategoricalHyperparameter,
)

try:
    from smac.facade.hyperparameter_optimization_facade import (
        HyperparameterOptimizationFacade,
    )
    from smac.acquisition.function.expected_improvement import EI
    from smac.acquisition.function.thompson import TS
    from smac.acquisition.maximizer.random_search import RandomSearch
    from smac.scenario import Scenario
    from smac.runhistory.dataclasses import TrialInfo, TrialValue
except ImportError:
    raise ImportError(
        "smac is a core dependency of this repository, but it is not automatically installed via pyproject.toml, please refer to the README.md for instructions on how to install this separately"
    )

from hpobench.tuning.gp_opt.tuning import GPTuner
from hpobench.tuning.gp_opt import wrapping as gp_opt_ranges
from hpobench.tuning.gp_opt.acquisition_functions import (
    ExpectedImprovement,
    LogExpectedImprovement,
    ThompsonSampling,
    UpperConfidenceBound,
    OptimisticThompsonSampling,
)

N_CANDIDATES = 2000


def create_runtime_tracker() -> list[datetime]:
    """Creates an empty list to track runtime timestamps during optimization.

    Returns:
        Empty list that will store datetime objects for runtime tracking.
    """
    return []


def record_runtime(runtimes: list[datetime]) -> None:
    """Records the current timestamp in the runtime tracking list.

    Args:
        runtimes: List of datetime objects to append the current timestamp to.
    """
    runtimes.append(datetime.now())


def apply_retroactive_timestamps(
    warm_start_configs: Optional[list[tuple[dict, float]]],
    runtimes: list[datetime],
) -> list[datetime]:
    """Applies retroactive timestamps to warm-start configurations.

    Creates timestamps for warm-start configurations by working backwards from the
    earliest objective function runtime, ensuring warm-starts appear to have
    occurred before optimization began.

    Args:
        warm_start_configs: List of (config, loss) tuples for warm-starting.
        runtimes: List of datetime objects from actual objective function calls.

    Returns:
        Combined list of timestamps for warm-start configs followed by objective function runtimes.
    """
    if not warm_start_configs or not runtimes:
        return runtimes

    # Get the smallest timestamp from objective function calls
    min_runtime = min(runtimes)

    # Assign backwards timestamps to warm-start configs (reverse order)
    warm_start_runtimes = []
    for i in range(len(warm_start_configs)):
        warm_start_runtimes.append(min_runtime - timedelta(seconds=i + 1))

    # Combine warm-start runtimes with objective function runtimes
    return warm_start_runtimes + runtimes


def build_history_entry(
    end_time: Optional[Any] = None,
    performance: Optional[Any] = None,
    configurations: Optional[Any] = None,
    iteration: Optional[int] = None,
) -> dict[str, Any]:
    """Creates a standardized dictionary entry for tuning history records.

    Args:
        end_time: Timestamp when the trial completed.
        performance: Observed performance metric value.
        configurations: Dictionary of hyperparameter configuration.
        iteration: Trial iteration number (1-based indexing).

    Returns:
        Dictionary containing all trial information with standardized keys.
    """
    return {
        "end_time": end_time,
        "performance": performance,
        "configurations": configurations,
        "iteration": iteration,
    }


def set_optuna_params(
    trial: optuna.trial.Trial,
    raw_params: dict[str, Union[IntRange, FloatRange, CategoricalRange]],
) -> dict[str, Any]:
    """Suggests hyperparameter values for an Optuna trial based on parameter range definitions.

    Args:
        trial: Active Optuna trial object to suggest parameters for.
        raw_params: Dictionary mapping parameter names to their range specifications
            (IntRange, FloatRange, or CategoricalRange).

    Returns:
        Dictionary mapping parameter names to their suggested values for this trial.
    """
    optuna_params: dict[str, Any] = {}
    for name, param in raw_params.items():
        if isinstance(param, IntRange):
            log_flag = getattr(param, "log", False)
            optuna_params[name] = trial.suggest_int(
                name, param.lower, param.upper, log=log_flag
            )
        elif isinstance(param, FloatRange):
            log_flag = getattr(param, "log", False)
            optuna_params[name] = trial.suggest_float(
                name, param.lower, param.upper, log=log_flag
            )
        elif isinstance(param, CategoricalRange):
            optuna_params[name] = trial.suggest_categorical(name, param.choices)
        else:
            raise ValueError(f"Unknown parameter type: {type(param)}")
    return optuna_params


def optuna_artificial_objective(
    trial: optuna.trial.Trial,
    params: dict[str, Union[IntRange, FloatRange, CategoricalRange]],
    performance_generator: ObjectiveMetricGenerator,
    runtimes: list[datetime],
) -> float:
    """Evaluates a hyperparameter configuration using synthetic performance generation for Optuna.

    Args:
        trial: Optuna trial object containing the hyperparameter suggestions.
        params: Dictionary mapping parameter names to their range specifications.
        performance_generator: Synthetic objective function that generates performance predictions.
        runtimes: List to record timestamps for runtime tracking.

    Returns:
        Predicted performance value for the suggested hyperparameter configuration.
    """
    result = performance_generator.predict(
        configuration=set_optuna_params(trial, params)
    )
    record_runtime(runtimes)

    return result


def build_optuna_distributions(
    raw_params: dict[str, Union[IntRange, FloatRange, CategoricalRange]]
) -> dict[str, optuna.distributions.BaseDistribution]:
    """Creates Optuna distribution objects for parameter spaces to support warm-start functionality.

    Args:
        raw_params: Dictionary mapping parameter names to their range specifications
            (IntRange, FloatRange, or CategoricalRange).

    Returns:
        Dictionary mapping parameter names to corresponding Optuna distribution objects
        for use in warm-start trial creation.
    """
    dists: dict[str, optuna.distributions.BaseDistribution] = {}
    # Suppress Optuna deprecation FutureWarnings that are raised when using
    # legacy distribution names (e.g., IntLogUniformDistribution). Optuna
    # internally converts these to the newer distribution classes but emits
    # warnings which are noisy for our benchmarking outputs.
    with warnings.catch_warnings():
        # Ignore FutureWarnings about deprecated Optuna distribution classes
        # (these are noisy and Optuna internally converts them to new classes).
        warnings.filterwarnings("ignore", category=FutureWarning)
        for name, param in raw_params.items():
            if isinstance(param, IntRange):
                log_flag = getattr(param, "log", False)
                if log_flag:
                    dists[name] = optuna.distributions.IntLogUniformDistribution(
                        low=param.lower, high=param.upper
                    )
                else:
                    dists[name] = optuna.distributions.IntUniformDistribution(
                        low=param.lower, high=param.upper
                    )
            elif isinstance(param, FloatRange):
                log_flag = getattr(param, "log", False)
                if log_flag:
                    dists[name] = optuna.distributions.LogUniformDistribution(
                        low=param.lower, high=param.upper
                    )
                else:
                    dists[name] = optuna.distributions.UniformDistribution(
                        low=param.lower, high=param.upper
                    )
            elif isinstance(param, CategoricalRange):
                dists[name] = optuna.distributions.CategoricalDistribution(
                    choices=param.choices
                )
            else:
                raise ValueError(f"Unknown parameter type: {type(param)}")
    return dists


def optuna_tune(
    raw_params: dict[str, Union[IntRange, FloatRange, CategoricalRange]],
    performance_generator: ObjectiveMetricGenerator,
    tuner_model: OptunaModel,
    warm_start_configs: Optional[list[tuple[dict, float]]] = None,
    random_state: Optional[int] = None,
    n_trials: Optional[int] = None,
    timeout: Optional[float] = None,
) -> pd.DataFrame:
    """Runs hyperparameter optimization using Optuna with a synthetic objective function.

    Args:
        raw_params: Dictionary mapping parameter names to their range specifications
            (IntRange, FloatRange, or CategoricalRange).
        performance_generator: Synthetic objective function for generating performance predictions.
        tuner_model: OptunaModel configuration specifying the search algorithm and parameters.
        warm_start_configs: Optional list of (configuration, loss) tuples for initialization.
        random_state: Optional random seed for reproducible results.
        n_trials: Optional maximum number of optimization trials.
        timeout: Optional time budget in seconds for the optimization process.

    Returns:
        DataFrame containing the complete tuning history with trial results and metadata.
    """
    searcher = tuner_model.searcher

    if searcher == "TPE":
        initialized_sampler = TPESampler(
            seed=random_state, n_startup_trials=0, n_ei_candidates=N_CANDIDATES
        )
    elif searcher == "random":
        initialized_sampler = RandomSampler(seed=random_state)
    elif searcher == "CMA-ES":
        initialized_sampler = CmaEsSampler(seed=random_state, n_startup_trials=0)
    elif searcher == "GP":
        initialized_sampler = GPSampler(seed=random_state, n_startup_trials=0)
    elif searcher.startswith("custom-GP-"):
        acq_func_name = searcher.replace("custom-GP-", "")
        try:
            acq_func = ExpandedAcquisitionFunction(acq_func_name)
        except ValueError:
            raise ValueError(f"Unknown CONFOPT acquisition function: {acq_func_name}")

        initialized_sampler = StrippedGPSampler(
            acquisition_function=acq_func,
            n_candidates=N_CANDIDATES,
            seed=random_state,
            n_startup_trials=0,
            maximize=False,
        )
    else:
        raise ValueError(f"Unknown optuna sampler: {searcher}")

    study = optuna.create_study(direction="minimize", sampler=initialized_sampler)
    distributions = build_optuna_distributions(raw_params)

    # Create runtime tracker
    runtimes = create_runtime_tracker()

    if warm_start_configs:
        for config, loss in warm_start_configs:
            trial = optuna.trial.create_trial(
                params=config,
                distributions=distributions,
                value=loss,
                state=optuna.trial.TrialState.COMPLETE,
            )
            study.add_trial(trial)

    if n_trials is not None:
        if warm_start_configs is not None:
            adj_n_trials = n_trials - len(warm_start_configs)
        else:
            adj_n_trials = n_trials
    else:
        adj_n_trials = n_trials

    study.optimize(
        lambda trial: optuna_artificial_objective(
            trial, raw_params, performance_generator, runtimes
        ),
        n_trials=adj_n_trials,
        timeout=timeout,
        n_jobs=1,
    )

    # Apply retroactive timestamps for warm-start configurations
    all_runtimes = apply_retroactive_timestamps(warm_start_configs, runtimes)

    history = [
        build_history_entry(
            end_time=all_runtimes[idx],
            performance=trial.value,
            configurations=trial.params,
            iteration=idx + 1,
        )
        for idx, trial in enumerate(study.trials)
    ]
    return pd.DataFrame(history)


def confopt_objective_function(
    performance_generator: ObjectiveMetricGenerator,
    runtimes: list[datetime],
) -> Any:
    """Creates a ConfOpt-compatible objective function that evaluates hyperparameter configurations.

    Args:
        performance_generator: Synthetic objective function for generating performance predictions.
        runtimes: List to record timestamps for runtime tracking during optimization.

    Returns:
        Callable objective function that takes a configuration dictionary and returns
        the predicted performance value for use with ConfOpt tuners.
    """

    def objective(configuration: Dict) -> float:
        result = performance_generator.predict(configuration=configuration)
        record_runtime(runtimes)

        return result

    return objective


def setup_confopt_params(
    raw_params: dict[str, Union[IntRange, FloatRange, CategoricalRange]],
) -> dict[str, Any]:
    """Converts parameter range specifications to ConfOpt-compatible search space definitions.

    Args:
        raw_params: Dictionary mapping parameter names to their range specifications
            (IntRange, FloatRange, or CategoricalRange).

    Returns:
        Dictionary mapping parameter names to ConfOpt range objects for search space definition.
    """
    confopt_params: dict[str, Any] = {}
    for name, param in raw_params.items():
        if isinstance(param, IntRange):
            log_flag = getattr(param, "log", False)
            confopt_params[name] = ranges.IntRange(
                min_value=param.lower, max_value=param.upper, log_scale=log_flag
            )
        elif isinstance(param, FloatRange):
            log_flag = getattr(param, "log", False)
            confopt_params[name] = ranges.FloatRange(
                min_value=param.lower, max_value=param.upper, log_scale=log_flag
            )
        elif isinstance(param, CategoricalRange):
            confopt_params[name] = ranges.CategoricalRange(choices=param.choices)
        else:
            raise ValueError(f"Unknown parameter type: {type(param)}")
    return confopt_params


def confopt_tune(
    raw_params: dict[str, Union[IntRange, FloatRange, CategoricalRange]],
    performance_generator: ObjectiveMetricGenerator,
    tuner_model: ConfOptModel,
    warm_start_configs: Optional[list[tuple[dict, float]]] = None,
    random_state: Optional[int] = None,
    n_trials: Optional[int] = None,
    timeout: Optional[float] = None,
    searcher_tuning_framework: Optional[str] = None,
) -> pd.DataFrame:
    """Runs conformal hyperparameter optimization using the ConfOpt framework with synthetic objectives.

    Args:
        raw_params: Dictionary mapping parameter names to their range specifications
            (IntRange, FloatRange, or CategoricalRange).
        performance_generator: Synthetic objective function for generating performance predictions.
        tuner_model: ConfOptModel configuration containing the conformal searcher and parameters.
        warm_start_configs: Optional list of (configuration, loss) tuples for initialization.
        random_state: Optional random seed for reproducible results.
        n_trials: Optional maximum number of optimization trials.
        timeout: Optional time budget in seconds for the optimization process.
        searcher_tuning_framework: Optional framework identifier for searcher training ("decaying" or "fixed").

    Returns:
        DataFrame containing the complete tuning history with conformal prediction intervals and metadata.
    """
    runtimes = create_runtime_tracker()

    objective_fn = confopt_objective_function(performance_generator, runtimes)
    confopt_params = setup_confopt_params(raw_params)
    
    search_space_size = _calculate_search_space_size(raw_params)
    n_candidates = min(N_CANDIDATES, max(100, search_space_size))
    
    conformal_tuner = ConformalTuner(
        objective_function=objective_fn,
        search_space=confopt_params,
        minimize=True,
        n_candidates=n_candidates,
        warm_starts=warm_start_configs,
        dynamic_sampling=True,
    )

    adj_n_trials = n_trials
    searcher = tuner_model.searcher

    searcher_copy = deepcopy(searcher)
    # NOTE: We take the original sampler's alpha, to avoid mutation later on:
    if isinstance(searcher.sampler, (LowerBoundSampler, PessimisticLowerBoundSampler)):
        alpha = searcher.sampler.alpha
    # NOTE: Zero random searches because this benchmark repository uses warm-starting:
    conformal_tuner.tune(
        searcher=searcher_copy,
        max_runtime=int(timeout) if timeout is not None else None,
        max_searches=adj_n_trials,
        n_random_searches=0,
        # conformal_retraining_frequency=1,
        verbose=False,
        random_state=random_state,
        optimizer_framework=searcher_tuning_framework
        if searcher_tuning_framework in ("decaying", "fixed")
        else None,
    )

    # Apply retroactive timestamps for warm-start configurations
    all_runtimes = apply_retroactive_timestamps(warm_start_configs, runtimes)

    history = []
    for idx, trial in enumerate(conformal_tuner.study.trials):
        history.append(
            build_history_entry(
                end_time=all_runtimes[idx],
                performance=trial.performance,
                configurations=trial.configuration,
                iteration=idx + 1,
            )
        )
    return pd.DataFrame(history)


def setup_skopt_params(
    raw_params: dict[str, Union[IntRange, FloatRange, CategoricalRange]]
) -> tuple[list[Any], list[str]]:
    """Converts parameter range specifications to scikit-optimize compatible search space.

    Args:
        raw_params: Dictionary mapping parameter names to their range specifications
            (IntRange, FloatRange, or CategoricalRange).

    Returns:
        Tuple containing:
        - List of skopt dimension objects defining the search space
        - List of parameter names in the same order as the dimensions
    """
    skopt_params: list[Any] = []
    skopt_param_names: list[str] = []
    for name, param in raw_params.items():
        if isinstance(param, IntRange):
            log_flag = getattr(param, "log", False)
            prior = "log-uniform" if log_flag else "uniform"
            skopt_params.append(
                SKInteger(param.lower, param.upper, prior=prior, name=name)
            )
        elif isinstance(param, FloatRange):
            log_flag = getattr(param, "log", False)
            prior = "log-uniform" if log_flag else "uniform"
            skopt_params.append(Real(param.lower, param.upper, prior=prior, name=name))
        elif isinstance(param, CategoricalRange):
            skopt_params.append(SKCategorical(param.choices, name=name))
        else:
            raise ValueError(f"Unknown parameter type: {type(param)}")
        skopt_param_names.append(name)

    return skopt_params, skopt_param_names


def skopt_objective(
    param_values: list[Any],
    param_names: list[str],
    performance_generator: ObjectiveMetricGenerator,
    runtimes: list[datetime],
) -> float:
    """Evaluates a hyperparameter configuration for scikit-optimize using synthetic performance generation.

    Args:
        param_values: List of parameter values in the same order as param_names.
        param_names: List of parameter names corresponding to the values.
        performance_generator: Synthetic objective function for generating performance predictions.
        runtimes: List to record timestamps for runtime tracking.

    Returns:
        Predicted performance value for the hyperparameter configuration.
    """
    params_dict = dict(zip(param_names, param_values))
    result = performance_generator.predict(configuration=params_dict)
    record_runtime(runtimes)
    return result


def skopt_tune(
    raw_params: dict[str, Union[IntRange, FloatRange, CategoricalRange]],
    performance_generator: ObjectiveMetricGenerator,
    tuner_model: SkOptModel,
    warm_start_configs: Optional[list[tuple[dict, float]]] = None,
    random_state: Optional[int] = None,
    n_trials: Optional[int] = None,
    timeout: Optional[float] = None,
) -> pd.DataFrame:
    """Runs Bayesian optimization using scikit-optimize (skopt) with a synthetic objective function.

    Args:
        raw_params: Dictionary mapping parameter names to their range specifications
            (IntRange, FloatRange, or CategoricalRange).
        performance_generator: Synthetic objective function for generating performance predictions.
        tuner_model: SkOptModel configuration specifying the optimization algorithm and parameters.
        warm_start_configs: Optional list of (configuration, loss) tuples for initialization.
        random_state: Optional random seed for reproducible results.
        n_trials: Optional maximum number of optimization trials.
        timeout: Optional time budget in seconds for the optimization process.

    Returns:
        DataFrame containing the complete tuning history with trial results and metadata.
    """
    skopt_params, param_names = setup_skopt_params(raw_params)
    if warm_start_configs is not None:
        x0 = [
            [config[name] for name in param_names] for config, _ in warm_start_configs
        ]
        y0 = [loss for _, loss in warm_start_configs]
    else:
        x0 = []
        y0 = []

    n_calls = (n_trials - len(warm_start_configs)) if warm_start_configs else n_trials

    runtimes = create_runtime_tracker()
    objective_fn = partial(
        skopt_objective,
        param_names=param_names,
        performance_generator=performance_generator,
        runtimes=runtimes,
    )

    searcher = tuner_model.searcher

    # NOTE: n_initial_points is set to 0 because this benchmark repository uses warm-starting:
    if searcher == "GP":
        result = gp_minimize(
            objective_fn,
            skopt_params,
            n_initial_points=0,
            n_calls=n_calls,
            x0=x0,
            y0=y0,
            random_state=random_state,
            acq_func="EI",
            acq_optimizer="sampling",
            n_points=N_CANDIDATES,
        )
    elif searcher == "RF":
        result = forest_minimize(
            objective_fn,
            skopt_params,
            n_initial_points=0,
            n_calls=n_calls,
            x0=x0,
            y0=y0,
            random_state=random_state,
            acq_func="EI",
            n_points=N_CANDIDATES,
        )
    elif searcher == "GBRT":
        result = gbrt_minimize(
            objective_fn,
            skopt_params,
            n_initial_points=0,
            n_calls=n_calls,
            x0=x0,
            y0=y0,
            random_state=random_state,
            acq_func="EI",
            n_points=N_CANDIDATES,
        )
    else:
        raise ValueError(f"Unknown scikit-opt method: {searcher}")

    if result is not None:
        # Apply retroactive timestamps for warm-start configurations
        all_runtimes = apply_retroactive_timestamps(warm_start_configs, runtimes)
        zipped = zip(result.func_vals, result.x_iters, all_runtimes)
    else:
        zipped = []

    history = [
        build_history_entry(
            end_time=end_time,
            performance=performance,
            iteration=idx + 1,
            configurations=dict(zip(param_names, params_list)),
        )
        for idx, (performance, params_list, end_time) in enumerate(zipped)
    ]
    return pd.DataFrame(history)


def setup_smac_configspace(
    raw_params: dict[str, Union[IntRange, FloatRange, CategoricalRange]],
    random_state: Optional[int] = None,
) -> ConfigurationSpace:
    """Creates SMAC ConfigurationSpace from parameter definitions.

    Args:
        raw_params: Dictionary mapping parameter names to IntRange, FloatRange, or CategoricalRange.
        random_state: Optional random seed.

    Returns:
        SMAC ConfigurationSpace object.
    """
    cs = ConfigurationSpace(seed=random_state)

    for name, param in raw_params.items():
        if isinstance(param, IntRange):
            log_flag = getattr(param, "log", False)
            hp = UniformIntegerHyperparameter(
                name, param.lower, param.upper, log=log_flag
            )
        elif isinstance(param, FloatRange):
            log_flag = getattr(param, "log", False)
            hp = UniformFloatHyperparameter(
                name, param.lower, param.upper, log=log_flag
            )
        elif isinstance(param, CategoricalRange):
            hp = CategoricalHyperparameter(name, param.choices)
        else:
            raise ValueError(f"Unknown parameter type: {type(param)}")
        cs.add_hyperparameter(hp)

    return cs


def smac_objective_function(
    config: Configuration,
    performance_generator: ObjectiveMetricGenerator,
    runtimes: list[datetime],
    seed: int = 0,
) -> float:
    """Objective function for SMAC using a synthetic performance generator.

    Args:
        config: SMAC Configuration object.
        performance_generator: ObjectiveMetricGenerator instance.
        runtimes: List to append runtime timestamps.
        seed: Random seed (required by SMAC interface).

    Returns:
        Predicted performance as float.
    """
    # Convert Configuration to dict for the performance generator
    config_dict = dict(config)
    result = performance_generator.predict(configuration=config_dict)
    record_runtime(runtimes)
    return result


class GlobalSearch(RandomSearch):
    """Custom RandomSearch that evaluates acquisition function for both TS and EI."""

    def _maximize(
        self,
        previous_configs: list,
        n_points: int,
        _sorted: bool = False,
    ):
        """Override to always evaluate acquisition function for TS."""
        if n_points > 1:
            rand_configs = self._configspace.sample_configuration(size=n_points)
        else:
            rand_configs = [self._configspace.sample_configuration()]

        # For both TS and EI, we need to evaluate the acquisition function
        if isinstance(self._acquisition_function, TS):
            origin_name = "Acquisition Function Maximizer: TS Random Search"
        else:
            origin_name = "Acquisition Function Maximizer: EI Random Search"

        for i in range(len(rand_configs)):
            rand_configs[i].origin = origin_name

        # Always evaluate acquisition function and sort by value
        return self._sort_by_acquisition_value(rand_configs)


def smac_tune(
    raw_params: dict[str, Union[IntRange, FloatRange, CategoricalRange]],
    performance_generator: ObjectiveMetricGenerator,
    tuner_model: SMACModel,
    warm_start_configs: Optional[list[tuple[dict, float]]] = None,
    random_state: Optional[int] = None,
    n_trials: Optional[int] = None,
    timeout: Optional[float] = None,
) -> pd.DataFrame:
    """Runs Bayesian optimization using SMAC3 with Random Forest surrogate and acquisition functions.

    Uses vanilla SMAC configuration for fair comparison with other tuners:
    - Each configuration evaluated exactly once (no racing)
    - No random interleaving (always uses acquisition function)
    - No parallelization
    - Single incumbent tracking
    - Deterministic scenario

    Args:
        raw_params: Dictionary mapping parameter names to their range specifications
            (IntRange, FloatRange, or CategoricalRange).
        performance_generator: Synthetic objective function for generating performance predictions.
        tuner_model: SMACModel configuration specifying the acquisition function and parameters.
        warm_start_configs: Optional list of (configuration, loss) tuples for initialization.
        random_state: Optional random seed for reproducible results.
        n_trials: Optional maximum number of optimization trials.
        timeout: Optional time budget in seconds for the optimization process.

    Returns:
        DataFrame containing the complete tuning history with trial results and metadata.
    """
    # Disable SMAC logging to reduce noise
    smac_logger = logging.getLogger("smac")
    smac_logger.setLevel(logging.ERROR)
    smac_logger.propagate = False

    smac_facade_logger = logging.getLogger("smac.facade")
    smac_facade_logger.setLevel(logging.ERROR)
    smac_facade_logger.propagate = False

    smac_intensifier_logger = logging.getLogger("smac.intensifier")
    smac_intensifier_logger.setLevel(logging.ERROR)
    smac_intensifier_logger.propagate = False

    smac_runhistory_logger = logging.getLogger("smac.runhistory")
    smac_runhistory_logger.setLevel(logging.ERROR)
    smac_runhistory_logger.propagate = False

    smac_optimizer_logger = logging.getLogger("smac.optimizer")
    smac_optimizer_logger.setLevel(logging.ERROR)
    smac_optimizer_logger.propagate = False

    # Create configuration space
    configspace = setup_smac_configspace(raw_params, random_state)

    scenario = Scenario(
        configspace=configspace,
        deterministic=True,  # Set to deterministic for fair comparison
        n_trials=n_trials if n_trials is not None else 100,
        walltime_limit=timeout,
        seed=random_state,
        n_workers=1,  # No parallelization
    )

    searcher = tuner_model.searcher
    # Configure acquisition function and maximizer based on sampler
    # Use TSRandomSearch for both EI and TS to properly evaluate acquisition functions
    if searcher == "SMAC-EI":
        acquisition_function = EI(xi=0.0, log=False)
        acquisition_maximizer = GlobalSearch(
            configspace=configspace,
            acquisition_function=acquisition_function,
            seed=random_state,
        )
    elif searcher == "SMAC-TS":
        # TODO: Fix SMAC-TS
        raise RuntimeError("SMAC-TS is unstable, SMAC-EI is recommended instead.")
        acquisition_function = TS()
        acquisition_maximizer = GlobalSearch(
            configspace=configspace,
            acquisition_function=acquisition_function,
            seed=random_state,
        )
    else:
        raise ValueError(f"Unknown SMAC sampler: {searcher}")

    # Setup runtime tracking
    runtimes = create_runtime_tracker()
    objective_fn = partial(
        smac_objective_function,
        performance_generator=performance_generator,
        runtimes=runtimes,
    )

    # Create SMAC facade with fair comparison settings
    smac = HyperparameterOptimizationFacade(
        scenario=scenario,
        target_function=objective_fn,
        model=HyperparameterOptimizationFacade.get_model(scenario),
        acquisition_function=acquisition_function,
        acquisition_maximizer=acquisition_maximizer,
        # Disable racing: each configuration evaluated exactly once
        intensifier=HyperparameterOptimizationFacade.get_intensifier(
            scenario, max_config_calls=1
        ),
        # Disable random interleaving: always use acquisition function
        random_design=HyperparameterOptimizationFacade.get_random_design(
            scenario, probability=0.0
        ),
        initial_design=HyperparameterOptimizationFacade.get_initial_design(
            scenario, n_configs=0 if warm_start_configs else None
        ),
        overwrite=True,
    )

    # Handle warm start configurations
    if warm_start_configs:
        for config_dict, cost in warm_start_configs:
            config = Configuration(configspace, config_dict)
            trial_info = TrialInfo(config=config, seed=random_state or 0)
            trial_value = TrialValue(cost=cost)
            smac.tell(trial_info, trial_value)

    # Run optimization
    smac.optimize()

    # Build history from runhistory
    history = []

    # Apply retroactive timestamps for warm-start configurations
    all_runtimes = apply_retroactive_timestamps(warm_start_configs, runtimes)

    for idx, (trial_key, trial_value) in enumerate(smac.runhistory.items()):
        config = smac.runhistory.get_config(trial_key.config_id)
        config_dict = config.get_dictionary()  # Use proper ConfigSpace method

        end_time = all_runtimes[idx]
        history.append(
            build_history_entry(
                end_time=end_time,
                performance=trial_value.cost,
                configurations=config_dict,
                iteration=idx + 1,
            )
        )

    return pd.DataFrame(history)


def gp_opt_objective_function(
    performance_generator: ObjectiveMetricGenerator,
    runtimes: list[datetime],
) -> Any:
    """Returns a callable objective function for gp_opt.

    Args:
        performance_generator: ObjectiveMetricGenerator instance.
        runtimes: List to track runtime timestamps.

    Returns:
        Callable that takes a configuration and returns predicted performance.
    """

    def objective(configuration: Dict) -> float:
        result = performance_generator.predict(configuration=configuration)
        record_runtime(runtimes)
        return result

    return objective


def setup_gp_opt_params(
    raw_params: dict[str, Union[IntRange, FloatRange, CategoricalRange]],
) -> dict[str, Any]:
    """Builds gp_opt search space from parameter definitions.

    Args:
        raw_params: Dictionary mapping parameter names to IntRange, FloatRange, or CategoricalRange.

    Returns:
        Dictionary mapping parameter names to gp_opt range objects.
    """
    gp_opt_params: dict[str, Any] = {}
    for name, param in raw_params.items():
        if isinstance(param, IntRange):
            log_flag = getattr(param, "log", False)
            gp_opt_params[name] = gp_opt_ranges.IntRange(
                min_value=param.lower, max_value=param.upper, log_scale=log_flag
            )
        elif isinstance(param, FloatRange):
            log_flag = getattr(param, "log", False)
            gp_opt_params[name] = gp_opt_ranges.FloatRange(
                min_value=param.lower, max_value=param.upper, log_scale=log_flag
            )
        elif isinstance(param, CategoricalRange):
            gp_opt_params[name] = gp_opt_ranges.CategoricalRange(choices=param.choices)
        else:
            raise ValueError(f"Unknown parameter type: {type(param)}")
    return gp_opt_params


def gp_opt_tune(
    raw_params: dict[str, Union[IntRange, FloatRange, CategoricalRange]],
    performance_generator: ObjectiveMetricGenerator,
    tuner_model: CustomGPModel,
    warm_start_configs: Optional[list[tuple[dict, float]]] = None,
    random_state: Optional[int] = None,
    n_trials: Optional[int] = None,
    timeout: Optional[float] = None,
) -> pd.DataFrame:
    """Runs gp_opt tuning with a synthetic objective.

    Args:
        raw_params: Dictionary mapping parameter names to IntRange, FloatRange, or CategoricalRange.
        performance_generator: ObjectiveMetricGenerator instance.
        tuner_model: Name of the surrogate model to use.
        warm_start_configs: Optional list of (config, loss) tuples for warm start.
        random_state: Optional random seed.
        n_trials: Optional number of trials.
        timeout: Optional time budget in seconds.

    Returns:
        DataFrame with tuning history.
    """
    # Create runtime tracker
    runtimes = create_runtime_tracker()

    objective_fn = gp_opt_objective_function(performance_generator, runtimes)
    gp_opt_params = setup_gp_opt_params(raw_params)
    searcher = GPTuner(
        objective_function=objective_fn,
        search_space=gp_opt_params,
        minimize=True,
        n_candidates=N_CANDIDATES,
        warm_starts=warm_start_configs,
        dynamic_sampling=True,
    )

    adj_n_trials = n_trials

    if tuner_model.searcher == "EI":
        acquisition_func = ExpectedImprovement()
    elif tuner_model.searcher == "TS":
        acquisition_func = ThompsonSampling()
    elif tuner_model.searcher == "log-EI":
        acquisition_func = LogExpectedImprovement()
    elif tuner_model.searcher == "UCB":
        acquisition_func = UpperConfidenceBound()
    elif tuner_model.searcher == "OBS":
        acquisition_func = OptimisticThompsonSampling()
    else:
        raise ValueError(f"Unknown gp_opt sampler: {tuner_model}")

    # NOTE: Zero random searches because this benchmark repository uses warm-starting:
    searcher.tune(
        acquisition_func=acquisition_func,
        max_runtime=int(timeout) if timeout is not None else None,
        max_searches=adj_n_trials,
        n_random_searches=0,
        retraining_frequency=1,
        verbose=False,
        random_state=random_state,
    )

    # Apply retroactive timestamps for warm-start configurations
    all_runtimes = apply_retroactive_timestamps(warm_start_configs, runtimes)

    history = []
    for idx, trial in enumerate(searcher.study.trials):
        history.append(
            build_history_entry(
                end_time=all_runtimes[idx],
                performance=trial.performance,
                configurations=trial.configuration,
                iteration=idx + 1,
            )
        )
    return pd.DataFrame(history)


def tune(
    performance_generator: ObjectiveMetricGenerator,
    tuner_config: TunerConfig,
    params: dict[str, Union[IntRange, FloatRange, CategoricalRange]],
    warm_start_configs: Optional[list[tuple[dict, float]]] = None,
    random_state: Optional[int] = None,
    n_trials: Optional[int] = None,
    timeout: Optional[float] = None,
) -> pd.DataFrame:
    """Unified tuning interface for optuna, confopt, and skopt.

    Args:
        performance_generator: ObjectiveMetricGenerator instance.
        tuner_config: TunerConfig object specifying tuner and searcher.
        params: Dictionary mapping parameter names to IntRange, FloatRange, or CategoricalRange.
        warm_start_configs: Optional list of (config, loss) tuples for warm start.
        random_state: Optional random seed.
        n_trials: Optional number of trials.
        timeout: Optional time budget in seconds.

    Returns:
        DataFrame with tuning history.
    """
    # Shared arguments for all tuner functions:
    shared_kwargs = {
        "tuner_model": tuner_config.tuner,
        "raw_params": params,
        "performance_generator": performance_generator,
        "warm_start_configs": warm_start_configs,
        "random_state": random_state,
        "n_trials": n_trials,
        "timeout": timeout,
    }

    if tuner_config.tuner.backend == "optuna":
        history = optuna_tune(
            **shared_kwargs,
        )
    elif tuner_config.tuner.backend == "confopt":
        history = confopt_tune(
            searcher_tuning_framework=tuner_config.searcher_tuning_framework,
            **shared_kwargs,
        )
    elif tuner_config.tuner.backend == "skopt":
        history = skopt_tune(
            **shared_kwargs,
        )
    elif tuner_config.tuner.backend == "syne_tune_cqr":
        history = syne_tune_cqr_tune(
            **shared_kwargs,
        )
    elif tuner_config.tuner.backend == "smac":
        history = smac_tune(
            **shared_kwargs,
        )
    elif tuner_config.tuner.backend == "gp_opt":
        history = gp_opt_tune(
            **shared_kwargs,
        )
    else:
        raise ValueError(f"Unknown tuner: {tuner_config.tuner.backend}")

    return history
