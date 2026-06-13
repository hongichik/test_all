import numpy as np
import torch
from scipy.sparse import csr_matrix
from operator import itemgetter

def data_masks(all_sessions, n_node):
    indptr, indices, data = [], [], []
    indptr.append(0)
    for j in range(len(all_sessions)):
        session = np.unique(all_sessions[j])
        length = len(session)
        s = indptr[-1]
        indptr.append((s + length))
        for i in range(length):
            indices.append(session[i]-1)
            data.append(1)
    matrix = csr_matrix((data, indices, indptr), shape=(len(all_sessions), n_node))

    return matrix

def split_validation(train_set, valid_portion):
    train_set_x, train_set_y = train_set
    n_samples = len(train_set_x)
    sidx = np.arange(n_samples, dtype='int32')
    np.random.shuffle(sidx)
    n_train = int(np.round(n_samples * (1. - valid_portion)))
    valid_set_x = [train_set_x[s] for s in sidx[n_train:]]
    valid_set_y = [train_set_y[s] for s in sidx[n_train:]]
    train_set_x = [train_set_x[s] for s in sidx[:n_train]]
    train_set_y = [train_set_y[s] for s in sidx[:n_train]]

    return (train_set_x, train_set_y), (valid_set_x, valid_set_y)

class Data():
    def __init__(self, data, shuffle=False, n_node=None):
        self.raw = np.array(data[0], dtype=object)
        H_T = data_masks(self.raw, n_node)
        BH_T = H_T.T.multiply(1.0/H_T.sum(axis=1).reshape(1, -1))
        BH_T = BH_T.T
        H = H_T.T
        DH = H.T.multiply(1.0/H.sum(axis=1).reshape(1, -1))
        DH = DH.T
        DHBH_T = np.dot(DH,BH_T)

        self.adjacency = DHBH_T.tocoo()
        self.n_node = n_node
        self.targets = np.asarray(data[1])
        self.length = len(self.raw)
        self.shuffle = shuffle

    def get_overlap(self, sessions):
        matrix = np.zeros((len(sessions), len(sessions)))
        for i in range(len(sessions)):
            seq_a = set(sessions[i])
            seq_a.discard(0)
            for j in range(i+1, len(sessions)):
                seq_b = set(sessions[j])
                seq_b.discard(0)
                overlap = seq_a.intersection(seq_b)
                ab_set = seq_a | seq_b
                matrix[i][j] = float(len(overlap))/float(len(ab_set))
                matrix[j][i] = matrix[i][j]
        matrix = matrix + np.diag([1.0]*len(sessions))
        degree = np.sum(np.array(matrix), 1)
        degree = np.diag(1.0/degree)
        return matrix, degree

    def get_overlap_tensors(self, sessions, device=None):
        """Jaccard overlap matrix on GPU (nhanh hơn get_overlap CPU)."""
        if device is None:
            device = torch.device('cuda' if torch.cuda.is_available() else 'cpu')
        n = len(sessions)
        if n == 0:
            z = torch.zeros(0, 0, device=device)
            return z, z

        unique_lists = [list(dict.fromkeys(x for x in s if x)) for s in sessions]
        max_u = max((len(u) for u in unique_lists), default=1)
        padded = torch.zeros(n, max_u, dtype=torch.long, device=device)
        mask = torch.zeros(n, max_u, dtype=torch.bool, device=device)
        for i, u in enumerate(unique_lists):
            if u:
                padded[i, : len(u)] = torch.tensor(u, device=device, dtype=torch.long)
                mask[i, : len(u)] = True

        eq = (
            (padded.unsqueeze(1).unsqueeze(3) == padded.unsqueeze(0).unsqueeze(2))
            & mask.unsqueeze(1).unsqueeze(3)
            & mask.unsqueeze(0).unsqueeze(2)
        )
        inter = eq.any(dim=3).sum(dim=2).float()
        sizes = mask.sum(dim=1).float()
        union = sizes.unsqueeze(1) + sizes.unsqueeze(0) - inter
        matrix = torch.zeros(n, n, device=device, dtype=torch.float32)
        valid = union > 0
        matrix[valid] = inter[valid] / union[valid]
        matrix.fill_diagonal_(1.0)
        deg = matrix.sum(dim=1)
        deg = torch.where(deg > 0, deg, torch.ones_like(deg))
        return matrix, torch.diag(1.0 / deg)

    def generate_batch(self, batch_size):
        if self.shuffle:
            shuffled_arg = np.arange(self.length)
            np.random.shuffle(shuffled_arg)
            self.raw = self.raw[shuffled_arg]
            self.targets = self.targets[shuffled_arg]
        n_batch = int(self.length / batch_size)
        if self.length % batch_size != 0:
            n_batch += 1
        slices = np.split(np.arange(n_batch * batch_size), n_batch)
        slices[-1] = np.arange(self.length-batch_size, self.length)
        return slices

    def get_slice(self, index):
        items, num_node = [], []
        inp = self.raw[index]
        for session in inp:
            num_node.append(len(np.nonzero(session)[0]))
        max_n_node = np.max(num_node)
        session_len = []
        reversed_sess_item = []
        mask = []
        for session in inp:
            nonzero_elems = np.nonzero(session)[0]
            session_len.append([len(nonzero_elems)])
            items.append(session + (max_n_node - len(nonzero_elems)) * [0])
            mask.append([1]*len(nonzero_elems) + (max_n_node - len(nonzero_elems)) * [0])
            reversed_sess_item.append(list(reversed(session)) + (max_n_node - len(nonzero_elems)) * [0])


        return self.targets[index]-1, session_len,items, reversed_sess_item, mask
