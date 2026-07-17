import networkx as nx
import numpy as np
from scipy.optimize import minimize_scalar

def get_gravity_null_model_manual_iterative(G, pos_attr='pos', tol=0.01, max_iter=1000):
    """
    Inférence par maximisation de la vraisemblance (descente de coordonnées et optim scalaire)
    du modèle gravitaire / ERGM géométrique non dirigé.
    """
    nodes = list(G.nodes())
    n = len(nodes)
    adj = nx.to_numpy_array(G)
    degrees = np.sum(adj, axis=1)
    
    # Matrice de distance (N, N)
    pos_array = np.array([G.nodes[u][pos_attr] for u in nodes])
    if len(pos_array.shape) == 1 or (len(pos_array.shape) == 2 and pos_array.shape[1] == 1):
        # Cas 1D : Différence absolue directe
        dist_matrix = np.abs(pos_array[:, np.newaxis] - pos_array[np.newaxis, :])
    else:
        dist_matrix = np.linalg.norm(pos_array[:, np.newaxis] - pos_array[np.newaxis, :], axis=2)
    
    # Initialisation des paramètres
    alphas = np.zeros(n)
    beta = 1.0
    
    def total_log_likelihood_beta(b, current_alphas):
        """ Log-vraisemblance négative pour l'optimisation de beta """
        theta = current_alphas[:, np.newaxis] + current_alphas[np.newaxis, :] - b * dist_matrix
        log_q = np.logaddexp(0, theta)
        # Triangle supérieur (réseau non dirigé, pas de boucles)
        ll = np.sum(np.triu(adj * theta - log_q, k=1))
        return -ll

    for iteration in range(max_iter):
        
        # 1. Mise à jour séquentielle des alphas (Descente de coordonnées vectorisée)
        for _ in range(5):
            theta = alphas[:, np.newaxis] + alphas[np.newaxis, :] - beta * dist_matrix
            theta = np.clip(theta, -50, 50)  # Stabilité numérique
            
            P = 1 / (1 + np.exp(-theta))
            np.fill_diagonal(P, 0)
            
            f_x = np.sum(P, axis=1) - degrees
            f_prime = np.sum(P * (1 - P), axis=1) + 1e-5  # Approximation de la Hessienne
            
            step = f_x / f_prime
            alphas -= 0.5 * np.clip(step, -2.0, 2.0)
            
        # 2. Mise à jour de beta
        res_beta = minimize_scalar(
            total_log_likelihood_beta, 
            args=(alphas,), 
            bounds=(0, 20), 
            method='bounded'
        )
        beta = res_beta.x
        
        # Évaluation de la convergence
        theta = alphas[:, np.newaxis] + alphas[np.newaxis, :] - beta * dist_matrix
        current_P = 1 / (1 + np.exp(-theta))
        np.fill_diagonal(current_P, 0)
        
        predicted_degrees = np.sum(current_P, axis=1)
        mae_degrees = np.mean(np.abs(predicted_degrees - degrees))
        
        if iteration % 100 == 0:
            print(f"Iteration {iteration}: MAE = {mae_degrees:.6f}, Beta = {beta:.4f}")
        
        if mae_degrees < tol:
            break

    print(f"Modèle gravitaire inféré. MAE = {mae_degrees:.4f}, alpha moy = {np.mean(alphas):.4f}, beta = {beta:.4f}")  
    
    A_sum = len(G.edges())
    normalization_factor = 2 * A_sum / current_P.sum()
    print(f"Vérification : Null Model donne 2*E / P.sum = {normalization_factor:.4f}")
    
    return current_P, nodes

def get_dcsbm_null_model(A, com_labels):
    """
    Computes the theoretical null model matrix for a DC-SBM (Degree-Corrected Stochastic Block Model)
    from an adjacency matrix A and a vector of community labels.
    
    Exact analytical formulation preserving symmetry.
    """
    N = A.shape[0]
    degrees = np.sum(A, axis=1)
    total_volume = np.sum(degrees)
    
    if total_volume == 0:
        return np.zeros((N, N))
        
    # Identification and numbering of unique blocks from 0 to K-1
    unique_coms, inverse_coms = np.unique(com_labels, return_inverse=True)
    K = len(unique_coms)
    
    # 1. Inter-block edge matrix M (K, K) and block volumes kappa (K,)
    M = np.zeros((K, K))
    kappa = np.zeros(K)
    
    for r in range(K):
        mask_r = (inverse_coms == r)
        kappa[r] = np.sum(degrees[mask_r])
        for s in range(K):
            mask_s = (inverse_coms == s)
            # Sum of edges between block r and block s
            M[r, s] = np.sum(A[mask_r][:, mask_s])
            
    # 2. Compute normalized connection probabilities per block: Omega_rs
    # Avoids division by zero if a block is completely isolated
    with np.errstate(divide='ignore', invalid='ignore'):
        # Expected P(r, s) without individual degree correction
        Omega = M / (np.outer(kappa, kappa) + 1e-12)
        
    # 3. Matrix expansion and application of individual node degree correction
    # P_ij = k_i * k_j * Omega[com_i, com_j]
    # To vectorize cleanly, we extract rows and columns from the Omega matrix
    Omega_expanded = Omega[inverse_coms[:, None], inverse_coms]
    
    # Outer product of degrees: (N, 1) x (1, N) -> (N, N)
    P = np.outer(degrees, degrees) * Omega_expanded
    
    # Optional masking of self-loops if your original graph has none
    np.fill_diagonal(P, 0.0)
    
    return P