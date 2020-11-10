import torch
from torch.optim.adamw import AdamW


class AdamMW(AdamW):

    @torch.no_grad()
    def step(self, closure=None):
        """Performs a single optimization step.

        Arguments:
            closure (callable, optional): A closure that reevaluates the model
                and returns the loss.
        """
        loss = None
        if closure is not None:
            with torch.enable_grad():
                loss = closure()

        for group in self.param_groups:
            for p in group['params']:
                if p.grad is None:
                    continue

                # Perform stepweight decay
                p.mul_(1 - group['lr'] * group['weight_decay'])

                # Perform optimization step
                grad = p.grad
                if grad.is_sparse:
                    raise RuntimeError('AdamW does not support sparse gradients')
                amsgrad = group['amsgrad']

                state = self.state[p]

                # State initialization
                if len(state) == 0:
                    state['step'] = 0
                    # Exponential moving average of gradient values
                    state['exp_avg'] = torch.zeros_like(p, memory_format=torch.preserve_format)
                    # Exponential moving average of squared gradient values
                    state['exp_avg_sq'] = torch.zeros_like(p, memory_format=torch.preserve_format)
                    if amsgrad:
                        # Maintains max of all exp. moving avg. of sq. grad. values
                        state['max_exp_avg_sq'] = torch.zeros_like(p, memory_format=torch.preserve_format)

                exp_avg, exp_avg_sq = state['exp_avg'], state['exp_avg_sq']
                if amsgrad:
                    max_exp_avg_sq = state['max_exp_avg_sq']
                beta1, beta2 = group['betas']

                state['step'] += 1
                cur_beta1 = beta1 - beta1 ** state['step']
                cur_beta2 = beta2 - beta2 ** state['step']

                # Decay the first and second moment running average coefficient
                exp_avg.mul_(cur_beta1).add_(grad, alpha=1 - cur_beta1)
                # exp_avg_sq.mul_(cur_beta2).addcmul_(grad, grad, value=1 - cur_beta2)
                exp_avg_sq.mul_(cur_beta2).add_(abs(grad), alpha=1 - cur_beta2)
                if amsgrad:
                    # Maintains the maximum of all 2nd moment running avg. till now
                    torch.maximum(max_exp_avg_sq, exp_avg_sq, out=max_exp_avg_sq)
                    # Use the max. for normalizing running avg. of gradient
                    denom = max_exp_avg_sq.sqrt().add_(group['eps'])
                else:
                    # denom = exp_avg_sq.sqrt().add_(group['eps'])
                    denom = exp_avg_sq.add_(group['eps'])

                step_size = group['lr']
                p.addcdiv_(exp_avg, denom, value=-step_size)

        return loss
