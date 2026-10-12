"""Forward Newton--GMRES on the tensor device, with a true-residual check.

Default JVPs differentiate the complete residual, including follower loads;
an optional factory supplies an assembled or reduced Jacobian action instead.
No CPU linear solve or differentiation through an iterative solver.
Dirichlet data are absolute unknown values, not displacement increments.
"""
from dataclasses import dataclass, field, replace
from math import isfinite
import torch


@dataclass(frozen=True)
class GMRESOptions:
    rtol: float = 1e-3
    atol: float = 1e-12
    restart: int = 50
    max_iterations: int = 1000
    check_every: int = 5
    check_policy: str = 'periodic'
    true_check_interval: int = 25

    def __post_init__(self):
        if not all(isfinite(t) and t >= 0 for t in (self.rtol,self.atol)) or self.rtol+self.atol == 0:
            raise ValueError('invalid linear tolerances')
        for n in (self.restart,self.max_iterations,self.check_every,self.true_check_interval):
            if not isinstance(n,int) or isinstance(n,bool) or n < 1:
                raise ValueError('positive integer GMRES controls required')
        if self.check_policy not in ('periodic','estimated'):
            raise ValueError('GMRES check_policy must be periodic or estimated')


@dataclass(frozen=True)
class NewtonOptions:
    rtol: float = 1e-8
    atol: float = 1e-8
    max_iterations: int = 25
    max_backtracks: int = 20
    armijo: float = 1e-4
    linear: GMRESOptions = field(default_factory=GMRESOptions)
    linear_tolerance_fraction: float = 0.
    linear_forcing: str = 'fixed'

    def __post_init__(self):
        if not all(isfinite(t) and t >= 0 for t in (self.rtol,self.atol)) or self.rtol+self.atol == 0:
            raise ValueError('invalid nonlinear tolerances')
        for n in (self.max_iterations,self.max_backtracks):
            if not isinstance(n,int) or isinstance(n,bool) or n < 1:
                raise ValueError('positive integer Newton controls required')
        if not isfinite(self.armijo) or not 0 < self.armijo < 1:
            raise ValueError('Armijo constant must be between zero and one')
        if not isinstance(self.linear,GMRESOptions) or self.linear.rtol >= 1-self.armijo:
            raise ValueError('linear relative tolerance must ensure a descent direction')
        if (not isfinite(self.linear_tolerance_fraction) or
                not 0 <= self.linear_tolerance_fraction < 1-self.armijo):
            raise ValueError('linear tolerance fraction must be nonnegative and ensure descent')
        if self.linear_forcing not in ('fixed','adaptive'):
            raise ValueError('linear_forcing must be fixed or adaptive')


def coupled_linear_policy(options, policy):
    """Execution-only comparisons, with the same final nonlinear target."""
    if policy == 'reference':
        return replace(options,linear=replace(options.linear,check_policy='periodic'),linear_forcing='fixed')
    if policy == 'estimated':
        return replace(options,linear=replace(options.linear,check_policy='estimated'),linear_forcing='fixed')
    if policy == 'inexact':
        return replace(options,linear=replace(options.linear,check_policy='estimated'),
                       linear_forcing='adaptive',linear_tolerance_fraction=.5)
    raise ValueError('linear policy must be reference, estimated or inexact')


@dataclass(frozen=True)
class NewtonResult:
    x: torch.Tensor
    converged: bool
    residual_norm: float
    tolerance: float
    iterations: int
    history: list


class NonlinearFailure(RuntimeError):
    """Retains the last accepted iterate; never mutates the caller's input."""
    def __init__(self,message,result):
        super().__init__(message)
        self.result = result


def _check(value,reference,name):
    _check_metadata(value,reference,name)
    if not torch.isfinite(value).all():
        raise FloatingPointError(f'nonfinite {name}')


def _check_metadata(value,reference,name):
    if (not isinstance(value,torch.Tensor) or value.shape != reference.shape or
        value.dtype != reference.dtype or value.device != reference.device):
        raise ValueError(f'{name} must match unknown shape, dtype and device')


def normalized_linear_action(action):
    """Evaluate an approximately linear action at unit input norm, then rescale.

    Nested iterative mass/pressure solves have absolute stopping tolerances.
    Using the same input scale in Arnoldi and in correction residual checks
    prevents tiny corrections from being dominated by those absolute errors.
    The zero action is exact and does not reuse a nonzero warm-start solution.
    This does not normalize the nonlinear residual or its acceptance test.
    """
    def apply(direction):
        scale = torch.linalg.vector_norm(direction)
        if scale.item() == 0:
            return torch.zeros_like(direction)
        return scale*action(direction/scale)
    return apply


@torch.no_grad()
def gmres(action,rhs,*,precondition=None,options=None):
    """Restarted right-preconditioned GMRES; residuals use the original A.

    Two orthogonalization passes. The small Hessenberg least-squares problem
    uses QR/triangular solve on the same device. Breakdown is never success
    unless the actual residual meets tolerance. Starts from zero.
    """
    opt = GMRESOptions() if options is None else options
    if rhs.dtype not in (torch.float32,torch.float64) or not rhs.numel():
        raise ValueError('nonempty floating rhs required')
    norm = lambda x: torch.linalg.vector_norm(x).item()
    _check_metadata(rhs,rhs,'rhs')
    rhs_norm=norm(rhs)
    if not isfinite(rhs_norm): raise FloatingPointError('nonfinite rhs norm')
    tol = max(opt.atol,opt.rtol*rhs_norm)
    shape = rhs.shape
    actions = true_checks = estimated_checks = residual_restarts = 0
    last_action_norm=0.
    def apply(v):
        nonlocal actions,last_action_norm
        actions += 1
        out = action(v.reshape(shape))
        _check_metadata(out,rhs,'operator action')
        # Arnoldi needs this norm anyway. Its finite result also validates the
        # complete action, avoiding an independent isfinite host barrier.
        last_action_norm=norm(out)
        if not isfinite(last_action_norm): raise FloatingPointError('nonfinite operator action norm')
        return out.reshape(-1)
    def solve_pre(v):
        out = v.reshape(shape) if precondition is None else precondition(v.reshape(shape))
        _check(out,rhs,'preconditioner action')
        return out.reshape(-1)
    x = torch.zeros_like(rhs).reshape(-1)
    b = rhs.reshape(-1)
    residual = b-apply(x)
    residual_norm=norm(residual)
    count = 0
    def info():
        return dict(iterations=count,residual_norm=residual_norm,tolerance=tol,
                    operator_actions=actions,true_residual_checks=true_checks,
                    estimated_residual_checks=estimated_checks,residual_restarts=residual_restarts)
    while residual_norm > tol and count < opt.max_iterations:
        beta = torch.linalg.vector_norm(residual)
        width = min(opt.restart,opt.max_iterations-count,b.numel())
        V = b.new_zeros((b.numel(),width+1))
        Z = b.new_zeros((b.numel(),width))
        H = b.new_zeros((width+1,width))
        # Givens rotations update only the small device-side Hessenberg system.
        # No coupled operator is called to obtain this residual estimate.
        rotated = b.new_zeros((width+1,width)) if opt.check_policy=='estimated' else None
        cosines,sines = b.new_zeros(width),b.new_zeros(width)
        g = b.new_zeros(width+1); g[0] = beta
        V[:,0] = residual/beta
        base = x.clone()
        for j in range(width):
            Z[:,j] = solve_pre(V[:,j])
            w = apply(Z[:,j])
            original_norm = last_action_norm
            for _ in range(2):
                coefficients = V[:,:j+1].T@w
                H[:j+1,j] += coefficients
                w = w-V[:,:j+1]@coefficients
            H[j+1,j] = torch.linalg.vector_norm(w)
            breakdown = H[j+1,j].item() <= 100*torch.finfo(b.dtype).eps*max(original_norm,torch.finfo(b.dtype).tiny)
            if not breakdown:
                V[:,j+1] = w/H[j+1,j]
            count += 1
            estimated_converged = False
            if rotated is not None:
                column = H[:j+2,j].clone()
                for k in range(j):
                    a,c = column[k].clone(),column[k+1].clone()
                    column[k] = cosines[k]*a+sines[k]*c
                    column[k+1] = -sines[k]*a+cosines[k]*c
                radius = torch.hypot(column[j],column[j+1])
                denominator = radius.clamp_min(torch.finfo(b.dtype).tiny)
                cosines[j],sines[j] = column[j]/denominator,column[j+1]/denominator
                column[j] = radius; column[j+1] = 0
                rotated[:j+2,j] = column
                previous = g[j].clone()
                g[j+1] = -sines[j]*previous; g[j] = cosines[j]*previous
                estimated_checks += 1
                estimated_converged = g[j+1].abs().item() <= tol
            scheduled = ((j+1)%opt.check_every==0 if rotated is None
                         else count%opt.true_check_interval==0)
            if breakdown or scheduled or estimated_converged or j+1 == width:
                Q,R = torch.linalg.qr(H[:j+2,:j+1],mode='reduced')
                if (R.diagonal().abs() <= torch.finfo(b.dtype).eps*R.abs().max()).any():
                    raise RuntimeError('GMRES singular Hessenberg system')
                target = b.new_zeros(j+2)
                target[0] = beta
                y = torch.linalg.solve_triangular(R,(Q.T@target)[:,None],upper=True)[:,0]
                x = base+Z[:,:j+1]@y
                residual = b-apply(x)
                residual_norm=norm(residual)
                true_checks += 1
                if residual_norm <= tol:
                    return x.reshape(shape),info()
                if breakdown:
                    raise RuntimeError('GMRES breakdown before true-residual convergence')
                if estimated_converged:
                    # Nested mass/pressure solves may make the action inexact.
                    # A rejected estimate restarts from its measured residual.
                    residual_restarts += 1
                    break
    if residual_norm > tol:
        raise RuntimeError(f'GMRES failed: true residual {residual_norm:.6g} > {tol:.6g} after {count} iterations')
    return x.reshape(shape),info()


@torch.no_grad()
def newton(residual,x0,*,validate,fixed=None,values=None,preconditioner_factory=None,
           linearization_factory=None,options=None):
    """Solve free residual=0 with exact JVP and Armijo residual-norm backtracking.

    A preconditioner is prepared once per Newton iteration and applied on the
    right in GMRES. Geometry is checked before evaluating any trial residual.
    A supplied linearization_factory(x) returns an exact Jacobian action,
    allowing assembled FE tangents and pressure elimination without autograd
    through iterative linear solvers. Otherwise use the residual's exact JVP.
    Optional linear_tolerance_fraction floors the inner absolute tolerance at
    a fraction of the final nonlinear target to avoid oversolving. GMRES still
    checks its true residual; Armijo and final nonlinear acceptance are intact.
    Singular tangents, nonconvergence and failed line searches raise with the
    last accepted state. Initial invalid input raises before any iteration.
    """
    opt = NewtonOptions() if options is None else options
    if x0.dtype not in (torch.float32,torch.float64) or not x0.numel():
        raise ValueError('nonempty floating unknown required')
    _check(x0,x0,'initial unknown')
    fixed = torch.zeros_like(x0,dtype=torch.bool) if fixed is None else fixed
    if fixed.shape != x0.shape or fixed.dtype != torch.bool or fixed.device != x0.device:
        raise ValueError('fixed mask must match unknown shape/device')
    values = x0 if values is None else values
    _check(values,x0,'Dirichlet values')
    x = torch.where(fixed,values,x0).detach().clone()
    project = lambda y: y.masked_fill(fixed,0)
    def evaluate(y):
        validate(y)
        r = residual(y)
        _check(r,x0,'nonlinear residual')
        return project(r).detach()
    r = evaluate(x)
    norm = lambda a: torch.linalg.vector_norm(a).item()
    initial = norm(r)
    tol = max(opt.atol,opt.rtol*initial)
    history = [dict(iteration=0,residual_norm=initial)]
    def result(ok):
        return NewtonResult(x.detach().clone(),ok,norm(r),tol,len(history)-1,list(history))
    for iteration in range(1,opt.max_iterations+1):
        if norm(r) <= tol:
            return result(True)
        try:
            tangent = None if linearization_factory is None else linearization_factory(x)
            def action(v):
                direction = project(v)
                out = (torch.func.jvp(residual,(x,),(direction,))[1]
                       if tangent is None else tangent(direction))
                return project(out).detach()
            inverse = None if preconditioner_factory is None else preconditioner_factory(x)
            precondition = None if inverse is None else lambda v: project(inverse(project(v)))
            forcing = opt.linear.rtol
            if opt.linear_forcing=='adaptive':
                current = norm(r)
                previous = initial if len(history)==1 else history[-2]['residual_norm']
                forcing = min(.5,max(opt.linear.rtol,.9*(current/max(previous,torch.finfo(x.dtype).tiny))**2))
                if len(history)==1:
                    forcing = min(forcing,.1)
                if current <= 200*tol:
                    forcing = min(forcing,.5*tol/current)
            linear = replace(opt.linear,rtol=forcing,
                             atol=max(opt.linear.atol,opt.linear_tolerance_fraction*tol))
            step,linear_info = gmres(action,-r,precondition=precondition,options=linear)
            linear_info.update(nonlinear_residual_norm=norm(r),nonlinear_tolerance=tol,
                               configured_atol=opt.linear.atol,effective_atol=linear.atol,
                               effective_rtol=linear.rtol,linear_forcing=opt.linear_forcing)
        except (RuntimeError,FloatingPointError) as exc:
            raise NonlinearFailure(f'Newton linear solve failed: {exc}',result(False)) from exc
        old_norm = norm(r)
        accepted = False
        for backtrack in range(opt.max_backtracks+1):
            alpha = 2.**(-backtrack)
            trial = torch.where(fixed,values,x+alpha*step)
            try:
                candidate = evaluate(trial)
            except (ValueError,FloatingPointError):
                continue
            if norm(candidate) <= (1-opt.armijo*alpha)*old_norm:
                x,r = trial.detach(),candidate
                accepted = True
                history.append(dict(iteration=iteration,residual_norm=norm(r),alpha=alpha,
                                    backtracks=backtrack,linear=linear_info))
                break
        if not accepted:
            raise NonlinearFailure('Newton backtracking failed',result(False))
    if norm(r) <= tol:
        return result(True)
    raise NonlinearFailure('Newton iteration limit reached',result(False))
