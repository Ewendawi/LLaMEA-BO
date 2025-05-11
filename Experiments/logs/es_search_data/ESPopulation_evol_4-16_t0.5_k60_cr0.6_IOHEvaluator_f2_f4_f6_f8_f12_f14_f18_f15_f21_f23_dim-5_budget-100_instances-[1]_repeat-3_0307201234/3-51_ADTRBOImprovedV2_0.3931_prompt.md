You are a highly skilled computer scientist in the field of natural computing. Your task is to design novel metaheuristic algorithms to solve black box optimization problems


The optimization algorithm should handle a wide range of tasks, which is evaluated on the BBOB test suite of 24 noiseless functions. Your task is to write the optimization algorithm in Python code. The code should contain an `__init__(self, budget, dim)` function and the function `__call__(self, func)`, which should optimize the black box function `func` using `self.budget` function evaluations.
The func() can only be called as many times as the budget allows, not more. Each of the optimization functions has a search space between -5.0 (lower bound) and 5.0 (upper bound). The dimensionality can be varied.
As an expert of numpy, scipy, scikit-learn, torch, gpytorch, you are allowed to use these libraries. Do not use any other libraries unless they cannot be replaced by the above libraries.  Do not remove the comments from the code.
Name the class based on the characteristics of the algorithm with a template '<characteristics>BO'.

Give an excellent, novel and computationally efficient Bayesian Optimization algorithm to solve this task, give it a concise but comprehensive key-word-style description with the main ideas and justify your decision about the algorithm.

The current population of algorithms already evaluated(name, score, runtime and description):
- HybridTrustRegionBO: 0.1829, 708.32 seconds, **HybridTrustRegionBO (HTRBO):** This algorithm combines the strengths of EATRBO and ATRDGBO by using an adaptive trust region, a hybrid surrogate model (Gaussian Process and Gradient Boosting), and an enhanced acquisition function. It leverages the uncertainty quantification of Gaussian Processes and the speed of Gradient Boosting. The acquisition function balances exploration and exploitation with a diversity component and dynamically adjusts the trust region and exploration factor.


- EATRBO_V2: 0.1824, 436.45 seconds, **EATRBO-V2: Enhanced Adaptive Trust Region Bayesian Optimization with Volume-Aware Exploration.** This algorithm refines EATRBO by incorporating a volume-aware exploration strategy into the acquisition function. It maintains the adaptive trust region and batch size mechanisms of EATRBO, while enhancing the exploration-exploitation balance by considering the volume of the search space that is far from existing data points. This encourages exploration in potentially promising, yet unexplored regions.


- ADTRBOImproved: 0.1808, 715.91 seconds, **ADTRBO-Improved:** This algorithm refines the Adaptive Diversity-Enhanced Trust Region Bayesian Optimization (ADTRBO) by incorporating enhancements to the acquisition function, trust region adaptation, and exploration-exploitation balance. Specifically, it introduces a dynamic diversity weight, a more robust trust region adjustment based on the uncertainty of the GP model, and a modified exploration factor that considers both the remaining budget and the model uncertainty. These changes aim to improve the algorithm's ability to escape local optima, adapt to the function landscape, and converge more efficiently.


- ATRDDEBO: 0.1797, 827.89 seconds, **Adaptive Trust Region with Dynamic Diversity and Exploration Bayesian Optimization (ATRDDEBO):** This algorithm combines the strengths of ADTRBO and EATRBO while introducing dynamic adjustments to both the diversity weight and exploration factor. It leverages an adaptive trust region to balance exploration and exploitation, incorporates a diversity term in the acquisition function to encourage exploration in less-visited regions, and dynamically adjusts the exploration factor based on both the remaining budget and the model's uncertainty. The diversity weight is also dynamically adjusted based on the distribution of samples within the trust region, promoting a more even spread of exploration. It uses a Gaussian Process with a Matern kernel for modeling the objective function and includes NaN handling.




The selected solution to update is:
**ADTRBO-Improved:** This algorithm refines the Adaptive Diversity-Enhanced Trust Region Bayesian Optimization (ADTRBO) by incorporating enhancements to the acquisition function, trust region adaptation, and exploration-exploitation balance. Specifically, it introduces a dynamic diversity weight, a more robust trust region adjustment based on the uncertainty of the GP model, and a modified exploration factor that considers both the remaining budget and the model uncertainty. These changes aim to improve the algorithm's ability to escape local optima, adapt to the function landscape, and converge more efficiently.


With code:
```python
from collections.abc import Callable
from scipy.stats import qmc
from scipy.stats import norm
import numpy as np
from sklearn.gaussian_process import GaussianProcessRegressor
from sklearn.gaussian_process.kernels import Matern, ConstantKernel
from scipy.optimize import minimize
from sklearn.cluster import KMeans
from sklearn.metrics import pairwise_distances
from sklearn.impute import SimpleImputer

class ADTRBOImproved:
    def __init__(self, budget:int, dim:int):
        self.budget = budget
        self.dim = dim
        # bounds has shape (2,<dimension>), bounds[0]: lower bound, bounds[1]: upper bound
        self.bounds = np.array([[-5.0]*dim, [5.0]*dim])
        # X has shape (n_points, n_dims), y has shape (n_points, 1)
        self.X: np.ndarray = None
        self.y: np.ndarray = None
        self.n_evals = 0 # the number of function evaluations
        self.n_init = 2 * self.dim # Initial samples
        self.trust_region_size = 2.0  # Initial trust region size
        self.exploration_factor = 2.0 # Initial exploration factor
        self.diversity_weight = 0.1 # Initial weight for the diversity term in the acquisition function
        self.imputer = SimpleImputer(strategy='mean') # Imputer for handling NaN values

        # Do not add any other arguments without a default value

    def _sample_points(self, n_points):
        # sample points
        # return array of shape (n_points, n_dims)
        sampler = qmc.Sobol(d=self.dim, scramble=False)
        samples = sampler.random(n=n_points)
        return qmc.scale(samples, self.bounds[0], self.bounds[1])

    def _fit_model(self, X, y):
        # Fit and tune surrogate model 
        # return the model
        # Do not change the function signature
        # Impute NaN values
        if np.isnan(X).any():
            X = self.imputer.fit_transform(X)
        kernel = ConstantKernel(1.0, constant_value_bounds="fixed") * Matern(length_scale=1.0, nu=2.5)
        model = GaussianProcessRegressor(kernel=kernel, n_restarts_optimizer=5, alpha=1e-5)
        model.fit(X, y)
        return model

    def _acquisition_function(self, X):
        # Implement acquisition function 
        # calculate the acquisition function value for each point in X
        # return array of shape (n_points, 1)
        if np.isnan(X).any():
            X = self.imputer.transform(X)
        mu, sigma = self.model.predict(X, return_std=True)
        mu = mu.reshape(-1, 1)
        sigma = sigma.reshape(-1, 1)

        # Lower Confidence Bound
        lcb = mu - self.exploration_factor * sigma

        # Diversity term: encourage exploration in less-visited regions
        if self.X is not None and len(self.X) > 5:
            kmeans = KMeans(n_clusters=min(5, len(self.X), 10), random_state=0, n_init = 'auto').fit(self.X)
            clusters = kmeans.predict(X)
            distances = np.array([np.min(pairwise_distances(x.reshape(1, -1), self.X[kmeans.labels_ == cluster].reshape(-1, self.dim))) if np.sum(kmeans.labels_ == cluster) > 0 else 0 for x, cluster in zip(X, clusters)])
            diversity = distances.reshape(-1, 1)
        else:
            diversity = np.zeros_like(lcb)

        # Dynamic diversity weight
        diversity_weight = self.diversity_weight * np.mean(sigma)
        return lcb + diversity_weight * diversity

    def _select_next_points(self, batch_size):
        # Select the next points to evaluate
        # Use a selection strategy to optimize/leverage the acquisition function 
        # The selection strategy can be any heuristic/evolutionary/mathematical/hybrid methods.
        # Your decision should consider the problem characteristics, acquisition function, and the computational efficiency.
        # return array of shape (batch_size, n_dims)
        
        # Optimize the acquisition function within the trust region using L-BFGS-B
        best_idx = np.argmin(self.y)
        best_x = self.X[best_idx]
        
        x_starts = best_x + np.random.normal(0, 0.1, size=(batch_size, self.dim))
        x_starts = np.clip(x_starts, self.bounds[0], self.bounds[1])

        candidates = []
        values = []
        for x_start in x_starts:
            # Define trust region bounds
            lower_bound = np.maximum(x_start - self.trust_region_size / 2, self.bounds[0])
            upper_bound = np.minimum(x_start + self.trust_region_size / 2, self.bounds[1])
            
            res = minimize(lambda x: self._acquisition_function(x.reshape(1, -1)),
                           x_start,
                           bounds=np.array([lower_bound, upper_bound]).T,
                           method="L-BFGS-B")
            candidates.append(res.x)
            values.append(res.fun)
        
        return np.array(candidates)

    def _evaluate_points(self, func, X):
        # Evaluate the points in X
        # func: takes array of shape (n_dims,) and returns np.float64.
        # return array of shape (n_points, 1)
        y = np.array([func(x) for x in X]).reshape(-1, 1)
        self.n_evals += len(X)
        return y
    
    def _update_eval_points(self, new_X, new_y):
        # Update self.X and self.y
        # Do not change the function signature
        if self.X is None:
            self.X = new_X
            self.y = new_y
        else:
            self.X = np.vstack((self.X, new_X))
            self.y = np.vstack((self.y, new_y))
    
    def __call__(self, func:Callable[[np.ndarray], np.float64]) -> tuple[np.float64, np.array]:
        # Main minimize optimization loop
        # func: takes array of shape (n_dims,) and returns np.float64. 
        # !!! Do not call func directly. Use _evaluate_points instead and be aware of the budget when calling it. !!!
        # Return a tuple (best_y, best_x)
        
        # Initial sampling
        X_init = self._sample_points(self.n_init)
        y_init = self._evaluate_points(func, X_init)
        self._update_eval_points(X_init, y_init)
        
        self.model = self._fit_model(self.X, self.y)
        
        while self.n_evals < self.budget:
            # Optimization
            # Batch size adjustment
            batch_size = min(int(self.trust_region_size), self.budget - self.n_evals)
            batch_size = max(1, batch_size) # Ensure batch_size is at least 1
            
            X_next = self._select_next_points(batch_size)
            y_next = self._evaluate_points(func, X_next)
            self._update_eval_points(X_next, y_next)

            # Adaptive trust region adjustment
            y_pred, sigma = self.model.predict(X_next, return_std=True)
            y_pred = y_pred.reshape(-1, 1)
            
            # Agreement between prediction and actual value, normalized by uncertainty
            agreement = np.abs(y_pred - y_next) / sigma.reshape(-1, 1)
            
            if np.mean(agreement) < 1.0:
                self.trust_region_size *= 1.1  # Increase trust region if model is accurate
            else:
                self.trust_region_size *= 0.9  # Decrease trust region if model is inaccurate
            
            self.trust_region_size = np.clip(self.trust_region_size, 0.1, 5.0) # Clip trust region size

            # Dynamic exploration factor adjustment
            self.exploration_factor = 1.0 + (self.budget - self.n_evals) / self.budget + np.mean(sigma) # Reduce exploration over time
            
            self.model = self._fit_model(self.X, self.y) # Refit the model with new data
            
        best_idx = np.argmin(self.y)
        best_y = self.y[best_idx][0]
        best_x = self.X[best_idx]

        return best_y, best_x

```
The algorithm ADTRBOImproved got an average Area over the convergence curve (AOCC, 1.0 is the best) score of 0.1808 with standard deviation 0.1009.

took 715.91 seconds to run.

Refine the strategy of the selected solution to improve it.



Give the response in the format:
# Description 
<description>
# Justification 
<justification for the key components of the algorithm or the changes made>
# Code 
<code>

