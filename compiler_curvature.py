#!/usr/bin/env python3
"""
Smart Memoized DP Compiler with Landscape Analysis
===================================================
No parameter exploration. Actions are selected based on landscape geometry.
Prints steps, tracks progress, and falls back to gradient descent at the end.
"""
import json, math, warnings, collections, os, sys, time, copy
warnings.filterwarnings('ignore')
import numpy as np
import scipy.sparse as sp, scipy.sparse.linalg as spla
import torch, torch.nn as nn, torch.nn.functional as F

# ============================================================================
# CONFIGURATION
# ============================================================================
D = 256
N_HEADS = 4
N_STU = 6
BATCH = 8
SEQ = 64
LR = 3e-4
ETA_MF = 0.01
N_SUB = 200
VOCAB = 1017
MAX_DP_STEPS = 50

PHI_CLEAN_TARGET = 5
TAU_MIN = 1.5
TAU_MAX = 5.7
VAL_FLOOR = 0.062
ORBIT_TOLERANCE = 0.3

# ============================================================================
# DATA LOADING
# ============================================================================
for f in ['/tmp/train_ids.json', '/tmp/val_ids.json', '/tmp/vocab.json']:
    if not os.path.exists(f):
        sys.exit(f"ERROR: {f} missing. Run: python build_corpus.py")

with open('/tmp/train_ids.json') as f: train_ids = list(map(int, json.load(f)))
with open('/tmp/val_ids.json') as f: val_ids = list(map(int, json.load(f)))
with open('/tmp/vocab.json') as f: _v = json.load(f)
VOCAB = len(_v) if isinstance(_v, list) else len(_v)
train_t = torch.tensor(train_ids, dtype=torch.long)
val_t = torch.tensor(val_ids, dtype=torch.long)

# ============================================================================
# MODEL DEFINITION
# ============================================================================
class Attn(nn.Module):
    def __init__(self):
        super().__init__()
        dh = D // N_HEADS
        self.WQ = nn.Linear(D, D, bias=False)
        self.WK = nn.Linear(D, D, bias=False)
        self.WV = nn.Linear(D, D, bias=False)
        self.op = nn.Linear(D, D, bias=False)
        self.ln = nn.LayerNorm(D)
        self.sc = math.sqrt(dh)
        self.nh = N_HEADS
        self.dh = dh
        for w in [self.WQ, self.WK, self.WV, self.op]:
            nn.init.normal_(w.weight, std=0.02)

    def forward(self, h):
        B, S, _ = h.shape
        Q = self.WQ(h).view(B, S, self.nh, self.dh).transpose(1, 2)
        K = self.WK(h).view(B, S, self.nh, self.dh).transpose(1, 2)
        V = self.WV(h).view(B, S, self.nh, self.dh).transpose(1, 2)
        sc = Q @ K.transpose(-2, -1) / self.sc
        mask = torch.triu(torch.ones(S, S), diagonal=1).bool()
        sc = sc.masked_fill(mask.unsqueeze(0).unsqueeze(0), float('-inf'))
        return self.ln(h + self.op((F.softmax(sc, dim=-1) @ V).transpose(1, 2).reshape(B, S, D)))


class FF(nn.Module):
    def __init__(self):
        super().__init__()
        self.g = nn.Linear(D, D * 2, bias=False)
        self.v = nn.Linear(D, D * 2, bias=False)
        self.o = nn.Linear(D * 2, D, bias=False)
        self.n = nn.LayerNorm(D)
        for w in [self.g, self.v, self.o]:
            nn.init.normal_(w.weight, std=0.02)

    def forward(self, h):
        return self.n(h + self.o(F.silu(self.g(h)) * self.v(h)))


class Block(nn.Module):
    def __init__(self):
        super().__init__()
        self.attn = Attn()
        self.ff = FF()

    def forward(self, h):
        return self.ff(self.attn(h))


class LM(nn.Module):
    def __init__(self):
        super().__init__()
        self.te = nn.Embedding(VOCAB, D)
        self.pe = nn.Embedding(512, D)
        self.blocks = nn.ModuleList([Block() for _ in range(N_STU)])
        self.ln_f = nn.LayerNorm(D)
        self.head = nn.Linear(D, VOCAB, bias=False)
        self.head.weight = self.te.weight
        nn.init.normal_(self.te.weight, std=0.02)
        nn.init.normal_(self.pe.weight, std=0.02)

    def forward(self, x, y=None):
        h = self.te(x) + self.pe(torch.arange(x.shape[1]))
        for b in self.blocks:
            h = b(h)
        logits = self.head(self.ln_f(h))
        if y is not None:
            return logits, F.cross_entropy(logits.view(-1, VOCAB), y.view(-1))
        return logits, None

    def flat_params(self):
        return torch.cat([p.data.flatten() for p in self.parameters()])

    def set_flat(self, v):
        i = 0
        for p in self.parameters():
            n = p.numel()
            p.data.copy_(v[i:i + n].reshape(p.shape))
            i += n


# ============================================================================
# UTILITY FUNCTIONS
# ============================================================================
def get_batch(split='train'):
    data = val_t if split == 'val' else train_t
    ix = torch.randint(0, len(data) - SEQ - 1, (BATCH,))
    return (torch.stack([data[i:i + SEQ] for i in ix]),
            torch.stack([data[i + 1:i + SEQ + 1] for i in ix]))


def eval_val(m, n=8):
    m.eval()
    ls = []
    with torch.no_grad():
        for _ in range(n):
            x, y = get_batch('val')
            _, l = m(x, y)
            ls.append(l.item())
    return float(np.mean(ls))


def sheet_angles(model):
    out = []
    WKs = [model.blocks[l].attn.WK.weight.data.float() for l in range(N_STU)]
    for l in range(N_STU - 1):
        try:
            phi = WKs[l + 1] @ torch.linalg.pinv(WKs[l])
            lam = torch.linalg.eigvals(phi)
            lam1 = lam[lam.abs().argmax()]
            a = float(torch.angle(lam1))
            while a > math.pi:
                a -= 2 * math.pi
            while a < -math.pi:
                a += 2 * math.pi
            out.append(a)
        except:
            out.append(float('nan'))
    return out


def phi_clean(model):
    angles = sheet_angles(model)
    return sum(1 for a in angles if not np.isnan(a) and 
               (abs(a) < ORBIT_TOLERANCE or abs(abs(a) - math.pi) < ORBIT_TOLERANCE))


def gluing_defect(model, n=6):
    model.zero_grad()
    ls = [model(*get_batch())[1] for _ in range(n)]
    torch.stack(ls).mean().backward()
    g_ff = sum(p.grad.data.norm().item() for nm, p in model.named_parameters()
               if '.ff.' in nm and p.grad is not None)
    g_emb = model.te.weight.grad.data.norm().item() if model.te.weight.grad is not None else 1e-8
    model.zero_grad()
    return float(g_ff / max(g_emb, 1e-8))


def w_ff_formula_clamped(tau):
    if tau < TAU_MIN:
        return 3.5
    if tau > TAU_MAX:
        return 0.47
    return 3.5 * (TAU_MIN / max(tau, 0.1)) ** 1.5


def compute_E_init():
    bigram = collections.Counter()
    perm = {}
    for i in range(len(train_ids) - 1):
        a, b = train_ids[i], train_ids[i + 1]
        if a < VOCAB and b < VOCAB:
            bigram[(a, b)] += 1
            perm.setdefault(a, b)

    rows, cols, vv = [], [], []
    for (a, b), cnt in bigram.items():
        rows.append(a); cols.append(b); vv.append(float(cnt))

    W_sp = sp.csr_matrix((vv, (rows, cols)), shape=(VOCAB, VOCAB), dtype=np.float32)
    W_sp = W_sp + W_sp.T
    d_inv = np.array(1.0 / (W_sp.sum(1) + 1e-8)).flatten()
    Dsi = sp.diags(np.sqrt(d_inv))
    L_sym = sp.eye(VOCAB) - Dsi @ W_sp @ Dsi
    evals, evecs = spla.eigsh(L_sym, k=D + 1, which='SM', tol=1e-4, maxiter=2000)
    idx_s = np.argsort(evals)
    evecs = evecs[:, idx_s][:, 1:D + 1]
    E_0 = (evecs / (np.sqrt(evals[idx_s[1:D + 1]]) + 1e-8)[np.newaxis, :]).astype(np.float32)
    E_0 = (E_0 / (E_0.std() + 1e-8) * 0.02)
    E_next = np.array([E_0[perm.get(t, t)] for t in range(VOCAB)], dtype=np.float32)
    E_init = (0.9 * E_0 + 0.1 * E_next)
    E_norm = float(np.linalg.norm(E_0))
    E_init = (E_init * (E_norm / max(float(np.linalg.norm(E_init)), 1e-8))).astype(np.float32)
    return E_init


# ============================================================================
# LANDSCAPE ANALYSIS (FIXED - ALL NATIVE TYPES)
# ============================================================================
class LandscapeAnalyzer:
    def __init__(self):
        self.cache = {}
    
    def _to_float(self, x):
        """Convert anything to a Python float."""
        if x is None:
            return 0.0
        if isinstance(x, torch.Tensor):
            if x.numel() == 1:
                return float(x.item())
            return float(x.mean().item())
        if isinstance(x, np.ndarray):
            if x.size == 1:
                return float(x.item())
            return float(np.mean(x))
        try:
            return float(x)
        except (TypeError, ValueError):
            return 0.0
    
    def analyze(self, model):
        """Measure the loss landscape geometry. All returns are Python floats."""
        # Force float conversion
        v = self._to_float(eval_val(model, n=8))
        phi = int(phi_clean(model))
        tau = self._to_float(gluing_defect(model, n=6))
        
        # Power iteration for Hessian extremes
        def hvp_s(v_tensor, n=4):
            model.zero_grad()
            ls = [model(*get_batch())[1] for _ in range(n)]
            loss = torch.stack(ls).mean()
            grads = torch.autograd.grad(loss, list(model.parameters()), create_graph=True)
            gv = (torch.cat([gr.flatten() for gr in grads]) * v_tensor.detach()).sum()
            hv = torch.cat([h.flatten() for h in
                            torch.autograd.grad(gv, list(model.parameters()), retain_graph=False)])
            model.zero_grad()
            return hv.detach()
        
        n_p = sum(p.numel() for p in model.parameters())
        
        # Largest eigenvalue (power iteration)
        torch.manual_seed(42)
        v_tensor = torch.randn(n_p)
        v_tensor = v_tensor / v_tensor.norm()
        for _ in range(10):
            Hv = hvp_s(v_tensor)
            v_tensor = Hv / max(self._to_float(Hv.norm()), 1e-10)
        lambda_max = self._to_float((v_tensor * hvp_s(v_tensor)).sum())
        
        # Smallest eigenvalue (power iteration on -H)
        torch.manual_seed(43)
        v_tensor = torch.randn(n_p)
        v_tensor = v_tensor / v_tensor.norm()
        for _ in range(10):
            Hv = hvp_s(v_tensor)
            v_tensor = -Hv / max(self._to_float(Hv.norm()), 1e-10)
        lambda_min = self._to_float((v_tensor * hvp_s(v_tensor)).sum())
        
        # Gradient norm
        model.zero_grad()
        ls = [model(*get_batch())[1] for _ in range(6)]
        torch.stack(ls).mean().backward()
        g_norm = 0.0
        for p in model.parameters():
            if p.grad is not None:
                g_norm += self._to_float(p.grad.data.norm())
        model.zero_grad()
        
        return {
            'val': v,
            'phi': phi,
            'tau': tau,
            'lambda_max': lambda_max,
            'lambda_min': lambda_min,
            'g_norm': g_norm,
            'is_positive_definite': lambda_min > 0,
            'has_negative_curvature': lambda_min < -0.01,
            'is_flat': abs(lambda_max) < 0.01,
            'in_orbit': phi == PHI_CLEAN_TARGET and TAU_MIN <= tau <= TAU_MAX,
            'near_floor': v < 0.1,
            'phase': 'saddle' if lambda_min < -0.01 else 'flat' if abs(lambda_max) < 0.01 else 'bowl'
        }


# ============================================================================
# COMPILER STATE
# ============================================================================
class CompilerState:
    def __init__(self, model, step, phase, val, phi, tau, action_history=None, parent=None):
        self.model = copy.deepcopy(model)
        self.step = step
        self.phase = phase
        self.val = val
        self.phi = phi
        self.tau = tau
        self.action_history = action_history or []
        self.parent = parent
        self.children = []

    def __repr__(self):
        orbit_ok = "✓" if self.phi == PHI_CLEAN_TARGET and TAU_MIN <= self.tau <= TAU_MAX else "✗"
        return (f"Step {self.step}: val={self.val:.4f}, phi={self.phi}/5, tau={self.tau:.2f} {orbit_ok}")


# ============================================================================
# SMART ACTION SELECTION (FIXED - ALL NATIVE TYPES)
# ============================================================================
def get_smart_actions(state, analyzer):
    """
    Return actions that have a mathematical chance of succeeding.
    No parameter exploration — each action is computed from geometry.
    """
    landscape = analyzer.analyze(state.model)
    actions = []
    
    # All values are already Python native types from LandscapeAnalyzer
    val = landscape['val']
    phi = landscape['phi']
    tau = landscape['tau']
    lambda_max = landscape['lambda_max']
    lambda_min = landscape['lambda_min']
    has_negative_curvature = landscape['has_negative_curvature']
    near_floor = landscape['near_floor']
    in_orbit = landscape['in_orbit']
    phase = landscape['phase']
    
    print(f"\n  Landscape: val={val:.4f}, phi={phi}/5, "
          f"tau={tau:.2f}, phase={phase}, "
          f"λ_min={lambda_min:.4f}, λ_max={lambda_max:.4f}")
    
    # 1. Saddle exit: only if negative curvature and not near floor
    if has_negative_curvature and not near_floor:
        if lambda_max - lambda_min > 0.01:
            alpha = -lambda_min / (lambda_max - lambda_min)
            alpha = np.clip(alpha, 0.5, 4.0)
            actions.append(('saddle_exit', {'alpha': float(alpha)}))
            print(f"    → saddle_exit: α={alpha:.3f} (curvature ratio)")
        else:
            print(f"    ℹ skipping saddle_exit: curvature ratio too small")
    else:
        if not has_negative_curvature:
            print(f"    ℹ skipping saddle_exit: no negative curvature (λ_min={lambda_min:.4f})")
        if near_floor:
            print(f"    ℹ skipping saddle_exit: near floor (val={val:.4f})")
    
    # 2. MF pump: works when not in orbit and not near floor and val > 0.3
    if not in_orbit and not near_floor and val > 0.3:
        eta = min(0.02, 0.01 / (1 + val))
        eta = max(0.001, eta)
        actions.append(('mf_pump', {'eta': float(eta)}))
        print(f"    → mf_pump: η={eta:.4f} (gradient-driven)")
    else:
        if in_orbit:
            print(f"    ℹ skipping mf_pump: already in orbit")
        if near_floor:
            print(f"    ℹ skipping mf_pump: near floor")
        if val <= 0.3:
            print(f"    ℹ skipping mf_pump: val={val:.4f} too low")
    
    # 3. Curvature settle: works almost everywhere. Step size is NOT chosen
    #    from val heuristically -- it's derived from measured local
    #    (lambda_min, lambda_max) via the Chebyshev schedule inside
    #    action_curvature_settle itself. We only vary the step BUDGET here,
    #    since farther-from-floor states can tolerate/benefit from more steps.
    if not near_floor:
        if val > 1.0:
            n_steps = 20
        elif val > 0.3:
            n_steps = 15
        else:
            n_steps = 10
        actions.append(('curvature_settle', {'n_steps': int(n_steps)}))
        print(f"    → curvature_settle: n_steps={n_steps} (eta from measured λ_min/λ_max)")
    else:
        print(f"    ℹ skipping curvature_settle: near floor")
    
    # 4. Restore orbit: only when near orbit but not in it
    if not in_orbit and phi >= 3 and not near_floor:
        off_wall = PHI_CLEAN_TARGET - phi
        step_size = min(0.5, 0.15 * off_wall)
        step_size = max(0.1, step_size)
        actions.append(('restore_orbit', {'step_size': float(step_size)}))
        print(f"    → restore_orbit: step={step_size:.2f} (off-wall count={off_wall})")
    else:
        if in_orbit:
            print(f"    ℹ skipping restore_orbit: already in orbit")
        if phi < 3:
            print(f"    ℹ skipping restore_orbit: phi={phi}/5 too low")
    
    # 5. K0 split: works in or near orbit
    if phi >= 4:
        w_ff = w_ff_formula_clamped(tau)
        actions.append(('k0_split', {'w_ff': 'clamped'}))
        print(f"    → k0_split: w_FF={w_ff:.2f} (clamped formula)")
    else:
        print(f"    ℹ skipping k0_split: phi={phi}/5 < 4")
    
    # 6. LM step: only near floor with positive curvature
    if near_floor and landscape['is_positive_definite']:
        actions.append(('lm_step', {'mu': 0.95}))
        print(f"    → lm_step: μ=0.95 (PD near floor)")
    elif near_floor:
        print(f"    ℹ skipping lm_step: not PD (λ_min={lambda_min:.4f})")
    
    # 7. Lanczos: only at floor in orbit
    if near_floor and in_orbit:
        actions.append(('lanczos', {'k': 8}))
        print(f"    → lanczos: k=8 (terminal projection)")
    elif near_floor:
        print(f"    ℹ skipping lanczos: not in orbit (phi={phi}/5)")
    
    # 8. If no actions, try curvature settle as fallback
    if not actions:
        print(f"    ⚠ No viable actions from geometry. Using fallback.")
        actions.append(('curvature_settle', {'n_steps': 10}))
        print(f"    → fallback: curvature_settle n_steps=10")
    
    return actions


# ============================================================================
# ACTION FUNCTIONS
# ============================================================================
def action_saddle_exit(state, params):
    model = state.model
    alpha = params['alpha']
    
    def hvp_s(v, n=8):
        model.zero_grad()
        ls = [model(*get_batch())[1] for _ in range(n)]
        loss = torch.stack(ls).mean()
        grads = torch.autograd.grad(loss, list(model.parameters()), create_graph=True)
        gv = (torch.cat([gr.flatten() for gr in grads]) * v.detach()).sum()
        hv = torch.cat([h.flatten() for h in
                        torch.autograd.grad(gv, list(model.parameters()), retain_graph=False)])
        model.zero_grad()
        return hv.detach()
    
    n_p = sum(p.numel() for p in model.parameters())
    torch.manual_seed(42)
    v = torch.randn(n_p)
    v = v / v.norm()
    for _ in range(10):
        Hv = hvp_s(v)
        neg = -Hv
        v = neg / max(float(neg.norm()), 1e-10)
    
    w0 = model.flat_params()
    model_try = copy.deepcopy(model)
    model_try.set_flat(w0 + alpha * (v / v.norm()))
    
    # Quick orbit check and correction
    if phi_clean(model_try) < PHI_CLEAN_TARGET:
        WKs = [model_try.blocks[l].attn.WK.weight.data.float().cpu().numpy()
               for l in range(N_STU)]
        for k in range(N_STU - 1):
            phases = sheet_angles(model_try)
            if k < len(phases) and not (abs(phases[k]) < ORBIT_TOLERANCE or 
                                        abs(abs(phases[k]) - math.pi) < ORBIT_TOLERANCE):
                try:
                    Wk = WKs[k].astype(complex)
                    Wk1 = WKs[k + 1].astype(complex)
                    Wk_inv = np.linalg.pinv(Wk)
                    M = Wk1 @ Wk_inv
                    evals_M, evecs_M = np.linalg.eig(M)
                    idx = np.argmax(np.abs(evals_M.real))
                    lam = evals_M[idx]
                    r_vec = evecs_M[:, idx]
                    evals_L, evecs_L = np.linalg.eig(M.T)
                    idx_L = np.argmax(np.abs(evals_L.real))
                    l_vec = evecs_L[:, idx_L].conj()
                    lr = l_vec @ r_vec
                    if abs(lr) > 1e-10:
                        l_vec = l_vec / lr
                    lam_mag = abs(lam)
                    Wk_inv_r = Wk_inv @ r_vec
                    J_k = np.outer(l_vec, Wk_inv_r)
                    dPhi = np.imag(J_k) / (lam_mag + 1e-10)
                    U_s, s_vals, Vt_s = np.linalg.svd(dPhi)
                    if s_vals[0] > 1e-10:
                        target = math.pi if phases[k] > 0 else 0.0
                        alpha_corr = (target - phases[k]) / s_vals[0]
                        alpha_corr = np.clip(alpha_corr, -2.0, 2.0) * 0.3
                        u1 = U_s[:, 0].real
                        v1 = Vt_s[0, :].real
                        delta = alpha_corr * np.outer(u1, v1)
                        with torch.no_grad():
                            model_try.blocks[k + 1].attn.WK.weight.data.add_(
                                torch.tensor(delta, dtype=torch.float32))
                except:
                    pass
    
    v_try = eval_val(model_try, n=6)
    
    if v_try < state.val * 0.95:
        return CompilerState(model_try, state.step + 1, 'saddle_exit',
                            v_try, phi_clean(model_try), gluing_defect(model_try),
                            state.action_history + [f'saddle_exit(α={alpha:.3f})'],
                            parent=state)
    return None


def action_mf_pump(state, params):
    eta = params['eta']
    model = state.model
    model_try = copy.deepcopy(model)
    v0 = state.val
    
    for mf_r in range(1, 4):
        # E step
        for l in range(N_STU):
            model_try.blocks[l].attn.WK.weight.requires_grad_(False)
            model_try.blocks[l].attn.WQ.weight.requires_grad_(False)
        
        emb_grad = torch.zeros(model_try.te.weight.shape)
        emb_fish = torch.zeros(model_try.te.weight.shape)
        torch.manual_seed((mf_r - 1) * 1000)
        
        for i in range(N_SUB // 3):
            ix = torch.randint(0, len(train_t) - SEQ - 1, (1,))[0].item()
            x = train_t[ix:ix + SEQ].unsqueeze(0)
            y = train_t[ix + 1:ix + SEQ + 1].unsqueeze(0)
            model_try.zero_grad()
            _, loss = model_try(x, y)
            loss.backward()
            if model_try.te.weight.grad is not None:
                g = model_try.te.weight.grad.detach()
                emb_grad += g
                emb_fish += g ** 2
        
        emb_grad /= (N_SUB // 3)
        emb_fish /= (N_SUB // 3)
        delta_E = -(emb_grad / (emb_fish + 1e-4))
        with torch.no_grad():
            model_try.te.weight.add_(eta * delta_E)
        
        for l in range(N_STU):
            model_try.blocks[l].attn.WK.weight.requires_grad_(True)
            model_try.blocks[l].attn.WQ.weight.requires_grad_(True)
        
        # WK step
        model_try.te.weight.requires_grad_(False)
        wk_grad = torch.zeros_like(model_try.blocks[0].attn.WK.weight)
        wk_fish = torch.zeros_like(model_try.blocks[0].attn.WK.weight)
        torch.manual_seed((mf_r - 1) * 1000 + 500)
        
        for i in range(N_SUB // 3):
            ix = torch.randint(0, len(train_t) - SEQ - 1, (1,))[0].item()
            x = train_t[ix:ix + SEQ].unsqueeze(0)
            y = train_t[ix + 1:ix + SEQ + 1].unsqueeze(0)
            model_try.zero_grad()
            _, loss = model_try(x, y)
            loss.backward()
            g = torch.zeros_like(model_try.blocks[0].attn.WK.weight)
            for bl in model_try.blocks:
                if bl.attn.WK.weight.grad is not None:
                    g += bl.attn.WK.weight.grad / N_STU
            wk_grad += g
            wk_fish += g ** 2
        
        wk_grad /= (N_SUB // 3)
        wk_fish /= (N_SUB // 3)
        delta_WK = -(wk_grad / (wk_fish + 1e-4))
        with torch.no_grad():
            for l in range(N_STU):
                model_try.blocks[l].attn.WK.weight.add_(eta * delta_WK)
                model_try.blocks[l].attn.WQ.weight.add_(eta * delta_WK.T)
        model_try.te.weight.requires_grad_(True)
        
        v_mf = eval_val(model_try, n=4)
        if v_mf > v0 * 1.5:
            return None
        if phi_clean(model_try) >= 4:
            break
    
    v_try = eval_val(model_try, n=6)
    if v_try < state.val * 0.95:
        return CompilerState(model_try, state.step + 1, 'mf_pump',
                            v_try, phi_clean(model_try), gluing_defect(model_try),
                            state.action_history + [f'mf_pump(η={eta:.4f})'],
                            parent=state)
    return None


def estimate_hessian_extremes(model, n_power_iter=10, n_hvp_samples=6):
    """
    Power iteration for the top (lambda_max) and bottom (lambda_min) Hessian
    eigenvalues at the model's CURRENT parameters, via Hessian-vector products
    (no explicit Hessian ever formed). Same cost/technique already used
    elsewhere in this file (LandscapeAnalyzer.analyze, action_saddle_exit) --
    reused here to size step lengths instead of just to pick a saddle direction.

    NOTE: this is a LOCAL estimate. It is only valid near the point it was
    measured at; re-estimate before trusting it after the parameters have
    moved substantially (see curvature_settle's re-anchoring loop below).
    """
    def hvp(v, n=n_hvp_samples):
        model.zero_grad()
        ls = [model(*get_batch())[1] for _ in range(n)]
        loss = torch.stack(ls).mean()
        grads = torch.autograd.grad(loss, list(model.parameters()), create_graph=True)
        gv = (torch.cat([g.flatten() for g in grads]) * v.detach()).sum()
        hv = torch.cat([h.flatten() for h in
                        torch.autograd.grad(gv, list(model.parameters()), retain_graph=False)])
        model.zero_grad()
        return hv.detach()

    n_p = sum(p.numel() for p in model.parameters())

    v = torch.randn(n_p); v = v / v.norm()
    for _ in range(n_power_iter):
        Hv = hvp(v)
        v = Hv / max(float(Hv.norm()), 1e-10)
    lambda_max = float((v * hvp(v)).sum())

    v = torch.randn(n_p); v = v / v.norm()
    for _ in range(n_power_iter):
        Hv = hvp(v)
        v = -Hv / max(float(Hv.norm()), 1e-10)
    lambda_min = float((v * hvp(v)).sum())

    return lambda_min, lambda_max


def chebyshev_step_schedule(n_steps, lambda_min, lambda_max):
    """
    Closed-form step sizes for gradient descent on a quadratic with spectrum
    in [lambda_min, lambda_max]: eta_k = 1 / x_k, where x_k are the roots of
    the degree-n Chebyshev polynomial mapped into [lambda_min, lambda_max].
    This is the step-size sequence that minimizes worst-case error after
    exactly n_steps, for a quadratic model of the loss (standard result,
    e.g. Nesterov). It is NOT the same as Adam/AdamW's adaptive per-parameter
    scaling -- it is a scalar sequence derived directly from the two measured
    eigenvalue extremes.
    """
    lambda_min = max(lambda_min, lambda_max * 1e-3, 1e-8)  # guard against <=0 / degenerate spectrum
    etas = []
    for k in range(1, n_steps + 1):
        theta_k = math.pi * (2 * k - 1) / (2 * n_steps)
        x_k = 0.5 * (lambda_max + lambda_min) + 0.5 * (lambda_max - lambda_min) * math.cos(theta_k)
        etas.append(1.0 / max(x_k, 1e-8))
    return etas


def action_curvature_settle(state, params, n_steps=15):
    """
    Replaces action_basin_settle's fixed LR-multiplier heuristic.

    Instead of guessing a learning-rate multiplier from val alone, this:
      1. Estimates local (lambda_min, lambda_max) via power iteration.
      2. Derives a Chebyshev step-size schedule from those two numbers
         (closed-form optimal for a quadratic model, see chebyshev_step_schedule).
      3. Takes n_steps of PLAIN gradient descent (no Adam moment-tracking,
         since the Chebyshev schedule assumes it IS controlling the raw
         step length) using that schedule.

    This is re-anchored every time it's called (every DP step calls it fresh
    off state.model), so as parameters move and the local quadratic
    approximation stops holding, the next call re-measures curvature rather
    than trusting a stale estimate.
    """
    model = state.model
    model_try = copy.deepcopy(model)

    lambda_min, lambda_max = estimate_hessian_extremes(model_try)
    lambda_max_eff = max(lambda_max, 1e-6)
    eta_crit = 2.0 / lambda_max_eff
    print(f"    [curvature_settle] lambda_min={lambda_min:.4f} lambda_max={lambda_max:.4f} "
          f"eta_crit=2/lambda_max={eta_crit:.6f}")

    etas = chebyshev_step_schedule(n_steps, lambda_min, lambda_max_eff)
    print(f"    [curvature_settle] eta schedule: min={min(etas):.6f} max={max(etas):.6f}")

    for step, eta in enumerate(etas, 1):
        model_try.train()
        x, y = get_batch()
        _, l = model_try(x, y)
        model_try.zero_grad()
        l.backward()
        torch.nn.utils.clip_grad_norm_(model_try.parameters(), 1.0)
        with torch.no_grad():
            for p in model_try.parameters():
                if p.grad is not None:
                    p.data.add_(p.grad, alpha=-eta)
        model_try.zero_grad()

        if step % 5 == 0 or step == n_steps:
            v = eval_val(model_try, n=4)
            if v > state.val * 1.5:
                return None  # schedule overshot -- curvature estimate was stale/wrong, bail out

    v_try = eval_val(model_try, n=8)
    if v_try < state.val * 0.95:
        return CompilerState(model_try, state.step + 1, 'curvature_settle',
                            v_try, phi_clean(model_try), gluing_defect(model_try),
                            state.action_history + [f'curvature_settle({n_steps}steps,lmax={lambda_max:.3f})'],
                            parent=state)
    return None


def action_restore_orbit(state, params):
    step_size = params['step_size']
    model = state.model
    
    phases = sheet_angles(model)
    off_wall = [i for i, p in enumerate(phases) 
                if not np.isnan(p) and not (abs(p) < ORBIT_TOLERANCE or abs(abs(p) - math.pi) < ORBIT_TOLERANCE)]
    
    if not off_wall:
        return None
    
    model_try = copy.deepcopy(model)
    WKs = [model_try.blocks[l].attn.WK.weight.data.float().cpu().numpy()
           for l in range(N_STU)]
    
    with torch.no_grad():
        for k in off_wall:
            if k >= len(WKs) - 1:
                continue
            try:
                Wk = WKs[k].astype(complex)
                Wk1 = WKs[k + 1].astype(complex)
                Wk_inv = np.linalg.pinv(Wk)
                M = Wk1 @ Wk_inv
                evals_M, evecs_M = np.linalg.eig(M)
                idx = np.argmax(np.abs(evals_M.real))
                lam = evals_M[idx]
                r_vec = evecs_M[:, idx]
                evals_L, evecs_L = np.linalg.eig(M.T)
                idx_L = np.argmax(np.abs(evals_L.real))
                l_vec = evecs_L[:, idx_L].conj()
                lr = l_vec @ r_vec
                if abs(lr) > 1e-10:
                    l_vec = l_vec / lr
                lam_mag = abs(lam)
                Wk_inv_r = Wk_inv @ r_vec
                J_k = np.outer(l_vec, Wk_inv_r)
                dPhi = np.imag(J_k) / (lam_mag + 1e-10)
                U_s, s_vals, Vt_s = np.linalg.svd(dPhi)
                if s_vals[0] > 1e-10:
                    target = math.pi if phases[k] > 0 else 0.0
                    alpha = (target - phases[k]) / s_vals[0]
                    alpha = np.clip(alpha, -2.0, 2.0) * step_size
                    u1 = U_s[:, 0].real
                    v1 = Vt_s[0, :].real
                    delta = alpha * np.outer(u1, v1)
                    model_try.blocks[k + 1].attn.WK.weight.data.add_(
                        torch.tensor(delta, dtype=torch.float32))
            except:
                pass
    
    v_try = eval_val(model_try, n=6)
    phi_try = phi_clean(model_try)
    
    if phi_try > state.phi and v_try < state.val * 1.1:
        return CompilerState(model_try, state.step + 1, 'restore_orbit',
                            v_try, phi_try, gluing_defect(model_try),
                            state.action_history + [f'restore_orbit(step={step_size:.2f})'],
                            parent=state)
    return None


def action_k0_split(state, params):
    model = state.model
    w_ff = w_ff_formula_clamped(state.tau)
    
    params_base = {n: p.data.clone() for n, p in model.named_parameters()}
    
    def ptype(name):
        if '.attn.WQ.' in name or '.attn.WK.' in name:
            return 'Attn'
        if 'te.weight' in name or '.ff.' in name:
            return 'EmbFF'
        return 'other'
    
    def get_lr(s, n, base_lr):
        return base_lr * 0.5 * (1 + math.cos(math.pi * s / n))
    
    # Branch 1: Emb+FF
    m1 = copy.deepcopy(model)
    for name, p in m1.named_parameters():
        if ptype(name) != 'EmbFF':
            p.requires_grad_(False)
    p1 = [p for p in m1.parameters() if p.requires_grad]
    opt1 = torch.optim.AdamW(p1, lr=LR, betas=(0.9, 0.95), weight_decay=0.1)
    
    for s in range(1, 21):
        for pg in opt1.param_groups:
            pg['lr'] = get_lr(s, 20, LR)
        m1.train()
        x, y = get_batch()
        _, l = m1(x, y)
        opt1.zero_grad()
        l.backward()
        torch.nn.utils.clip_grad_norm_(p1, 1.0)
        opt1.step()
    
    # Branch 2: Attn
    m2 = copy.deepcopy(model)
    for name, p in m2.named_parameters():
        if ptype(name) != 'Attn':
            p.requires_grad_(False)
    p2 = [p for p in m2.parameters() if p.requires_grad]
    opt2 = torch.optim.AdamW(p2, lr=LR, betas=(0.9, 0.95), weight_decay=0.1)
    
    for s in range(1, 21):
        for pg in opt2.param_groups:
            pg['lr'] = get_lr(s, 20, LR)
        m2.train()
        x, y = get_batch()
        _, l = m2(x, y)
        opt2.zero_grad()
        l.backward()
        torch.nn.utils.clip_grad_norm_(p2, 1.0)
        opt2.step()
    
    # Combine
    m_out = copy.deepcopy(model)
    with torch.no_grad():
        for name, p in m_out.named_parameters():
            pt = ptype(name)
            d1 = dict(m1.named_parameters())[name].data - params_base[name]
            d2 = dict(m2.named_parameters())[name].data - params_base[name]
            if pt == 'EmbFF':
                if 'te.weight' in name:
                    p.data.add_(d1)
                else:
                    p.data.add_(w_ff * d1)
            elif pt == 'Attn':
                p.data.add_(d2)
    
    v_try = eval_val(m_out, n=6)
    if v_try < state.val * 0.95:
        return CompilerState(m_out, state.step + 1, 'k0_split',
                            v_try, phi_clean(m_out), gluing_defect(m_out),
                            state.action_history + [f'k0_split(w_FF={w_ff:.2f})'],
                            parent=state)
    return None


def action_lm_step(state, params):
    mu = params['mu']
    model = state.model
    
    def hvp_l(v, n=4):
        model.zero_grad()
        ls = [model(*get_batch())[1] for _ in range(n)]
        loss = torch.stack(ls).mean()
        grads = torch.autograd.grad(loss, list(model.parameters()), create_graph=True)
        gv = (torch.cat([gr.flatten() for gr in grads]) * v.detach()).sum()
        hv = torch.cat([h.flatten() for h in
                        torch.autograd.grad(gv, list(model.parameters()), retain_graph=False)])
        model.zero_grad()
        return hv.detach()
    
    model_try = copy.deepcopy(model)
    model_try.zero_grad()
    ls = [model_try(*get_batch())[1] for _ in range(20)]
    torch.stack(ls).mean().backward()
    g = torch.cat([p.grad.flatten() if p.grad is not None else torch.zeros(p.numel())
                   for p in model_try.parameters()]).detach()
    model_try.zero_grad()
    
    n_p = sum(p.numel() for p in model_try.parameters())
    d = torch.zeros(n_p)
    r = -g.clone()
    p = r.clone()
    rr = float((r * r).sum())
    
    for _ in range(6):
        Hp = hvp_l(p) + mu * p
        al = rr / max(float((p * Hp).sum()), 1e-10)
        d += al * p
        r -= al * Hp
        rr2 = float((r * r).sum())
        p = r + (rr2 / max(rr, 1e-10)) * p
        rr = rr2
    
    w0 = model_try.flat_params()
    model_try.set_flat(w0 + d)
    v_try = eval_val(model_try, n=6)
    
    if v_try < state.val * 0.95:
        return CompilerState(model_try, state.step + 1, 'lm_step',
                            v_try, phi_clean(model_try), gluing_defect(model_try),
                            state.action_history + [f'lm_step(μ={mu:.2f})'],
                            parent=state)
    return None


def action_lanczos(state, params):
    model = state.model
    
    def hvp_l(v, n=4):
        model.zero_grad()
        ls = [model(*get_batch())[1] for _ in range(n)]
        loss = torch.stack(ls).mean()
        grads = torch.autograd.grad(loss, list(model.parameters()), create_graph=True)
        gv = (torch.cat([gr.flatten() for gr in grads]) * v.detach()).sum()
        hv = torch.cat([h.flatten() for h in
                        torch.autograd.grad(gv, list(model.parameters()), retain_graph=False)])
        model.zero_grad()
        return hv.detach()
    
    model_try = copy.deepcopy(model)
    n_p = sum(p.numel() for p in model_try.parameters())
    torch.manual_seed(7)
    q = torch.randn(n_p)
    q = q / q.norm()
    Q = [q]
    alphas = []
    betas = []
    
    for j in range(8):
        z = hvp_l(Q[j])
        alpha = float((Q[j] * z).sum())
        alphas.append(alpha)
        z = z - alpha * Q[j]
        if j > 0:
            z = z - betas[-1] * Q[j - 1]
        for qi in Q:
            z = z - float((qi * z).sum()) * qi
        beta = float(z.norm())
        betas.append(beta)
        if beta < 1e-8:
            break
        Q.append(z / beta)
    
    n_l = len(alphas)
    if n_l < 2:
        return None
    
    T = torch.zeros(n_l, n_l)
    for i in range(n_l):
        T[i, i] = alphas[i]
    for i in range(n_l - 1):
        T[i, i + 1] = betas[i]
        T[i + 1, i] = betas[i]
    
    T_evals, T_evecs = torch.linalg.eigh(T)
    V = torch.stack(Q[:n_l], dim=1) @ T_evecs
    
    mu = 0.95
    v0 = eval_val(model_try, n=6)
    accepted = False
    
    for si in range(3):
        model_try.zero_grad()
        ls = [model_try(*get_batch())[1] for _ in range(20)]
        torch.stack(ls).mean().backward()
        g = torch.cat([p.grad.flatten() if p.grad is not None else torch.zeros(p.numel())
                       for p in model_try.parameters()]).detach()
        model_try.zero_grad()
        
        g_proj = V.T @ g
        d_proj = g_proj / (T_evals + mu)
        g_res = g - V @ (V.T @ g)
        d = -(V @ d_proj + g_res / mu)
        
        w0 = model_try.flat_params()
        model_try.set_flat(w0 + d)
        v_try = eval_val(model_try, n=6)
        
        if v_try < v0:
            v0 = v_try
            accepted = True
        else:
            model_try.set_flat(w0)
            break
    
    if accepted and v0 < state.val * 0.95:
        return CompilerState(model_try, state.step + 1, 'lanczos',
                            v0, phi_clean(model_try), gluing_defect(model_try),
                            state.action_history + ['lanczos'],
                            parent=state)
    return None


# ============================================================================
# GRADIENT DESCENT FALLBACK
# ============================================================================
def run_curvature_informed_finish(model, max_rounds=8, n_steps_per_round=15, target_val=VAL_FLOOR):
    """
    Replaces the fixed-LR 400-step run_gradient_descent fallback.

    Instead of one long run at a single fixed learning rate, this re-anchors:
    each round, re-measure (lambda_min, lambda_max) at the CURRENT parameters
    (they've moved since the last measurement, so the old estimate may no
    longer be valid), derive a fresh Chebyshev step schedule from them, and
    take n_steps_per_round plain-GD steps. Stop early if target_val is
    reached or a round fails to improve val (diminishing/no progress).

    Honesty note: this is a heuristic built on a LOCAL quadratic approximation
    of the loss. It is not guaranteed to reach any particular loss value --
    the real loss surface is not exactly quadratic, so the Chebyshev schedule
    is optimal for the local model, not for the true loss. Re-anchoring each
    round is what keeps it honest as that local model goes stale.
    """
    print(f"\n  Running curvature-informed finish "
          f"(up to {max_rounds} rounds x {n_steps_per_round} steps, re-anchored each round)...")

    history = []
    v_prev = eval_val(model, n=8)

    for rnd in range(1, max_rounds + 1):
        lambda_min, lambda_max = estimate_hessian_extremes(model)
        lambda_max_eff = max(lambda_max, 1e-6)
        etas = chebyshev_step_schedule(n_steps_per_round, lambda_min, lambda_max_eff)
        print(f"    Round {rnd}: λ_min={lambda_min:.4f} λ_max={lambda_max:.4f} "
              f"η∈[{min(etas):.6f}, {max(etas):.6f}]")

        for eta in etas:
            model.train()
            x, y = get_batch()
            _, l = model(x, y)
            model.zero_grad()
            l.backward()
            torch.nn.utils.clip_grad_norm_(model.parameters(), 1.0)
            with torch.no_grad():
                for p in model.parameters():
                    if p.grad is not None:
                        p.data.add_(p.grad, alpha=-eta)
            model.zero_grad()

        v = eval_val(model, n=8)
        phi = phi_clean(model)
        tau = gluing_defect(model, n=4)
        history.append((rnd * n_steps_per_round, v, phi, tau))
        print(f"    Round {rnd} result: val={v:.4f}, phi={phi}/5, tau={tau:.2f}")

        if v < target_val:
            print(f"    ✓ Reached target val < {target_val} after {rnd} rounds "
                  f"({rnd * n_steps_per_round} total steps)")
            break
        if v >= v_prev * 0.999:
            print(f"    ~ No meaningful improvement this round (val {v_prev:.4f} -> {v:.4f}), stopping")
            break
        v_prev = v

    v_final = eval_val(model, n=12)
    phi_final = phi_clean(model)
    tau_final = gluing_defect(model, n=6)
    print(f"    Curvature-informed finish final: val={v_final:.4f}, phi={phi_final}/5, tau={tau_final:.2f}")
    return model, v_final, phi_final, tau_final, history


# ============================================================================
# SMART DP COMPILER
# ============================================================================
class SmartDPCompiler:
    def __init__(self):
        self.analyzer = LandscapeAnalyzer()
        self.failed_actions = set()
        self.exhausted_states = set()
        self.visited_states = []
        self.action_log = []
        self.best_state = None
        
    def get_state_key(self, state):
        val_bucket = int(state.val / 0.1)
        phi = state.phi
        tau_bucket = int(state.tau / 0.5)
        angles = sheet_angles(state.model)
        phase_bucket = tuple([int(a / 0.3) for a in angles if not np.isnan(a)])
        return (val_bucket, phi, tau_bucket, phase_bucket)
    
    def mark_failed(self, state, action_name, params):
        state_key = self.get_state_key(state)
        key = (state_key, action_name, tuple(sorted(params.items())))
        self.failed_actions.add(key)
        self.action_log.append({
            'state': str(state),
            'action': action_name,
            'params': params,
            'result': 'FAILED'
        })
    
    def find_backtrack_state(self, state_stack):
        for i in range(len(state_stack) - 1, -1, -1):
            state = state_stack[i]
            state_key = self.get_state_key(state)
            
            if state_key in self.exhausted_states:
                continue
            if state_key in self.visited_states:
                continue
            
            # Get smart actions for this state
            actions = get_smart_actions(state, self.analyzer)
            untried = [(name, params) for name, params in actions 
                      if (state_key, name, tuple(sorted(params.items()))) not in self.failed_actions]
            
            if untried:
                return i, state, untried
        
        return None, None, None
    
    def run(self):
        print("=" * 70)
        print("SMART DP COMPILER WITH LANDSCAPE ANALYSIS")
        print("=" * 70)
        print()
        
        # Initialize model
        E_init = compute_E_init()
        model = LM()
        model.te.weight.data.copy_(torch.tensor(E_init))
        
        v0 = eval_val(model, n=10)
        phi0 = phi_clean(model)
        tau0 = gluing_defect(model, n=6)
        
        print(f"Initial: val={v0:.4f}, phi={phi0}/5, tau={tau0:.2f}")
        print()
        
        # Initialize state
        initial_state = CompilerState(model, 0, 'init', v0, phi0, tau0, [], None)
        state_stack = [initial_state]
        self.best_state = initial_state
        self.visited_states = [self.get_state_key(initial_state)]
        step_counter = 0
        
        for step_counter in range(MAX_DP_STEPS):
            current = state_stack[-1]
            print(f"\n[Step {step_counter}] Current: {current}")
            
            # Check success
            if current.val < VAL_FLOOR and current.phi == PHI_CLEAN_TARGET:
                print(f"\n✓ SUCCESS! val={current.val:.4f}, phi={current.phi}/5")
                print(f"  Path: {' → '.join(current.action_history)}")
                return current
            
            # Get smart actions for current state
            actions = get_smart_actions(current, self.analyzer)
            state_key = self.get_state_key(current)
            
            # Filter untried
            untried = [(name, params) for name, params in actions 
                      if (state_key, name, tuple(sorted(params.items()))) not in self.failed_actions]
            
            if not untried:
                print(f"\n  ⊘ No untried actions at {current}")
                # Backtrack
                idx, back_state, back_untried = self.find_backtrack_state(state_stack)
                if back_state is None:
                    print(f"\n⚠ No states with untried actions. Best val={self.best_state.val:.4f}")
                    print(f"  Path: {' → '.join(self.best_state.action_history)}")
                    return self.best_state
                print(f"  → Backtracking to step {idx}")
                state_stack = state_stack[:idx+1]
                continue
            
            # Try actions
            action_taken = False
            for action_name, params in untried:
                print(f"\n  → Trying {action_name} with {params}")
                
                # Apply action
                result = self.apply_action(current, action_name, params)
                
                if result is None:
                    print(f"    ⊘ {action_name}: failed")
                    self.mark_failed(current, action_name, params)
                    continue
                
                if result.val < current.val * 0.95:
                    print(f"    ✓ {action_name}: {current.val:.4f} → {result.val:.4f} (phi={result.phi}/5)")
                    state_stack.append(result)
                    self.visited_states.append(self.get_state_key(result))
                    
                    if result.val < self.best_state.val:
                        self.best_state = result
                        print(f"    ★ New best: {result.val:.4f}")
                    
                    action_taken = True
                    break
                elif result.phi > current.phi and result.val < current.val * 1.1:
                    print(f"    ~ {action_name}: phi {current.phi}→{result.phi}/5, val {current.val:.4f}→{result.val:.4f}")
                    state_stack.append(result)
                    self.visited_states.append(self.get_state_key(result))
                    action_taken = True
                    break
                else:
                    print(f"    ⊘ {action_name}: no gain ({current.val:.4f} → {result.val:.4f})")
                    self.mark_failed(current, action_name, params)
            
            if not action_taken:
                print(f"\n  ⊘ No working action at {current}")
                self.exhausted_states.add(state_key)
        
        print(f"\n⚠ Max steps reached. Best val={self.best_state.val:.4f}")
        return self.best_state
    
    def apply_action(self, state, action_name, params):
        if action_name == 'saddle_exit':
            return action_saddle_exit(state, params)
        elif action_name == 'mf_pump':
            return action_mf_pump(state, params)
        elif action_name == 'curvature_settle':
            return action_curvature_settle(state, params.get('n_steps', 15))
        elif action_name == 'restore_orbit':
            return action_restore_orbit(state, params)
        elif action_name == 'k0_split':
            return action_k0_split(state, params)
        elif action_name == 'lm_step':
            return action_lm_step(state, params)
        elif action_name == 'lanczos':
            return action_lanczos(state, params)
        return None


# ============================================================================
# MAIN
# ============================================================================
def main():
    np.random.seed(42)
    torch.manual_seed(42)
    
    compiler = SmartDPCompiler()
    final_state = compiler.run()
    
    print("\n" + "=" * 70)
    print("FINAL RESULTS")
    print("=" * 70)
    print(f"  Final val:     {final_state.val:.4f}")
    print(f"  Final phi:     {final_state.phi}/5")
    print(f"  Final tau:     {final_state.tau:.2f}")
    print(f"  Total steps:   {final_state.step}")
    print(f"  Path:          {' → '.join(final_state.action_history)}")
    
    # If val is not good enough, run the curvature-informed finish
    # (replaces the old fixed-LR 400-step gradient_descent fallback)
    if final_state.val > 0.1 or final_state.phi < PHI_CLEAN_TARGET:
        print("\n" + "=" * 70)
        print("RUNNING CURVATURE-INFORMED FINISH (Chebyshev step schedule)")
        print("=" * 70)
        model, v_final, phi_final, tau_final, history = run_curvature_informed_finish(
            final_state.model, max_rounds=8, n_steps_per_round=15, target_val=VAL_FLOOR
        )
        
        print("\n" + "=" * 70)
        print("FINAL RESULTS AFTER CURVATURE-INFORMED FINISH")
        print("=" * 70)
        print(f"  Final val:     {v_final:.4f}")
        print(f"  Final phi:     {phi_final}/5")
        print(f"  Final tau:     {tau_final:.2f}")
        total_steps_used = history[-1][0] if history else 0
        print(f"  Path:          {' → '.join(final_state.action_history)} "
              f"→ curvature_informed_finish({total_steps_used} steps)")
        
        # Save final model
        torch.save(model.state_dict(), 'compiler_curvature_final.pt')
        print(f"\n  Saved: compiler_curvature_final.pt")
    else:
        # Save final model
        torch.save(final_state.model.state_dict(), 'compiler_smart_final.pt')
        print(f"\n  Saved: compiler_smart_final.pt")
    
    print("\n" + "=" * 70)
    print("COMPLETE")
    print("=" * 70)


if __name__ == '__main__':
    main()
