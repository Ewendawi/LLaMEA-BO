# Description
**QuantileRegretBO (QRBO):** This algorithm focuses on minimizing the quantile of the observed regret. It uses a Gaussian Process (GP) to model the objective function and estimates the distribution of the regret. The acquisition function is based on the Conditional Value at Risk (CVaR) of the regret, which is optimized to select the next points. This approach is robust to noisy evaluations and outliers, as it focuses on the tail of the regret distribution. The algorithm also incorporates a dynamic adjustment of the quantile level based on the optimization progress, adapting the risk aversion during the search.

# Justification
This algorithm diverges from the previous ones in several key aspects:

1.  **Focus on Quantile Regret:** Instead of directly minimizing the objective function or using Expected Improvement, it minimizes the quantile of the regret. This makes it more robust to noise and outliers.
2.  **CVaR Acquisition:** The use of Conditional Value at Risk (CVaR) as the acquisition function allows for risk-averse or risk-seeking behavior, depending on the quantile level.
3.  **Dynamic Quantile Adjustment:** Adapting the quantile level during the optimization process allows the algorithm to balance exploration and exploitation more effectively. Initially, a higher quantile (more risk-averse) encourages exploration, while later, a lower quantile (more risk-seeking) focuses on exploitation.
4.  **No Sparse GP**: The sparse GP from AdaptiveVarianceBO caused a `TypeError`. The `sample_weight` argument is not available in the `GaussianProcessRegressor.fit()` method from scikit-learn.
5.  **No Gradient Information**: GradientEnhancedBO requires gradient information, which is not available in the black-box setting.
6.  **No Trust Region**: TrustRegionBO focuses on local search, which might not be effective in high-dimensional spaces.
7.  **No Evolutionary Algorithm**: BayesianEvolutionaryBO had a `ValueError` because the mutation constant was out of range.

# Code
```python
from collections.abc import Callable
from scipy.stats import qmc #If you are using QMC sampling, qmc from scipy is encouraged. Remove this line if you have better alternatives.
from scipy.stats import norm
import numpy as np
from sklearn.gaussian_process import GaussianProcessRegressor
from sklearn.gaussian_process.kernels import RBF, ConstantKernel
from scipy.optimize import minimize

class QuantileRegretBO:
    def __init__(self, budget:int, dim:int):
        self.budget = budget
        self.dim = dim
        # bounds has shape (2,<dimension>), bounds[0]: lower bound, bounds[1]: upper bound
        self.bounds = np.array([[-5.0]*dim, [5.0]*dim])
        # X has shape (n_points, n_dims), y has shape (n_points, 1)
        self.X: np.ndarray = None
        self.y: np.ndarray = None
        self.n_evals = 0 # the number of function evaluations
        self.n_init = 2 * dim
        self.gp = None
        self.quantile_level = 0.9 # Initial quantile level for CVaR
        self.quantile_decay = 0.95 # Decay factor for quantile level
        self.min_quantile_level = 0.5 # Minimum quantile level
        self.best_y = np.inf
        self.best_x = None

        # Do not add any other arguments without a default value

    def _sample_points(self, n_points):
        # sample points
        # return array of shape (n_points, n_dims)
        sampler = qmc.LatinHypercube(d=self.dim)
        sample = sampler.random(n=n_points)
        return qmc.scale(sample, self.bounds[0], self.bounds[1])

    def _fit_model(self, X, y):
        # Fit and tune surrogate model 
        # return the model
        # Do not change the function signature
        kernel = ConstantKernel(1.0, constant_value_bounds="fixed") * RBF(length_scale=1.0, length_scale_bounds="fixed")
        gp = GaussianProcessRegressor(kernel=kernel, n_restarts_optimizer=5, alpha=1e-6)
        gp.fit(X, y)
        return gp

    def _acquisition_function(self, X):
        # Implement acquisition function 
        # calculate the acquisition function value for each point in X
        # return array of shape (n_points, 1)
        if self.gp is None:
            return np.zeros((len(X), 1)) # Return zeros if the model is not fitted yet

        mu, sigma = self.gp.predict(X, return_std=True)
        
        # Calculate CVaR of the regret
        regret = mu - self.best_y
        alpha = self.quantile_level
        
        # CVaR approximation (using Gaussian quantiles)
        VaR = regret + sigma * norm.ppf(alpha)
        CVaR = regret - (sigma * norm.pdf(norm.ppf(alpha)) / (1 - alpha))

        # If alpha is close to 1, the above calculation can be unstable.
        # In this case, we can approximate CVaR with VaR.
        if alpha > 0.99:
            CVaR = VaR
            
        return CVaR.reshape(-1, 1)

    def _select_next_points(self, batch_size):
        # Select the next points to evaluate
        # Use a selection strategy to optimize/leverage the acquisition function 
        # The selection strategy can be any heuristic/evolutionary/mathematical/hybrid methods.
        # Your decision should consider the problem characteristics, acquisition function, and the computational efficiency.
        # return array of shape (batch_size, n_dims)

        # Optimize the acquisition function to find the next points
        x_tries = self._sample_points(batch_size * 10) # Generate more candidates
        acq_values = self._acquisition_function(x_tries)

        # Select the top batch_size points based on the acquisition function values
        indices = np.argsort(acq_values.flatten())[:batch_size] # changed from [::-1] to [:] since we want to minimize CVaR
        return x_tries[indices]

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
        
        # Update best observed solution
        best_index = np.argmin(self.y)
        if self.y[best_index, 0] < self.best_y:
            self.best_x = self.X[best_index]
            self.best_y = self.y[best_index, 0]

    def __call__(self, func:Callable[[np.ndarray], np.float64]) -> tuple[np.float64, np.array]:
        # Main minimize optimization loop
        # func: takes array of shape (n_dims,) and returns np.float64. 
        # !!! Do not call func directly. Use _evaluate_points instead and be aware of the budget when calling it. !!!
        # Return a tuple (best_y, best_x)
        
        # Initial exploration
        initial_X = self._sample_points(self.n_init)
        initial_y = self._evaluate_points(func, initial_X)
        self._update_eval_points(initial_X, initial_y)

        while self.n_evals < self.budget:
            # Optimization

            # Fit GP model
            self.gp = self._fit_model(self.X, self.y)

            # Select points by acquisition function
            batch_size = min(10, self.budget - self.n_evals)
            next_X = self._select_next_points(batch_size)
            next_y = self._evaluate_points(func, next_X)
            self._update_eval_points(next_X, next_y)
            
            # Decay quantile level
            self.quantile_level *= self.quantile_decay
            self.quantile_level = max(self.quantile_level, self.min_quantile_level)

        return self.best_y, self.best_x
```
## Feedback
 The algorithm QuantileRegretBO got an average Area over the convergence curve (AOCC, 1.0 is the best) score of 0.1578 with standard deviation 0.1029.

took 1.30 seconds to run.