---
title: Xgboost Params
---


## Summary of the Best XGBoost Parameters

XGBoost offers a wide array of parameters, which can be grouped into three main categories: general parameters, booster parameters, and learning task parameters. Below is a structured summary of the most important and commonly tuned parameters for optimal model performance.

---

**General Parameters**

- **booster**: Type of model to run at each iteration. Options are `gbtree` (default), `gblinear`, or `dart`.
- **device**: Specify computation device (`cpu` or `cuda` for GPU acceleration).
- **verbosity**: Controls the amount of messages printed. Range: 0 (silent) to 3 (debug).
- **nthread**: Number of parallel threads used for running XGBoost.

---

**Tree Booster Parameters (for `gbtree` and `dart`)**


| Parameter | Default | Description | Typical Range |
| :-- | :-- | :-- | :-- |
| eta (learning_rate) | 0.3 | Step size shrinkage to prevent overfitting. Lower values make learning slower but safer. | [0.01, 0.3] |
| gamma | 0 | Minimum loss reduction required to make a split. Higher values make the algorithm more conservative. | [0, ∞) |
| max_depth | 6 | Maximum depth of a tree. Larger values increase model complexity and risk of overfitting. |  |
| min_child_weight | 1 | Minimum sum of instance weight (hessian) in a child. Higher values make the algorithm more conservative. |  |
| subsample | 1 | Fraction of training samples used per tree. Reduces overfitting. | (0.5, 1] |
| colsample_bytree | 1 | Fraction of features used per tree. | (0.5, 1] |
| colsample_bylevel | 1 | Fraction of features used per tree level. | (0.5, 1] |
| colsample_bynode | 1 | Fraction of features used per split. | (0.5, 1] |
| lambda (reg_lambda) | 1 | L2 regularization term on weights. | [0, ∞) |
| alpha (reg_alpha) | 0 | L1 regularization term on weights. | [0, ∞) |
| tree_method | auto | Algorithm for constructing trees: `auto`, `exact`, `approx`, `hist`, `gpu_hist`. |  |
| scale_pos_weight | 1 | Controls balance of positive/negative weights for unbalanced classification. | [1, \#neg/\#pos] |


---

**Learning Task Parameters**

- **objective**: Specifies the learning task (e.g., `reg:squarederror` for regression, `binary:logistic` for binary classification, `multi:softmax` for multiclass).
- **eval_metric**: Evaluation metric for validation data (e.g., `rmse`, `logloss`, `auc`).
- **seed**: Random seed for reproducibility.

---

**Specialized Parameters**

- **DART Booster**: Parameters like `rate_drop`, `skip_drop`, and `sample_type` control dropout behavior in the DART booster.
- **gblinear Booster**: Parameters like `updater`, `feature_selector`, and `top_k` control linear model fitting.
- **Categorical Features**: Parameters such as `max_cat_to_onehot` and `max_cat_threshold` manage categorical data handling.

---

**Parameter Tuning Tips**

- Start with default values and tune the following for best results:
    - `max_depth`, `min_child_weight` (model complexity)
    - `subsample`, `colsample_bytree` (overfitting control)
    - `eta` (learning rate; lower values often require more boosting rounds)
    - `gamma`, `lambda`, `alpha` (regularization)
- For imbalanced datasets, adjust `scale_pos_weight`.
- Use `tree_method=hist` or `gpu_hist` for large datasets or GPU acceleration.

---





## Example of Good XGBoost Parameters

Your provided parameter set is well-constructed for advanced regression tasks, especially with large datasets or when you want to control tree complexity using the number of leaves rather than depth. Here’s an annotated example, with explanations and minor suggestions for further tuning based on best practices and XGBoost documentation[^1][^2][^3][^4][^5]:

```javascript
var xgbParams = {
  verbosity: 0,                      // Silent logging
  objective: 'reg:squarederror',     // Standard for regression
  nthread: 4,                        // Use 4 CPU threads
  colsample_bytree: 0.85,            // Use 85% of features per tree
  colsample_bylevel: 0.85,           // Use 85% of features per tree level
  alpha: 0.05,                       // L1 regularization (encourages sparsity)
  lambda: 1.2,                       // L2 regularization (prevents overfitting)
  early_stopping_rounds: 75,         // Stop if no improvement after 75 rounds
  seed: 42,                          // For reproducibility
  nrounds: 2500,                     // Max number of boosting rounds
  tree_method: 'approx',             // Fast approximate tree building
  grow_policy: 'lossguide',          // Grow trees by loss reduction, not depth
  max_depth: 0,                      // Unlimited depth (used with lossguide)
  max_leaves: 64,                    // Limit number of leaves per tree
  eta: 0.25,                         // Learning rate (lower for more conservative learning)
  gamma: 0,                          // Minimum loss reduction for split (0 = no constraint)
  min_child_weight: 1,               // Minimum sum hessian in a child (default, can increase for more conservative splits)
  subsample: 0.95                    // Use 95% of data per tree (helps prevent overfitting)
};
```


### Why These Parameters Work Well

- **colsample_bytree/colsample_bylevel**: Subsampling features helps reduce overfitting, especially in high-dimensional data[^1][^2].
- **alpha/lambda**: Regularization terms are crucial for controlling model complexity and preventing overfitting, especially with many trees or deep trees[^1][^2][^4].
- **tree_method: 'approx' \& grow_policy: 'lossguide'**: This combination enables efficient training on large datasets, and `lossguide` allows you to control complexity via `max_leaves` instead of `max_depth`[^1][^3].
- **max_leaves**: Directly limits the number of terminal nodes, which is effective for large or sparse datasets[^1][^3].
- **eta**: A moderate learning rate of 0.25 is a reasonable starting point; you can lower it (e.g., 0.05–0.1) for more conservative learning and increase `nrounds` if needed[^5].
- **subsample**: High subsampling (0.95) allows nearly all data to be used but still adds some randomness for regularization[^1][^2].
- **early_stopping_rounds**: Prevents unnecessary training if validation error stops improving[^1][^2].


### Additional Notes

- If your dataset is very large or you have access to a GPU, consider using `tree_method: 'hist'` or `'gpu_hist'` for further speedup[^1][^2].
- For imbalanced regression or classification, you might also want to tune `scale_pos_weight`[^1][^2].
- For time series or weather-energy modeling, these parameters are a strong starting point, but always validate with cross-validation or a hold-out set[^12][^13].


### Typical Ranges for Key Parameters

| Parameter | Typical Range |
| :-- | :-- |
| eta | 0.01 – 0.3 |
| max_leaves | 16 – 256 |
| colsample_bytree | 0.5 – 1.0 |
| subsample | 0.5 – 1.0 |
| alpha/lambda | 0 – 10 |
| min_child_weight | 1 – 10 |

### References to Documentation

[^2]: https://xgboost.readthedocs.io/en/stable/parameter.html

[^3]: https://xgboosting.com/configure-xgboost-grow_policy-parameter/

[^4]: https://datascience.stackexchange.com/questions/108233/recommendations-for-tuning-xgboost-hyperparams

[^5]: https://www.machinelearningmastery.com/xgboost-for-regression/

[^6]: https://www.kaggle.com/code/prashant111/a-guide-on-xgboost-hyperparameters-tuning

[^7]: https://stackoverflow.com/questions/69786993/tuning-xgboost-hyperparameters-with-randomizedsearchcv

[^8]: https://xgboost.readthedocs.io/en/release_0.90/parameter.html

[^9]: https://www.machinelearningmastery.com/xgboost-for-time-series-forecasting/

[^10]: https://xgboost.readthedocs.io/en/latest/parameter.html

[^11]: https://stackoverflow.com/questions/44058786/specifying-tree-method-param-for-xgboost-in-python


