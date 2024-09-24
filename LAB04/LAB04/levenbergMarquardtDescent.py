# Optimization for Engineers - Dr.Johannes Hild
# Levenberg-Marquardt descent

# Purpose: Find pmin to satisfy norm(jacobian_R.T @ R(pmin))<=eps

# Input Definition:
# R: error vector class with methods .residual() and .jacobian()
# p0: column vector in R**n (parameter point), starting point.
# eps: positive value, tolerance for termination. Default value: 1.0e-4.
# alpha0: positive value, starting value for damping. Default value: 1.0e-3.
# beta: positive value bigger than 1, scaling factor for alpha. Default value: 100.
# verbose: bool, if set to true, verbose information is displayed.

# Output Definition:
# pmin: column vector in R**n (parameter point)

# Required files:
# d = PrecCGSolver(A,b) from PrecCGSolver.py

# Test cases:
# p0 = np.array([[180],[0]])
# myObjective =  simpleValleyObjective(p0)
# xk = np.array([[0, 0], [1, 2]])
# fk = np.array([[2, 3]])
# myErrorVector = leastSquaresModel(myObjective, xk, fk)
# eps = 1.0e-4
# alpha0 = 1.0e-3
# beta = 100
# pmin = levenbergMarquardtDescent(myErrorVector, p0, eps, alpha0, beta, 1)
# should return pmin close to [[1], [1]]

import numpy as np
import PrecCGSolver as PCG

def matrnr():
    # set your matriculation number here
    matrnr = 23353068
    return matrnr

def levenbergMarquardtDescent(R, p0: np.array, eps=1.0e-4, alpha0=1.0e-3, beta=100, verbose=0):
    if eps <= 0:
        raise TypeError('range of eps is wrong!')

    if alpha0 <= 0:
        raise TypeError('range of alpha0 is wrong!')

    if beta <= 1:
        raise TypeError('range of beta is wrong!')

    if verbose:
        print('Start levenbergMarquardtDescent...')

    countIter = 0
    p = p0
    alpha = alpha0

# INCOMPLETE CODE STARTS

    while True:
        J = R.jacobian(p)
        R_p = R.residual(p)
        gradp = J.T @ R_p
        
        if np.linalg.norm(gradp) <= eps:
            break

        A = J.T @ J + alpha * np.eye(J.shape[1])
        b = -gradp
        d = PCG.PrecCGSolver(A, b, delta=1.0e-6, verbose=0)

        p_new = p + d.reshape(p.shape)

        R_p_new = R.residual(p_new)
        if 0.5 * np.dot(R_p_new.T, R_p_new) < 0.5 * np.dot(R_p.T, R_p):
            
            p = p_new
            alpha = alpha0
        else:

            alpha *= beta

        countIter += 1

    # INCOMPLETE CODE ENDS

    if verbose:
        print('levenbergMarquardtDescent terminated after', countIter, 'steps with norm of gradient =', np.linalg.norm(gradp))

    return p
'''
from simpleValleyObjective import simpleValleyObjective
from leastSquaresModel import leastSquaresModel

# Test cases:
p0 = np.array([[180],[0]])
myObjective =  simpleValleyObjective(p0)
xk = np.array([[0, 0], [1, 2]])
fk = np.array([[2, 3]])
myErrorVector = leastSquaresModel(myObjective, xk, fk)
eps = 1.0e-4
alpha0 = 1.0e-3
beta = 100
pmin = levenbergMarquardtDescent(myErrorVector, p0, eps, alpha0, beta, 1)
#should return pmin close to [[1], [1]]
# Run the Levenberg-Marquardt Descent algorithm
optimized_p = levenbergMarquardtDescent(myErrorVector, p0, verbose=1)

print("Optimized Parameters:", optimized_p)
'''