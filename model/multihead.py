# model/multihead.py

import torch
import torch.nn as nn
from torch.nn import functional as F
import sys
import os

sys.path.insert(0, os.path.dirname(__file__))
from tokenizer import encode, decode, vocab_size, text

# ─────────────────────────────────────────
# HYPERPARAMETERS
# ─────────────────────────────────────────
batch_size    = 32
block_size    = 8
max_iters     = 3000
eval_interval = 300
learning_rate = 1e-2
eval_iters    = 200
device        = 'cpu'
n_embd        = 32
n_head        = 4    # ← NEW: number of attention heads

torch.manual_seed(1337)

# ─────────────────────────────────────────
# DATA
# ─────────────────────────────────────────
data       = torch.tensor(encode(text), dtype=torch.long)
n          = int(0.9 * len(data))
train_data = data[:n]
val_data   = data[n:]

# ─────────────────────────────────────────
# DATA LOADER
# ─────────────────────────────────────────
def get_batch(split):
    data = train_data if split == 'train' else val_data
    ix   = torch.randint(len(data) - block_size, (batch_size,))
    x    = torch.stack([data[i:i+block_size]     for i in ix])
    y    = torch.stack([data[i+1:i+block_size+1] for i in ix])
    return x, y

# ─────────────────────────────────────────
# LOSS ESTIMATOR
# ─────────────────────────────────────────
@torch.no_grad()
def estimate_loss():
    out = {}
    model.eval()
    for split in ['train', 'val']:
        losses = torch.zeros(eval_iters)
        for k in range(eval_iters):
            X, Y         = get_batch(split)
            logits, loss = model(X, Y)
            losses[k]    = loss.item()
        out[split] = losses.mean()
    model.train()
    return out

# ─────────────────────────────────────────
# SINGLE ATTENTION HEAD — same as before
# ─────────────────────────────────────────
class Head(nn.Module):
    """ one head of self attention """

    def __init__(self, head_size):
        super().__init__()
        self.query = nn.Linear(n_embd, head_size, bias=False)
        self.key   = nn.Linear(n_embd, head_size, bias=False)
        self.value = nn.Linear(n_embd, head_size, bias=False)
        self.register_buffer('tril', torch.tril(torch.ones(block_size, block_size)))

    def forward(self, x):
        B, T, C = x.shape
        q = self.query(x)  # (B, T, head_size)
        k = self.key(x)    # (B, T, head_size)

        wei = q @ k.transpose(-2, -1) * C**-0.5  # (B, T, T)
        wei = wei.masked_fill(self.tril[:T, :T] == 0, float('-inf'))
        wei = F.softmax(wei, dim=-1)

        v   = self.value(x)
        out = wei @ v      # (B, T, head_size)
        return out

# ─────────────────────────────────────────
# MULTI HEAD ATTENTION — THE NEW PART
# ─────────────────────────────────────────
class MultiHeadAttention(nn.Module):
    """ multiple heads of self attention running in parallel """

    def __init__(self, num_heads, head_size):
        super().__init__()
        # create num_heads independent attention heads
        self.heads = nn.ModuleList([Head(head_size) for _ in range(num_heads)])
        # projection layer — combines all head outputs back to n_embd
        self.proj  = nn.Linear(n_embd, n_embd)

    def forward(self, x):
        # run all heads in parallel and concatenate results
        out = torch.cat([h(x) for h in self.heads], dim=-1)
        # (B, T, head_size * num_heads) = (B, T, 8*4) = (B, T, 32)

        # project back to n_embd
        out = self.proj(out)  # (B, T, n_embd)
        return out

# ─────────────────────────────────────────
# FEEDFORWARD NETWORK — ALSO NEW
# ─────────────────────────────────────────
class FeedForward(nn.Module):
    """
    a simple linear layer followed by non linearity
    this comes AFTER attention and lets each token
    think about what it gathered from attention
    """

    def __init__(self, n_embd):
        super().__init__()
        self.net = nn.Sequential(
            nn.Linear(n_embd, 4 * n_embd),  # expand to 4x
            nn.ReLU(),                        # non linearity
            nn.Linear(4 * n_embd, n_embd),  # back to n_embd
        )

    def forward(self, x):
        return self.net(x)

# ─────────────────────────────────────────
# MODEL WITH MULTI HEAD ATTENTION
# ─────────────────────────────────────────
class MultiHeadModel(nn.Module):

    def __init__(self, vocab_size):
        super().__init__()
        self.token_embedding_table    = nn.Embedding(vocab_size, n_embd)
        self.position_embedding_table = nn.Embedding(block_size, n_embd)

        # head_size = n_embd // n_head = 32 // 4 = 8
        # each head gets an equal slice of the embedding dimension
        self.sa_heads = MultiHeadAttention(n_head, n_embd // n_head)

        # feedforward comes after attention
        self.ffwd    = FeedForward(n_embd)
        self.lm_head = nn.Linear(n_embd, vocab_size)

    def forward(self, idx, targets=None):
        B, T = idx.shape

        tok_emb = self.token_embedding_table(idx)                               # (B, T, 32)
        pos_emb = self.position_embedding_table(torch.arange(T, device=device)) # (T, 32)
        x       = tok_emb + pos_emb   # (B, T, 32)

        # attention — tokens communicate with each other
        x = self.sa_heads(x)          # (B, T, 32)

        # feedforward — tokens individually process what they gathered
        x = self.ffwd(x)              # (B, T, 32)

        logits = self.lm_head(x)      # (B, T, 65)

        if targets is None:
            loss = None
        else:
            B, T, C = logits.shape
            logits  = logits.view(B*T, C)
            targets = targets.view(B*T)
            loss    = F.cross_entropy(logits, targets)

        return logits, loss

    def generate(self, idx, max_new_tokens):
        for _ in range(max_new_tokens):
            idx_cond     = idx[:, -block_size:]
            logits, loss = self(idx_cond)
            logits       = logits[:, -1, :]
            probs        = F.softmax(logits, dim=-1)
            idx_next     = torch.multinomial(probs, num_samples=1)
            idx          = torch.cat((idx, idx_next), dim=1)
        return idx

# ─────────────────────────────────────────
# TRAINING LOOP
# ─────────────────────────────────────────
model     = MultiHeadModel(vocab_size)
optimizer = torch.optim.AdamW(model.parameters(), lr=learning_rate)

print("Training with Multi-Head Attention...")
print(f"Vocab size: {vocab_size} | Heads: {n_head} | Device: {device}\n")

for iter in range(max_iters):
    if iter % eval_interval == 0:
        losses = estimate_loss()
        print(f"step {iter:4d}: train loss {losses['train']:.4f} | val loss {losses['val']:.4f}")

    xb, yb       = get_batch('train')
    logits, loss = model(xb, yb)
    optimizer.zero_grad(set_to_none=True)
    loss.backward()
    optimizer.step()

print("\nTraining complete! Generating text...\n")
print("-" * 50)

# ─────────────────────────────────────────
# GENERATE
# ─────────────────────────────────────────
context = torch.zeros((1, 1), dtype=torch.long, device=device)
print(decode(model.generate(context, max_new_tokens=500)[0].tolist()))
print("-" * 50)