# --- cell 1 ---
import numpy as np
from sklearn.linear_model import Ridge, Lasso, ElasticNet, RidgeCV, LassoCV
# You can import any sklearn module you need

def train(X_train, y_train, X_val, y_val):
    """
    Train a regression model that generalizes well despite having
    MORE features than training samples (many are noise or redundant).
    
    WARNING: LinearRegression() WILL overfit here.
    - LinearRegression(): Train R² ≈ 1.0, Val R² ≈ -5.0
    - You need regularization to pass!
    
    Args:
        X_train: numpy array of shape (n_samples, n_features) -- standardized
                 (~250 samples, ~264 features -- more features than samples!)
        y_train: numpy array of shape (n_samples,) -- target values
        X_val:   numpy array of shape (n_val, n_features) -- standardized
        y_val:   numpy array of shape (n_val,) -- validation targets
    
    Returns:
        predict: callable that takes X (n, n_features) and returns y_pred (n,)
    """
    # TODO: fit a regularized model and return a predict function
    # 
    # Ideas:
    #   - Ridge(alpha=??) or RidgeCV (auto-tunes alpha)
    #   - Lasso(alpha=??) or LassoCV (auto-tunes + feature selection)
    #   - ElasticNet (combines L1 + L2)
    #   - SelectKBest + Ridge pipeline
    #   - Any sklearn approach that handles overfitting!
    #
    # Plain LinearRegression() will NOT work here.
    alphas = np.logspace(-3, 4, 50)
    l1_ratios = [0.1, 0.5, 0.9, 1.0]
    
    best_r2 = -np.inf
    best_model = None
    
    for l1_ratio in l1_ratios:
        for alpha in alphas:
            # fit_intercept=True is default in scikit-learn, solving the centering issue
            model = ElasticNet(alpha=alpha, l1_ratio=l1_ratio, max_iter=5000, tol=1e-3)
            model.fit(X_train, y_train)
            
            # Evaluate directly on the provided validation set
            r2 = model.score(X_val, y_val)
            
            if r2 > best_r2:
                best_r2 = r2
                best_model = model
                
    # Fallback just in case
    if best_model is None:
        best_model = ElasticNet(alpha=1.0, l1_ratio=0.5).fit(X_train, y_train)

    # Safely cap predictions to the training distribution bounds
    y_min, y_max = np.min(y_train), np.max(y_train)
    
    def predict(X):
        # 1. Generate predictions using the best tuned ElasticNet model
        preds = best_model.predict(X)
        
        # 2. Clip predictions to prevent infinite errors if a test sample's 
        #    polynomial features extrapolate wildly out of bounds
        return np.clip(preds, y_min, y_max)

    return predict