from importlib.metadata import version
print("torch version:", version("torch"))


print("\n================ 3.3.1 A simple self-attention mechanism without trainable weights ================")
import torch
inputs = torch.tensor(
  [[0.43, 0.15, 0.89], # Your     (x^1)
   [0.55, 0.87, 0.66], # journey  (x^2)
   [0.57, 0.85, 0.64], # starts   (x^3)
   [0.22, 0.58, 0.33], # with     (x^4)
   [0.77, 0.25, 0.10], # one      (x^5)
   [0.05, 0.80, 0.55]] # step     (x^6)
)
query = inputs[1]
attn_scores_2 = torch.empty(inputs.shape[0]) # allocate memory
for i, xi in enumerate(inputs):
    attn_scores_2[i] = torch.dot(xi, query)
print("Attention scores:", attn_scores_2)

# torch.dot() equals to the following code:
res = 0.
for idx, element in enumerate(inputs[0]):
    res += inputs[0][idx] * query[idx]
print(res)
print(torch.dot(inputs[0], query))

# nomalize the attention scores
# 1. using built-in functions
attn_weights_2_tmp = attn_scores_2 / attn_scores_2.sum()
print("Attention weights:", attn_weights_2_tmp)
print("Sum:", attn_weights_2_tmp.sum())
# 2. implementing softmax manually
def softmax_naive(x):
    return torch.exp(x) / torch.exp(x).sum(dim=0)
attn_weights_2_naive = softmax_naive(attn_scores_2)
print("Attention weights:", attn_weights_2_naive)
print("Sum:", attn_weights_2_naive.sum())
# 3. using torch.softmax()
attn_weights_2_torch = torch.softmax(attn_scores_2, dim=0)
print("Attention weights:", attn_weights_2_torch)
print("Sum:", attn_weights_2_torch.sum())

# compute context vector as weighted sum of value vectors
query = inputs[1]
context_vec_2 = torch.zeros(query.shape)
for i, x_i in enumerate(inputs):
    context_vec_2 += attn_weights_2_torch[i] * x_i
print("Context vector:", context_vec_2)

print("\n================ 3.3.3 Computing attention weights for all input tokens ================")
attn_scores = torch.empty(6, 6)
for i, x_i in enumerate(inputs):
    for j, x_j in enumerate(inputs):
        attn_scores[i, j] = torch.dot(x_i, x_j)
print("Attention scores:\n", attn_scores)

attn_scores = inputs @ inputs.T
print("Attention scores:\n", attn_scores)

attn_weights = torch.softmax(attn_scores, dim=-1)
print("Attention weights:\n", attn_weights)

row_2_sum = attn_weights[1].sum()
print("Row 2 sum:", row_2_sum)
print("All row sums:", attn_weights.sum(dim=-1))

all_context_vecs = attn_weights @ inputs
print("All context vectors:\n", all_context_vecs)
print("Previous 2nd context vector:", context_vec_2)

print("\n================ 3.4.1 Computing the attention weights step by step ================")
x_2 = inputs[1]
d_in = inputs.shape[1]
d_out = 2
torch.manual_seed(123)
W_query = torch.nn.Parameter(torch.rand(d_in, d_out), requires_grad=False)
W_key = torch.nn.Parameter(torch.rand(d_in, d_out), requires_grad=False)
W_value = torch.nn.Parameter(torch.rand(d_in, d_out), requires_grad=False)
query_2 = x_2 @ W_query
keys_2 = x_2 @ W_key
values_2 = x_2 @ W_value
print("Query vector: ", query_2)
keys = inputs @ W_key
values = inputs @ W_value
print("keys.shape:", keys.shape)
print("values.shape:", values.shape)
keys_2 = keys[1]
attn_scores_22 = query_2.dot(keys_2)
print("22 Attention score:", attn_scores_22)
attn_scores_2 = query_2 @ keys.T
print("2 Attention scores:", attn_scores_2)
d_k = keys.shape[1]
attn_weights_2 = torch.softmax(attn_scores_2 / d_k**0.5, dim=-1)
print("2 Attention weights:", attn_weights_2)
context_vec_2 = attn_weights_2 @ values
print("2 Context vector:", context_vec_2)


print("\n================ 3.4.2 Implementing a compact SelfAttention class ================")
import torch.nn as nn
class SelfAttention_v1(nn.Module):

    def __init__(self, d_in, d_out):
        super().__init__()
        self.W_query = torch.nn.Parameter(torch.rand(d_in, d_out))
        self.W_key = torch.nn.Parameter(torch.rand(d_in, d_out))
        self.W_value = torch.nn.Parameter(torch.rand(d_in, d_out))

    def forward(self, x):
        keys = x @ self.W_key
        values = x @ self.W_value
        queries = x @ self.W_query
        
        # softmax[(q*k^T) / sqrt(d_k)] * v
        attn_scores = queries @ keys.T
        attn_weights = torch.softmax(
            attn_scores / keys.shape[-1]**0.5, dim=-1
        )
        context_vec = attn_weights @ values
        
        return context_vec

torch.manual_seed(123)
sa_v1 = SelfAttention_v1(d_in=d_in, d_out=d_out)
print(sa_v1(inputs))

class SelfAttention_v2(nn.Module):

    def __init__(self, d_in, d_out, qkv_bias=False):
        super().__init__()
        self.W_query = nn.Linear(d_in, d_out, bias=qkv_bias)
        self.W_key = nn.Linear(d_in, d_out, bias=qkv_bias)
        self.W_value = nn.Linear(d_in, d_out, bias=qkv_bias)

    def forward(self, x):
        keys = self.W_key(x)
        values = self.W_value(x)
        queries = self.W_query(x)
        
        # softmax[(q*k^T) / sqrt(d_k)] * v
        attn_scores = queries @ keys.T
        attn_weights = torch.softmax(
            attn_scores / keys.shape[-1]**0.5, dim=-1
        )
        context_vec = attn_weights @ values
        
        return context_vec

torch.manual_seed(789)
sa_v2 = SelfAttention_v2(d_in=d_in, d_out=d_out)
print(sa_v2(inputs))

print("\n================ 3.5.1 Applying a causal attention mask ================")
queries = sa_v2.W_query(inputs)
keys = sa_v2.W_key(inputs)
attn_scores = queries @ keys.T
attn_weights = torch.softmax(
    attn_scores / keys.shape[-1]**0.5, dim=-1
)
print("Attention weights without mask:\n", attn_weights)
context_length = attn_scores.shape[0]
mask_simple = torch.tril(torch.ones(context_length, context_length))
print("Simple causal mask:\n", mask_simple)
masked_simple = attn_weights * mask_simple
print("Masked attention weights (simple):\n", masked_simple)
row_sums = masked_simple.sum(dim=-1, keepdim=True)
masked_simple_norm = masked_simple / row_sums
print("Normalized masked attention weights (simple):\n", masked_simple_norm)
mask = torch.triu(torch.ones(context_length, context_length), diagonal=1)
masked = attn_scores.masked_fill(mask.bool(), -torch.inf)
print("Masked attention scores:\n", masked)
attn_weights = torch.softmax(
    masked / keys.shape[-1]**0.5, dim=-1
)
print("Normalized masked attention weights (complicated):\n", attn_weights)


print("\n================ 3.5.2 Masking additional attention weights with dropout ================")
torch.manual_seed(123)
dropout = torch.nn.Dropout(0.5)
example = torch.ones(6, 6)
print("example dropout:\n", dropout(example)) # note, dropout scale the output by 1/(1-p) to keep the expected value unchanged
torch.manual_seed(123)
print(dropout(attn_weights))

print("\n================ 3.5.3 Implementing a compact causal self-attention class ================")
batch = torch.stack((inputs, inputs), dim=0) # 增加1个维度（升维）
print("batch.shape:", batch.shape)
class CausalAttention(nn.Module):

    def __init__(self, d_in, d_out, context_length, dropout, qkv_bias=False):
        super().__init__()
        self.W_query = nn.Linear(d_in, d_out, bias=qkv_bias)
        self.W_key = nn.Linear(d_in, d_out, bias=qkv_bias)
        self.W_value = nn.Linear(d_in, d_out, bias=qkv_bias)
        self.dropout = nn.Dropout(dropout)
        self.register_buffer(
            'mask', torch.triu(torch.ones(context_length, context_length), diagonal=1)
        )

    def forward(self, x):
        b, num_tokens, d_in = x.shape
        keys = self.W_key(x)
        queries = self.W_query(x)
        values = self.W_value(x)
        attn_scores = queries @ keys.transpose(-2, -1)
        attn_scores.masked_fill_(
            self.mask.bool()[:num_tokens, :num_tokens], -torch.inf
        )
        attn_weights = torch.softmax(
            attn_scores / keys.shape[-1]**0.5, dim=-1
        )
        attn_weights = self.dropout(attn_weights)
        context_vec = attn_weights @ values
        return context_vec

torch.manual_seed(123)
context_length = batch.shape[1]
ca = CausalAttention(d_in, d_out, context_length, 0.0)
context_vecs = ca(batch)
print("Context vectors:\n", context_vecs)
print("Context vector shape:", context_vecs.shape)

print("\n================ 3.6.1 Stacking multiple single-head attention layers ================")
class MultiHeadAttentionWrapper(nn.Module):

    def __init__(self, d_in, d_out, context_length, dropout, num_heads, qkv_bias=False):
        super().__init__()
        self.heads = nn.ModuleList(
            [CausalAttention(d_in, d_out, context_length, dropout, qkv_bias) for _ in range(num_heads)]
        )

    def forward(self, x):
        return torch.cat([head(x) for head in self.heads], dim=-1)

torch.manual_seed(123)
context_length = batch.shape[1]
mha = MultiHeadAttentionWrapper(d_in, d_out, context_length, 0.0, num_heads=2)
context_vecs = mha(batch)
print("MHA Context vectors:\n", context_vecs)
print("MHA Context vector shape:", context_vecs.shape)

print("\n================ 3.6.2 Implementing multi-head attention with weight splits ================")
class MultiHeadAttention(nn.Module):

    def __init__(self, d_in, d_out, context_length, dropout, num_heads, qkv_bias=False):
        super().__init__()
        assert (d_out % num_heads == 0), "d_out must be divisible by num_heads"
        
        self.d_out = d_out
        self.num_heads = num_heads
        self.head_dim = d_out // num_heads

        self.W_query = nn.Linear(d_in, d_out, bias=qkv_bias)
        self.W_key = nn.Linear(d_in, d_out, bias=qkv_bias)
        self.W_value = nn.Linear(d_in, d_out, bias=qkv_bias)
        self.out_proj = nn.Linear(d_out, d_out)
        self.dropout = nn.Dropout(dropout)
        self.register_buffer(
            # diagonal=1 means the upper triangular part above the main diagonal will be filled with 1
            'mask', torch.triu(torch.ones(context_length, context_length), diagonal=1)
        )

    def forward(self, x):
        b, num_tokens, d_in = x.shape

        keys = self.W_key(x)
        queries = self.W_query(x)
        values = self.W_value(x)

        keys = keys.view(b, num_tokens, self.num_heads, self.head_dim).transpose(1, 2) # (b, num_heads, num_tokens, head_dim)
        queries = queries.view(b, num_tokens, self.num_heads, self.head_dim).transpose(1, 2)
        values = values.view(b, num_tokens, self.num_heads, self.head_dim).transpose(1, 2)

        attn_scores = queries @ keys.transpose(-2, -1)
        mask_bool = self.mask.bool()[:num_tokens, :num_tokens]
        attn_scores.masked_fill_(mask_bool, -torch.inf)
        attn_weights = torch.softmax(
            attn_scores / keys.shape[-1]**0.5, dim=-1
        )
        attn_weights = self.dropout(attn_weights)
        # print("attn_weights sum: ", attn_weights.sum(dim=-1, keepdim=True))
        # print("attn_weights shape: ", attn_weights.shape)

        context_vec = (attn_weights @ values).transpose(1, 2) # (b, num_tokens, num_heads, head_dim)
        context_vec = context_vec.contiguous().view(b, num_tokens, self.d_out) # view 要求输入张量内存连续, view() 只是改变张量的"形状解释方式"，不移动数据
        context_vec = self.out_proj(context_vec)

        return context_vec

torch.manual_seed(123)
batch_size, context_length, d_in = batch.shape
d_out = 2
mha = MultiHeadAttention(d_in, d_out, context_length, dropout=0.0, num_heads=2)
context_vecs = mha(batch)
print("MHA Context vectors:\n", context_vecs)
print("MHA Context vectors shape:\n", context_vecs.shape)

print("\n================ Look at what happens in 'attn_scores = queries @ keys.transpose(2, 3)'  ================")
a = torch.tensor([[[[0.2745, 0.6584, 0.2775, 0.8573],
                    [0.8993, 0.0390, 0.9268, 0.7388],
                    [0.7179, 0.7058, 0.9156, 0.4340]],

                   [[0.0772, 0.3565, 0.1479, 0.5331],
                    [0.4066, 0.2318, 0.4545, 0.9737],
                    [0.4606, 0.5159, 0.4220, 0.5786]]]])
print(a @ a.transpose(2, 3))
print("a shape:", a.shape)
first_head = a[0, 0, :, :]
first_res = first_head @ first_head.T
print("first head:", first_res)

second_head = a[0, 1, :, :]
second_res = second_head @ second_head.T
print("second head:", second_res)

        

















