"""
train.py
-----
Module for training a Random Forest model for sales forecasting.
Evaluates the model on a validation set and saves the trained model for future use.

Main steps:
    1. Load the prepared dataset (grid_model.csv).
    2. Split the data into training and validation sets based on date_block_num.
    3. Optimize hyperparameters using RandomizedSearchCV.
    4. Train a Random Forest regressor with the best hyperparameters.
    5. Evaluate the model using RMSE on the validation set.
    6. Save the trained model to the artifacts directory.
"""

# -----
# Libraries
import time
from pathlib import Path

import joblib
import numpy as np
import pandas as pd
from sklearn.ensemble import RandomForestRegressor
from sklearn.metrics import mean_squared_error
from sklearn.model_selection import RandomizedSearchCV

from utils.logger import setup_logger

# -----
# Constants
GRID_MODEL_PREP = "grid_model.csv"
MODEL_PATH = "random_forest_lags.pkl"

FEATURE_LAGS = ["lag_1", "lag_3", "lag_6", "lag_12"]
TARGET_COL = "item_cnt_month"

MONTH_TRAIN = 32
MONTH_VAL = 33
CLIP = 20

RANDOM_SEED = 10
N_ESTIMATORS = 100
MAX_DEPTH = 10

# Hyperparameter search space for RandomizedSearchCV
PARAM_DISTRIBUTIONS = {
    "n_estimators": [50, 100, 200, 300],
    "max_depth": [5, 8, 10, 12, 15, None],
    "min_samples_split": [2, 5, 10],
    "min_samples_leaf": [1, 2, 4],
    "max_features": ["sqrt", "log2"],
}
N_ITER_SEARCH = 20
CV_FOLDS = 3

logger = setup_logger("train")


# -----
# Loading data function
def load_prepared_data(prep_dir: Path) -> pd.DataFrame:
    """
    Load the prepared dataset for modeling.

    Parameters:
    ---
    prep_dir: Path
        Directory containing the prepared dataset (grid_model.csv)

    Returns:
    ---
    pd.DataFrame
        DataFrame with lag features and target variable.
    """
    logger.info("Loading prepared dataset...")
    grid = pd.read_csv(prep_dir / GRID_MODEL_PREP)
    logger.info("Prepared dataset loaded: %s records", f"{len(grid):,}")
    return grid


# -----
# Splitting data function

def split_data(grid_model, month_train=MONTH_TRAIN):
    train_grid = grid_model[grid_model["date_block_num"] <= month_train].copy()

    max_month = grid_model["date_block_num"].max()
    val_grid = grid_model[grid_model["date_block_num"] == max_month].copy()

    if val_grid.empty:
        logger.warning("Validation set is empty. Using fallback sample.")
        val_grid = grid_model.sort_values("date_block_num").tail(1000)

    logger.info(f"Train size: {len(train_grid)}")
    logger.info(f"Validation size: {len(val_grid)} (month {max_month})")

    return train_grid, val_grid

def features_and_target(
    grid: pd.DataFrame,
    features: list[str] | None = None,
    clip: float = CLIP,
) -> tuple[pd.DataFrame, pd.Series]:
    """
    Separate features and target variable, applying clipping to the target.

    Parameters:
    ---
    grid: pd.DataFrame
        Subset of the prepared dataset containing lag features and target variable.
    features: list[str] | None
        List of feature column names (default: FEATURE_LAGS).
    clip: float
        Maximum value to clip the target variable to prevent extreme values.

    Returns:
    ---
    tuple[pd.DataFrame, pd.Series]
        (features_matrix, target)
    """
    if features is None:
        features = FEATURE_LAGS

    features_matrix = grid[features]
    target = grid[TARGET_COL].clip(0, clip)
    return features_matrix, target


# -----
# Hyperparameter optimization function
def optimize_hyperparameters(
    features_train: pd.DataFrame,
    target_train: pd.Series,
    param_distributions: dict | None = None,
    n_iter: int = N_ITER_SEARCH,
    cv: int = CV_FOLDS,
    random_seed: int = RANDOM_SEED,
) -> dict:
    """
    Search for the best hyperparameters using RandomizedSearchCV.

    Parameters:
    ---
    features_train: pd.DataFrame
        Training features (lag columns).
    target_train: pd.Series
        Training target variable.
    param_distributions: dict | None
        Hyperparameter search space (default: PARAM_DISTRIBUTIONS).
    n_iter: int
        Number of parameter combinations to try (default: 20).
    cv: int
        Number of cross-validation folds (default: 3).
    random_seed: int
        Random seed for reproducibility.

    Returns:
    ---
    dict
        Best hyperparameters found by the search.
    """
    if param_distributions is None:
        param_distributions = PARAM_DISTRIBUTIONS

    logger.info(
        "Starting RandomizedSearchCV — %s iterations, %s-fold CV...", n_iter, cv
    )
    base_model = RandomForestRegressor(random_state=random_seed, n_jobs=-1)
    search = RandomizedSearchCV(
        estimator=base_model,
        param_distributions=param_distributions,
        n_iter=n_iter,
        cv=cv,
        scoring="neg_root_mean_squared_error",
        random_state=random_seed,
        n_jobs=-1,
        verbose=0,
    )
    search.fit(features_train, target_train)

    best_params = search.best_params_
    best_cv_rmse = -search.best_score_
    logger.info("Best hyperparameters found: %s", best_params)
    logger.info("Best CV RMSE: %.4f", best_cv_rmse)
    return best_params


# -----
# Training and evaluation functions
def train_model(
    features_train: pd.DataFrame,
    target_train: pd.Series,
    n_estimators: int = N_ESTIMATORS,
    max_depth: int = MAX_DEPTH,
    random_seed: int = RANDOM_SEED,
) -> RandomForestRegressor:
    """
    Train a Random Forest regressor with the given hyperparameters.

    Parameters:
    ---
    features_train: pd.DataFrame
        Training features (lag columns).
    target_train: pd.Series
        Training target variable.
    n_estimators: int
        Number of trees in the Random Forest.
    max_depth: int
        Maximum depth of each tree.
    random_seed: int
        Random seed for reproducibility.

    Returns:
    ---
    RandomForestRegressor
        Trained model.
    """
    logger.info(
        "Training Random Forest — n_estimators=%s, max_depth=%s, random_state=%s",
        n_estimators,
        max_depth,
        random_seed,
    )
    model = RandomForestRegressor(
        n_estimators=n_estimators,
        max_depth=max_depth,
        random_state=random_seed,
        n_jobs=-1,
    )
    model.fit(features_train, target_train)
    logger.info("Model training complete")
    return model


def calculate_rmse(
    model: RandomForestRegressor,
    features_val: pd.DataFrame,
    target_val: pd.Series,
) -> float:
    """
    Calculate the RMSE of the model on the validation set.

    Parameters:
    ---
    model: RandomForestRegressor
        Trained model.
    features_val: pd.DataFrame
        Validation features.
    target_val: pd.Series
        Validation target variable.

    Returns:
    ---
    float
        RMSE value.
    """
    predictions = model.predict(features_val)
    rmse = float(np.sqrt(mean_squared_error(target_val, predictions)))
    logger.info("Validation RMSE (Random Forest): %.4f", rmse)
    return rmse


# -----
# Saving model function
def save_model(model: RandomForestRegressor, artifacts_dir: Path) -> Path:
    """
    Save the trained model to the artifacts directory.

    Parameters:
    ---
    model: RandomForestRegressor
        Trained model to be saved.
    artifacts_dir: Path
        Directory where the model will be saved.

    Returns:
    ---
    Path
        Path to the saved model file.
    """
    artifacts_dir.mkdir(parents=True, exist_ok=True)
    model_path = artifacts_dir / MODEL_PATH
    joblib.dump(model, model_path)
    logger.info("Model saved: %s", MODEL_PATH)
    return model_path


# -----
# Main function
def train_and_evaluate(
    prep_dir: Path,
    artifacts_dir: Path,
    n_estimators: int = N_ESTIMATORS,
    max_depth: int = MAX_DEPTH,
    random_seed: int = RANDOM_SEED,
    use_random_search: bool = False,
) -> float:
    """
    Execute the full training and evaluation pipeline:
    1. Load the prepared dataset.
    2. Split into training and validation sets.
    3. Optionally optimize hyperparameters with RandomizedSearchCV.
    4. Train the Random Forest model with best hyperparameters.
    5. Calculate RMSE on the validation set.
    6. Save the trained model.

    Parameters:
    ---
    prep_dir: Path
        Directory containing the prepared dataset (grid_model.csv).
    artifacts_dir: Path
        Directory where the trained model will be saved.
    n_estimators: int
        Number of trees (used if use_random_search=False).
    max_depth: int
        Max tree depth (used if use_random_search=False).
    random_seed: int
        Random seed for reproducibility.
    use_random_search: bool
        Whether to run RandomizedSearchCV before training (default: True).

    Returns:
    ---
    float
        RMSE value on the validation set.
    """
    logger.info("=" * 50)
    logger.info("Starting training pipeline (train.py)")
    logger.info("=" * 50)
    start_time = time.time()

    try:
        grid = load_prepared_data(prep_dir)
        train_grid, val_grid = split_data(grid)

        features_train, target_train = features_and_target(train_grid)
        features_val, target_val = features_and_target(val_grid)

        if use_random_search:
            best_params = optimize_hyperparameters(
                features_train, target_train, random_seed=random_seed
            )
            n_estimators = best_params.get("n_estimators", n_estimators)
            max_depth = best_params.get("max_depth", max_depth)

        model = train_model(features_train, target_train, n_estimators, max_depth, random_seed)
        if len(features_val) == 0:
            logger.warning("Skipping RMSE calculation because validation set is empty.")
            rmse = float("nan")
        else:
            rmse = calculate_rmse(model, features_val, target_val)

        save_model(model, artifacts_dir)

    except FileNotFoundError as e:
        logger.error("Input file not found: %s", e)
        raise
    except Exception as e:
        logger.error("Unexpected error during training: %s", e)
        raise

    duration = time.time() - start_time
    logger.info("Training pipeline completed in %.2f seconds", duration)
    logger.info("=" * 50)
    return rmse


# -----
# Entry point
if __name__ == "__main__":
    BASE_PATH = Path(__file__).resolve().parent.parent
    train_and_evaluate(
        prep_dir=BASE_PATH / "data" / "prep",
        artifacts_dir=BASE_PATH / "artifacts",
    )
