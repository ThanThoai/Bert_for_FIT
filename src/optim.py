import math
import torch
from torch.optim import Optimizer
from torch.nn.utils import clip_grad_norm_


def warmup_cosine(x, warmup = 0.002):
    if x < warmup:
        return x / warmup

    return 0.5 * (1.0 + torch.cos(math.pi * x))


def warmup_constant(x, warmup = 0.002):
    if x < warmup:
        return x / warmup

    return 1.0

def warmup_linear(x, warmup = 0.002):
    if x < warmup:
        return x / warmup
    return 1.0 - x

SCHEDULES = {
    'warmup_cosine': warmup_cosine,
    'warmup_constant': warmup_constant,
    'warmup_linear': warmup_linear,
}


class BertAdam(Optimizer):

    def __init__(self, params, lr, warmup = -1, t_total=-1, schedule = "warmup_linear", b1 = 0.9, b2 = 0.999, e = 1e-6, weight_decay_rate = 0.01, max_grad_norm =1.0):
        if not lr >= 0.0:
            raise ValueError("Invalid learning rate: {} - should be >= 0.0".format(lr))
        if schedule not in SCHEDULES:
            raise ValueError("Invalid schedule parameter: {}".format(schedule))
        if not 0.0 <= warmup < 1.0 and not warmup == -1:
            raise ValueError("Invalid warmup: {} - should be in [0.0, 1.0[ or -1".format(warmup))
        if not 0.0 <= b1 < 1.0:
            raise ValueError("Invalid b1 parameter: {} - should be in [0.0, 1.0[".format(b1))
        if not 0.0 <= b2 < 1.0:
            raise ValueError("Invalid b2 parameter: {} - should be in [0.0, 1.0[".format(b2))
        if not e >= 0.0:
            raise ValueError("Invalid epsilon value: {} - should be >= 0.0".format(e))
        defaults = dict(lr=lr, schedule=schedule, warmup=warmup, t_total=t_total,
                        b1=b1, b2=b2, e=e, weight_decay_rate=weight_decay_rate,
                        max_grad_norm=max_grad_norm)
        super(BertAdam, self).__init__(params, defaults)

    def get_lr(self):
        lr = []
        for group in self.param_groups:
            for p in group["params"]:
                state = self.state[p]
                if len(state) == 0:
                    return [0]
                if group["t_total"] != -1:
                    schedule_fct = SCHEDULES[group["schedule"]]
                    lr_scheduled = group['lr'] * schedule_fct(state['step'] / group['t_total'], group['warmup'])
                else:
                    lr_scheduled = group['lr']
                lr.append(lr_scheduled)
        return lr

    def step(self, closure = None):

        loss = None
        if closure is not None:
            loss = closure()
        
        for group in self.param_groups:
            for p in group["params"]:
                if p.grad is None:
                    continue
                grad = p.grad.data
                if grad.is_sparse:
                    raise RuntimeError("Error")

                state = self.state[p]

                if len(state) == 0:
                    state['step'] = 0
                    state['next_m'] = torch.zeros_like(p.data)
                    state['next_v'] = torch.zeros_like(p.data)

                next_m, next_v = state['next_m'], state['next_v']
                beta_1, beta_2 = group['b1'], group['b2']

                if group["max_grad_norm"] > 0:
                    clip_grad_norm_(p, group["max_grad_norm"])

                next_m.mul_(beta_1).add_(1 - beta_1, grad)
                next_v.mul_(beta_2).addcmul_(1 - beta_2, grad, grad)

                update = next_m / (next_v.sqrt() + group['e'])

                if group['weight_decay_rate'] > 0.0:
                    update += group['weight_decay_rate'] * p.data
                
                if group['t_total'] != -1:
                    schedule_fct = SCHEDULES[group['schedule']]
                    lr_scheduled = group['lr'] * schedule_fct(state['step'] / group['t_total'], group['warmup'])
                
                else:
                    lr_scheduled = group['lr']
                
                update_with_lr = lr_scheduled * update
                p.data.add_(- update_with_lr)
                state['step'] += 1

        return loss

