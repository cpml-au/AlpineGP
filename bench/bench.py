# import matplotlib.pyplot as plt
from deap import gp, base

from flex.gp import regressor as gps
from flex.gp.util import (
    detect_nested_trigonometric_functions,
    load_config_data,
    compile_individual_with_consts,
)
from flex.gp.primitives import add_primitives_to_pset_from_dict
import numpy as np
import ray

import time

import warnings
import pygmo as pg

import re
from sklearn.metrics import r2_score
from datasets import generate_dataset

import mygrad as mg
from mygrad._utils.lock_management import mem_guard_off

from functools import partial

import optuna
import sympy as sp


def check_trig_fn(ind):
    return len(re.findall("cos", str(ind))) + len(re.findall("sin", str(ind)))


def check_nested_trig_fn(ind):
    return detect_nested_trigonometric_functions(str(ind))


def eval_model(individual, X, consts=[]):
    num_variables = X.shape[1]
    if num_variables > 1:
        X = [X[:, i] for i in range(num_variables)]
    else:
        X = [X]
    warnings.filterwarnings("ignore")
    y_pred = individual(*X, consts)
    return y_pred


def compute_MSE(individual, X, y, consts=[]):
    y_pred = eval_model(individual, X, consts)
    MSE = np.mean((y - y_pred) ** 2)

    if np.isnan(MSE) or np.isinf(MSE):
        MSE = 1e8

    return MSE


def sanitize_array_for_metrics(arr, name, clip_value=1e150):
    """Return a finite float64 array suitable for metric computation."""
    arr = np.asarray(arr, dtype=np.float64).reshape(-1)
    arr = np.nan_to_num(arr, nan=0.0, posinf=clip_value, neginf=-clip_value)
    arr = np.clip(arr, -clip_value, clip_value)
    return arr


def safe_r2_score(y_true, y_pred):
    """Robust R^2 computation that avoids crashing on bad numeric values."""
    try:
        return r2_score(y_true, y_pred)
    except ValueError as exc:
        print(f"Warning: r2_score failed ({exc}). Returning NaN.")
        return np.nan


def gaussian_iid_negative_log_likelihood(mse, n_samples):
    """Total Gaussian i.i.d. negative log-likelihood with MLE variance."""
    eps = 1e-12
    sigma2 = max(mse, eps)
    n = max(int(n_samples), 1)
    return 0.5 * n * (np.log(2.0 * np.pi * sigma2) + 1.0)


def bic_gaussian_iid(mse, n_samples, model_size):
    """Bayesian Information Criterion under Gaussian i.i.d. residuals."""
    nll = gaussian_iid_negative_log_likelihood(mse, n_samples)
    n = max(int(n_samples), 2)
    k = max(int(model_size), 1)
    return 2.0 * nll + k * np.log(n)


def compute_fitness_value(MSE, n_samples, model_size, penalty):
    # Evolution fitness: only MSE + linear size regularization.
    # BIC is reserved for optional final model selection at the end.
    return MSE + penalty["reg_param"] * model_size


def select_best_model_by_bic(estimator, pset, X, y):
    """
    Select best individual in the final population using BIC.

    This is intended for end-of-evolution model selection only.
    """
    toolbox = base.Toolbox()
    toolbox.register("compile", gp.compile, pset=pset)

    best = None
    best_bic = np.inf

    for ind in estimator.get_population_individuals():
        consts = getattr(ind, "consts", [])
        if consts is None:
            continue
        callable, _ = compile_individual_with_consts(ind, toolbox)
        mse = compute_MSE(callable, X, y, consts=consts)
        model_size = len(ind) + len(consts)
        bic = bic_gaussian_iid(mse, y.shape[0], model_size)
        if bic < best_bic:
            best_bic = bic
            best = ind

    if best is None:
        raise RuntimeError(
            "Unable to select a best model by BIC from final population."
        )

    estimator._best = best
    return best, best_bic


def eval_MSE_and_tune_constants(tree, toolbox, X, y):
    individual, num_consts = compile_individual_with_consts(tree, toolbox)

    if num_consts > 0:

        eval_MSE = partial(compute_MSE, individual=individual, X=X, y=y)

        x0 = np.ones(num_consts)

        class fitting_problem:
            def fitness(self, x):
                total_err = eval_MSE(consts=x)
                return [total_err]

            def gradient(self, x):
                with mem_guard_off:
                    xt = mg.tensor(x, copy=False)
                    f = self.fitness(xt)[0]
                    f.backward()
                return xt.grad

            def get_bounds(self):
                return (-5.0 * np.ones(num_consts), 5.0 * np.ones(num_consts))

        # PYGMO SOLVER
        prb = pg.problem(fitting_problem())
        # algo = pg.algorithm(pg.nlopt(solver="lbfgs"))
        algo = pg.algorithm(pg.pso(gen=10))
        pop = pg.population(prb, size=70)
        # algo.extract(pg.nlopt).maxeval = 10
        pop = pg.population(prb, size=1)
        pop.push_back(x0)
        pop = algo.evolve(pop)
        MSE = pop.champion_f[0]
        consts = pop.champion_x

        if np.isinf(MSE) or np.isnan(MSE):
            MSE = 1e8
    else:
        MSE = compute_MSE(individual, X, y)
        consts = []
    return MSE, consts


def get_features_batch(
    individuals_batch,
    individ_feature_extractors=[len, check_nested_trig_fn, check_trig_fn],
):
    features_batch = [
        [fe(i) for i in individuals_batch] for fe in individ_feature_extractors
    ]

    individ_length = features_batch[0]
    nested_trigs = features_batch[1]
    num_trigs = features_batch[2]
    return individ_length, nested_trigs, num_trigs


def predict(
    individuals_batch,
    toolbox,
    X,
    penalty,
    fitness_scale,
    tarpeian_length_threshold,
):

    predictions = [None] * len(individuals_batch)

    for i, tree in enumerate(individuals_batch):
        callable, _ = compile_individual_with_consts(tree, toolbox)
        predictions[i] = eval_model(callable, X, consts=tree.consts)

    return predictions


def compute_MSEs(
    individuals_batch,
    toolbox,
    X,
    y,
    penalty,
    fitness_scale,
    tarpeian_length_threshold,
):

    total_errs = [None] * len(individuals_batch)

    for i, tree in enumerate(individuals_batch):
        callable, _ = compile_individual_with_consts(tree, toolbox)
        total_errs[i] = compute_MSE(callable, X, y, consts=tree.consts)

    return total_errs


def compute_attributes(
    individuals_batch,
    toolbox,
    X,
    y,
    penalty,
    fitness_scale,
    tarpeian_length_threshold,
):

    attributes = [None] * len(individuals_batch)

    individ_length, nested_trigs, num_trigs = get_features_batch(individuals_batch)

    for i, tree in enumerate(individuals_batch):

        # Tarpeian selection
        if individ_length[i] >= tarpeian_length_threshold:
            consts = None
            fitness = (1e8,)
        else:
            MSE, consts = eval_MSE_and_tune_constants(tree, toolbox, X, y)
            if MSE < 1e-12:
                # Keep fitness equal to pure error so early stopping can trigger.
                fitness = (fitness_scale * MSE,)
            else:
                num_consts = len(consts)
                model_size = individ_length[i] + num_consts
                age_penalty = penalty.get("age_reg_param", 0.0) * getattr(
                    tree, "age", 0
                )
                fitness_value = compute_fitness_value(
                    MSE=MSE,
                    n_samples=y.shape[0],
                    model_size=model_size,
                    penalty=penalty,
                )
                fitness = (
                    fitness_scale
                    * (
                        fitness_value
                        + age_penalty
                        + 100000 * nested_trigs[i]
                        + 0.0 * num_trigs[i]
                    ),
                )
        attributes[i] = {"consts": consts, "fitness": fitness}
    return attributes


def assign_attributes(individuals_batch, attributes):
    for ind, attr in zip(individuals_batch, attributes):
        ind.consts = attr["consts"]
        ind.fitness.values = attr["fitness"]


def eval(problem, cfgfile, seed=42, grid_search=False, coarse_grained_islands=False,
         remove_init_duplicates=True, custom_logger=None):

    regressor_params, config_file_data = load_config_data(cfgfile)

    scaleXy = config_file_data["gp"]["scaleXy"]

    # generate training and test datasets
    (
        X_train_scaled,
        y_train_scaled,
        X_test_scaled,
        y_test,
        _,
        scaler_y,
        num_variables,
        _,
    ) = generate_dataset(problem, scaleXy=scaleXy, random_state=seed)

    if num_variables == 1:
        pset = gp.PrimitiveSetTyped("Main", [float], float)
        pset.renameArguments(ARG0="x")
    elif num_variables == 2:
        pset = gp.PrimitiveSetTyped("Main", [float, float], float)
        pset.renameArguments(ARG0="x")
        pset.renameArguments(ARG1="y")
    else:
        pset = gp.PrimitiveSetTyped("Main", [float] * num_variables, float)

    pset = add_primitives_to_pset_from_dict(pset, config_file_data["gp"]["primitives"])

    batch_size = config_file_data["gp"]["batch_size"]
    if config_file_data["gp"]["use_constants"]:
        pset.addTerminal(object, float, "c")

    callback_func = assign_attributes
    fitness_scale = 1.0

    penalty = config_file_data["gp"]["penalty"]
    tarpeian_length_threshold = config_file_data["gp"].get(
        "tarpeian_length_threshold", 40
    )
    common_params = {
        "penalty": penalty,
        "fitness_scale": fitness_scale,
        "tarpeian_length_threshold": tarpeian_length_threshold,
    }

    gpsr = gps.GPSymbolicRegressor(
        pset_config=pset,
        fitness=compute_attributes,
        predict_func=predict,
        score_func=compute_MSEs,
        common_data=common_params,
        callback_func=callback_func,
        custom_logger=custom_logger,
        print_log=True,
        num_best_inds_str=1,
        save_best_individual=False,
        output_path="./",
        seed_str=None,
        batch_size=batch_size,
        remove_init_duplicates=remove_init_duplicates,
        save_detailed_log=False,
        early_stop_fitness_threshold=1e-12,
        coarse_grained_islands=coarse_grained_islands,
        **regressor_params,
    )

    if grid_search:
        study = optuna.create_study(study_name=problem, direction="maximize")

        param = {
            "num_individuals": optuna.distributions.CategoricalDistribution([100, 200])
        }

        # wrap regressor inside an optuna CV search object
        best_estimator = optuna.integration.OptunaSearchCV(
            gpsr,
            param,
            cv=5,
            study=study,
            refit=True,
            n_trials=2,
            verbose=2,
            timeout=3600,
        )
    else:
        best_estimator = gpsr

    tic = time.time()
    best_estimator.fit(X_train_scaled, y_train_scaled)
    toc = time.time()

    if grid_search:
        best_estimator = best_estimator.best_estimator_
    else:
        best_estimator = best_estimator

    final_model_selection = config_file_data["gp"].get(
        "final_model_selection", "fitness"
    )
    if final_model_selection == "bic":
        best_model, best_bic = select_best_model_by_bic(
            estimator=best_estimator,
            pset=pset,
            X=X_train_scaled,
            y=y_train_scaled,
        )
    else:
        best_model = best_estimator.get_best_individuals(n_ind=1)[0]

    try:
        best_model_sympy = sp.simplify(best_estimator.get_best_individual_sympy())
        best_model_str = str(best_model_sympy)
    except Exception as exc:
        print(
            "Warning: failed to convert best model to SymPy "
            f"({type(exc).__name__}: {exc}). "
            "Using raw GP string instead."
        )
        best_model_str = str(best_model)
    print("Best selected model = ", best_model_str)

    if hasattr(best_model, "consts"):
        print("Best parameters = ", best_model.consts)

    print("Elapsed time = ", toc - tic)
    individuals_per_sec = (
        (best_estimator.get_last_gen() + 1)
        * gpsr.num_individuals
        * gpsr.num_islands
        / (toc - tic)
    )
    print("Individuals per sec = ", individuals_per_sec)

    u_best = best_estimator.predict(X_test_scaled)

    # de-scale outputs before computing errors
    if scaleXy:
        u_best = scaler_y.inverse_transform(u_best.reshape(-1, 1)).flatten()

    y_test_safe = sanitize_array_for_metrics(y_test, "y_test")
    u_best_safe = sanitize_array_for_metrics(u_best, "u_best")
    MSE = np.mean((u_best_safe - y_test_safe) ** 2)
    r2_test = safe_r2_score(y_test_safe, u_best_safe)
    print("MSE on the test set = ", MSE)
    print("R^2 on the test set = ", r2_test)

    pred_train = best_estimator.predict(X_train_scaled)

    if scaleXy:
        pred_train = scaler_y.inverse_transform(pred_train.reshape(-1, 1)).flatten()
        y_train_scaled = scaler_y.inverse_transform(
            y_train_scaled.reshape(-1, 1)
        ).flatten()

    y_train_safe = sanitize_array_for_metrics(y_train_scaled, "y_train")
    pred_train_safe = sanitize_array_for_metrics(pred_train, "pred_train")
    MSE = np.mean((pred_train_safe - y_train_safe) ** 2)
    r2_train = safe_r2_score(y_train_safe, pred_train_safe)
    print("MSE on the training set = ", MSE)
    print("R^2 on the training set = ", r2_train)

    return r2_train, r2_test, best_model_str, toc - tic


if __name__ == "__main__":
    import argparse
    import pathlib

    parser = argparse.ArgumentParser()

    parser.add_argument(
        "cfgfile",
        type=pathlib.Path,
        help="Path of the YAML config file for the problem.",
    )
    parser.add_argument("problem", help="Name of the PMLB or Nguyen dataset.")

    parser.add_argument(
        "-gs",
        action="store_true",
        help="Perform grid search for hyperparameter tuning.",
    )

    args = parser.parse_args()

    problem = args.problem
    cfgfile = args.cfgfile

    seeds = [29802, 22118, 860, 15795, 21575, 5390, 11964, 6265, 23654, 11284]

    r2_tests = []

    header = ["problem", "trial", "r2_train", "r2_test", "seed", "best_model"]

    with open(f"./results/{problem}.csv", "w") as f:
        for h in header:
            f.write(h)
            f.write("\n" if h == header[-1] else ";")

    for i, seed in enumerate(seeds):
        print("PROBLEM: ", problem)
        print("seed: ", seed)
        r2_train, r2_test, best_model_str, _ = eval(
            problem=problem, cfgfile=cfgfile, seed=seed, grid_search=args.gs
        )
        r2_tests.append(r2_test)

        stats = {
            "problem": problem,
            "trial": i + 1,
            "r2_train": r2_train,
            "r2_test": r2_test,
            "seed": seed,
            "best_model": best_model_str,
        }

        with open(f"./results/{problem}.csv", "a") as f:
            for h in header:
                f.write(f"{stats[h]}")
                f.write("\n" if h == header[-1] else ";")

    print("Median Test R^2 = ", np.median(r2_tests))

    ray.shutdown()
