import os
import sys
import types
import torch
import numpy as np
from scipy import linalg
from tqdm import tqdm
from einops import rearrange
from exit.utils import get_model, generate_src_mask, cosine_schedule, gumbel_sample

try:
    from nlgmetricverse import NLGMetricverse, load_metric
    import nlgmetricverse.metrics._core.base as nlg_base
    import nlgmetricverse.metrics._core.utils as nlg_utils
    from nlgmetricverse.tokenizer import DefaultTokenizer as NLGDefaultTokenizer
    from nlgmetricverse.utils.string import normalize_text as nlg_normalize_text
    from nlgmetricverse.utils.data_structure import NestedSingleType
except ImportError:
    NLGMetricverse = None
    load_metric = None
    nlg_base = None
    nlg_utils = None
    NLGDefaultTokenizer = None
    nlg_normalize_text = None
    NestedSingleType = None
else:
    def _safe_import_module(module_name, filepath):
        module = sys.modules.get(module_name)
        if module is not None and getattr(module, "__file__", None) == filepath:
            return module

        # nlgmetricverse BLEU downloads a tiny external script and imports it
        # via importlib. On this environment the default loader trips over a
        # stale/incompatible bytecode path on Python 3.12, so load from source.
        module = types.ModuleType(module_name)
        module.__file__ = filepath
        with open(filepath, "r", encoding="utf-8") as handle:
            source = handle.read()
        exec(compile(source, filepath, "exec"), module.__dict__)
        sys.modules[module_name] = module
        return module

    nlg_utils.import_module = _safe_import_module
    nlg_base.import_module = _safe_import_module

    def _safe_get_type(cls, obj, order=None):
        _obj = obj
        types = []

        while cls.is_iterable(_obj):
            types.append(type(_obj).__name__)
            if len(_obj) == 0:
                if order is not None:
                    try:
                        return types[order]
                    except IndexError:
                        return None
                return cls.join(types)
            _obj = _obj[0]

        types.append(type(_obj).__name__)

        if order is not None:
            try:
                return types[order]
            except IndexError:
                return None

        return cls.join(types)

    NestedSingleType.get_type = classmethod(_safe_get_type)

try:
    # the bert_score package exposes a `score` function
    from bert_score import score as bert_score
except ImportError:
    bert_score = None

nlg_default_tokenizer = NLGDefaultTokenizer() if NLGDefaultTokenizer is not None else None

os.environ['TOKENIZERS_PARALLELISM'] = 'false'

##### ---- T2M Evaluations ---- #####
def euclidean_distance_matrix(matrix1, matrix2):
    """
        Params:
        -- matrix1: N1 x D
        -- matrix2: N2 x D
        Returns:
        -- dist: N1 x N2
        dist[i, j] == distance(matrix1[i], matrix2[j])
    """
    assert matrix1.shape[1] == matrix2.shape[1]
    d1 = -2 * np.dot(matrix1, matrix2.T)  # shape (num_test, num_train)
    d2 = np.sum(np.square(matrix1), axis=1, keepdims=True)  # shape (num_test, 1)
    d3 = np.sum(np.square(matrix2), axis=1)  # shape (num_train, )
    dists = np.sqrt(d1 + d2 + d3)  # broadcasting
    return dists

def calculate_top_k(mat, top_k):
    size = mat.shape[0]
    gt_mat = np.expand_dims(np.arange(size), 1).repeat(size, 1)
    bool_mat = (mat == gt_mat)
    correct_vec = False
    top_k_list = []
    for i in range(top_k):
        # print(correct_vec, bool_mat[:, i])
        correct_vec = (correct_vec | bool_mat[:, i])
        # print(correct_vec)
        top_k_list.append(correct_vec[:, None])
    top_k_mat = np.concatenate(top_k_list, axis=1)
    return top_k_mat

def calculate_R_precision(embedding1, embedding2, top_k, sum_all=False):
    dist_mat = euclidean_distance_matrix(embedding1, embedding2)
    matching_score = dist_mat.trace()
    argmax = np.argsort(dist_mat, axis=1)
    top_k_mat = calculate_top_k(argmax, top_k)
    if sum_all:
        return top_k_mat.sum(axis=0), matching_score
    else:
        return top_k_mat, matching_score

def calculate_multimodality(activation, multimodality_times):
    assert len(activation.shape) == 3
    assert activation.shape[1] > multimodality_times
    num_per_sent = activation.shape[1]

    first_dices = np.random.choice(num_per_sent, multimodality_times, replace=False)
    second_dices = np.random.choice(num_per_sent, multimodality_times, replace=False)
    dist = linalg.norm(activation[:, first_dices] - activation[:, second_dices], axis=2)
    return dist.mean()

def calculate_diversity(activation, diversity_times):
    assert len(activation.shape) == 2
    assert activation.shape[0] > diversity_times
    num_samples = activation.shape[0]

    first_indices = np.random.choice(num_samples, diversity_times, replace=False)
    second_indices = np.random.choice(num_samples, diversity_times, replace=False)
    dist = linalg.norm(activation[first_indices] - activation[second_indices], axis=1)
    return dist.mean()

def calculate_frechet_distance(mu1, sigma1, mu2, sigma2, eps=1e-6):
    mu1 = np.atleast_1d(mu1)
    mu2 = np.atleast_1d(mu2)

    sigma1 = np.atleast_2d(sigma1)
    sigma2 = np.atleast_2d(sigma2)

    assert mu1.shape == mu2.shape, \
        'Training and test mean vectors have different lengths'
    assert sigma1.shape == sigma2.shape, \
        'Training and test covariances have different dimensions'

    diff = mu1 - mu2

    # Product might be almost singular
    covmean, _ = linalg.sqrtm(sigma1.dot(sigma2), disp=False)
    if not np.isfinite(covmean).all():
        msg = ('fid calculation produces singular product; '
               'adding %s to diagonal of cov estimates') % eps
        print(msg)
        offset = np.eye(sigma1.shape[0]) * eps
        covmean = linalg.sqrtm((sigma1 + offset).dot(sigma2 + offset))

    # Numerical error might give slight imaginary component
    if np.iscomplexobj(covmean):
        if not np.allclose(np.diagonal(covmean).imag, 0, atol=1e-3):
            m = np.max(np.abs(covmean.imag))
            raise ValueError('Imaginary component {}'.format(m))
        covmean = covmean.real

    tr_covmean = np.trace(covmean)

    return (diff.dot(diff) + np.trace(sigma1)
            + np.trace(sigma2) - 2 * tr_covmean)

def calculate_activation_statistics(activations):
    mu = np.mean(activations, axis=0)
    cov = np.cov(activations, rowvar=False)
    return mu, cov

def calculate_frechet_feature_distance(feature_list1, feature_list2):
    feature_list1 = np.stack(feature_list1)
    feature_list2 = np.stack(feature_list2)

    # normalize the scale
    mean = np.mean(feature_list1, axis=0)
    std = np.std(feature_list1, axis=0) + 1e-10
    feature_list1 = (feature_list1 - mean) / std
    feature_list2 = (feature_list2 - mean) / std

    dist = calculate_frechet_distance(
        mu1=np.mean(feature_list1, axis=0),
        sigma1=np.cov(feature_list1, rowvar=False),
        mu2=np.mean(feature_list2, axis=0),
        sigma2=np.cov(feature_list2, rowvar=False),
    )
    return dist


def _forward_bitm(model, token_ids_t, token_ids_m, seq_mask_t, seq_mask_m, mode=None, motion_ids_for_text=None):
    if mode is not None and getattr(get_model(model), 'supports_strict_ar', False):
        kwargs = {'mode': mode}
        if motion_ids_for_text is not None:
            kwargs['motion_ids_for_text'] = motion_ids_for_text
        return model(token_ids_t, token_ids_m, seq_mask_t, seq_mask_m, **kwargs)
    return model(token_ids_t, token_ids_m, seq_mask_t, seq_mask_m)


def inference_t2m(model, lens_m: torch.Tensor, token_ids_t, seq_mask_t, seq_mask_m, seq_mask_no_end_m,
             special_ids_m, max_length, shape, rand_pos=True, token_cond=None, max_steps=10):
    # init sampling score
    scores = torch.ones(shape, dtype=torch.float32, device=lens_m.device)

    # init motion token ids
    if token_cond is not None:  # has partial condition
        token_ids_m = token_cond.clone()
        token_ids_m[~seq_mask_no_end_m] = special_ids_m['pad_id']
        num_token_cond = (token_ids_m == special_ids_m['mask_id']).sum(-1)
    else:  # start from full mask
        token_ids_m = torch.full(shape, special_ids_m['mask_id'], dtype=torch.long, device=lens_m.device)

    sample_max_steps = torch.round(max_steps / max_length * lens_m) + 1e-8
    for step in range(max_steps):
        timestep = torch.clip(step / sample_max_steps, max=1)
        if len(lens_m) == 1 and step > 0 and torch.clip((step - 1) / sample_max_steps, max=1).cpu().item() == timestep:
            break
        rand_mask_prob = cosine_schedule(timestep)
        num_token_masked = (rand_mask_prob * lens_m).long().clip(min=1)

        if token_cond is not None:
            num_token_masked = (rand_mask_prob * num_token_cond).long().clip(min=1)
            scores[token_cond != special_ids_m['mask_id']] = 0

        # remove no motion frames
        scores[~seq_mask_no_end_m] = 0
        scores = scores / scores.sum(-1)[:, None]  # normalize only unmasked token

        _, sorted_score_indices = scores.sort(descending=True)  # deterministic

        token_ids_m[~seq_mask_m] = special_ids_m['pad_id']  # replace with pad id
        token_ids_m.scatter_(-1, lens_m[..., None].long(), special_ids_m['end_id'])  # replace with end id

        # replace "mask_id" to "ids" that have highest "num_token_masked" "scores"
        select_masked_indices = generate_src_mask(sorted_score_indices.shape[1], num_token_masked)
        # repeat last_id to make it scatter_ the existing last ids
        last_index = sorted_score_indices.gather(-1, num_token_masked.unsqueeze(-1) - 1)
        sorted_score_indices = sorted_score_indices * select_masked_indices + (last_index * ~select_masked_indices)
        token_ids_m.scatter_(-1, sorted_score_indices, special_ids_m['mask_id'])

        logits = _forward_bitm(model, token_ids_t, token_ids_m, seq_mask_t, seq_mask_m, mode='motion')

        if rand_pos:
            temperature = 1  # starting_temperature * (steps_until_x0 / timesteps)  # temperature is annealed
        else:
            temperature = 0  # starting_temperature * (steps_until_x0 / timesteps)  # temperature is annealed

        # if temperature == 0, it is equal to argmax (pred_ids = pred_m.argmax(dim=-1))
        pred_ids_m = gumbel_sample(logits['logits_m'], temperature=temperature, dim=-1)
        is_mask = token_ids_m == special_ids_m['mask_id']

        token_ids_m = torch.where(is_mask, pred_ids_m, token_ids_m)

        # Update score
        probs_without_temperature = logits['logits_m'].softmax(dim=-1)
        scores = 1 - probs_without_temperature.gather(-1, pred_ids_m[..., None])
        scores = rearrange(scores, '... 1 -> ...')
        scores = scores.masked_fill(~is_mask, 0)

    return token_ids_m

@torch.no_grad()
def eval_bitm_t2m(out_dir, val_loader, net, bitm, logger, writer, nb_iter, eval_wrapper, special_ids_m, max_m,
                  best_iter=0, best_fid=1000, best_div=100, best_top1=0, best_top2=0, best_top3=0, best_matching=100,
                  draw=True, save=True, num_repeat=1, rand_pos=False):
    if num_repeat < 0:  # evaluate all generations
        is_avg_all = True
        num_repeat = -num_repeat
    else:  # evaluate last generation
        is_avg_all = False

    bitm.eval()
    nb_sample = 0
    motion_annotation_list = []
    motion_pred_list = []
    motion_multimodality = []
    R_precision_real = 0.
    R_precision = 0.
    matching_score_real = 0.
    matching_score_pred = 0.

    for batch in tqdm(val_loader, position=1, leave=True):
        # BiTM text eval may append multi-reference captions; T2M only needs the
        # original first 9 fields, so keep this path backward-compatible.
        word_embeddings, pos_one_hots, sent_len, _, pose, m_length, token_ids_t, seq_mask_t, _ = batch[:9]
        bs, seq = pose.shape[:2]
        lens_m = torch.ceil(m_length / 4).long()
        pred_len = m_length.cuda()

        # generate target token masks
        seq_mask_m = generate_src_mask(max_m, lens_m + 1)
        seq_mask_no_end_m = generate_src_mask(max_m, lens_m)

        motion_multimodality_batch = []

        for i in range(num_repeat):
            index_motion = inference_t2m(bitm,
                                         lens_m=lens_m.cuda(),
                                         token_ids_t=token_ids_t.cuda(),
                                         seq_mask_t=seq_mask_t.cuda(),
                                         seq_mask_m=seq_mask_m.cuda(),
                                         seq_mask_no_end_m=seq_mask_no_end_m.cuda(),
                                         special_ids_m=special_ids_m,
                                         max_length=max_m - 1,
                                         shape=(bs, max_m),
                                         rand_pos=rand_pos)  # (bs, max_m)

            # [INFO] need to run single sample at a time because it's conv
            pred_pose_eval = torch.zeros(pose.shape).cuda()
            for k in range(bs):
                # [INFO] Eval by m_length
                pred_pose = net(index_motion[k:k + 1, :lens_m[k].item()], type='decode')  # (1, m_length, dim_m)
                pred_pose_eval[k:k + 1, :pred_len[k].item()] = pred_pose  # (bs, m_length, dim_m)

            et_pred, em_pred = eval_wrapper.get_co_embeddings(word_embeddings, pos_one_hots, sent_len, pred_pose_eval, m_length)

            motion_multimodality_batch.append(em_pred.reshape(bs, 1, -1))

            if i == 0 or is_avg_all:
                pose = pose.cuda().float()

                et, em = eval_wrapper.get_co_embeddings(word_embeddings, pos_one_hots, sent_len, pose, m_length)
                motion_annotation_list.append(em)
                motion_pred_list.append(em_pred)

                temp_R, temp_match = calculate_R_precision(et.cpu().numpy(), em.cpu().numpy(), top_k=3, sum_all=True)
                R_precision_real += temp_R
                matching_score_real += temp_match

                temp_R, temp_match = calculate_R_precision(et_pred.cpu().numpy(), em_pred.cpu().numpy(), top_k=3, sum_all=True)
                R_precision += temp_R
                matching_score_pred += temp_match

                nb_sample += bs

        motion_multimodality.append(torch.cat(motion_multimodality_batch, dim=1))

    motion_annotation_np = torch.cat(motion_annotation_list, dim=0).cpu().numpy()
    motion_pred_np = torch.cat(motion_pred_list, dim=0).cpu().numpy()
    gt_mu, gt_cov = calculate_activation_statistics(motion_annotation_np)
    mu, cov = calculate_activation_statistics(motion_pred_np)

    diversity_real = calculate_diversity(motion_annotation_np, 300 if nb_sample > 300 else 100)
    diversity = calculate_diversity(motion_pred_np, 300 if nb_sample > 300 else 100)

    R_precision_real = R_precision_real / nb_sample
    R_precision = R_precision / nb_sample

    matching_score_real = matching_score_real / nb_sample
    matching_score_pred = matching_score_pred / nb_sample

    multimodality = 0
    motion_multimodality = torch.cat(motion_multimodality, dim=0).cpu().numpy()
    if num_repeat > 1:
        multimodality = calculate_multimodality(motion_multimodality, 10)

    fid = calculate_frechet_distance(gt_mu, gt_cov, mu, cov)

    msg = f"--> \t Eva. Iter {nb_iter} :, \n\
                FID. {fid:.4f} , \n\
                Diversity Real. {diversity_real:.4f}, \n\
                Diversity. {diversity:.4f}, \n\
                R_precision_real. {R_precision_real}, \n\
                R_precision. {R_precision}, \n\
                matching_score_real. {matching_score_real}, \n\
                matching_score_pred. {matching_score_pred}, \n\
                multimodality. {multimodality:.4f}"
    logger.info(msg)

    if draw:
        writer.add_scalar('./Test/FID', fid, nb_iter)
        writer.add_scalar('./Test/Diversity', diversity, nb_iter)
        writer.add_scalar('./Test/top1', R_precision[0], nb_iter)
        writer.add_scalar('./Test/top2', R_precision[1], nb_iter)
        writer.add_scalar('./Test/top3', R_precision[2], nb_iter)
        writer.add_scalar('./Test/matching_score', matching_score_pred, nb_iter)
        writer.add_scalar('./Test/multimodality', multimodality, nb_iter)

    if fid < best_fid:
        msg = f"--> --> \t FID Improved from {best_fid:.5f} to {fid:.5f} !!!"
        logger.info(msg)
        best_fid, best_iter = fid, nb_iter

    if matching_score_pred < best_matching:
        msg = f"--> --> \t Matching Score Improved from {best_matching:.5f} to {matching_score_pred:.5f} !!!"
        logger.info(msg)
        best_matching = matching_score_pred

    if abs(diversity_real - diversity) < abs(diversity_real - best_div):
        msg = f"--> --> \t Diversity Improved from {best_div:.5f} to {diversity:.5f} !!!"
        logger.info(msg)
        best_div = diversity

    if R_precision[0] > best_top1:
        msg = f"--> --> \t Top1 Improved from {best_top1:.4f} to {R_precision[0]:.4f} !!!"
        logger.info(msg)
        best_top1 = R_precision[0]

    if R_precision[1] > best_top2:
        msg = f"--> --> \t Top2 Improved from {best_top2:.4f} to {R_precision[1]:.4f} !!!"
        logger.info(msg)
        best_top2 = R_precision[1]

    if R_precision[2] > best_top3:
        msg = f"--> --> \t Top3 Improved from {best_top3:.4f} to {R_precision[2]:.4f} !!!"
        logger.info(msg)
        best_top3 = R_precision[2]

    if save:
        torch.save({'bitm': get_model(bitm).state_dict()}, os.path.join(out_dir, 'net_last.pth'))

    bitm.train()
    return best_iter, best_fid, best_div, best_top1, best_top2, best_top3, best_matching, multimodality

##### ---- M2T Evaluations ---- #####
def decode_token_ids(token_ids, tokenizer, eos_id):
    if hasattr(token_ids, 'tolist'):
        token_ids = token_ids.tolist()

    batch_tokens = []
    for row in token_ids:
        if eos_id in row:
            batch_tokens.append(row[:row.index(eos_id)])
        else:
            batch_tokens.append(row)

    return tokenizer.batch_decode(batch_tokens, skip_special_tokens=True, clean_up_tokenization_spaces=True)

def prepare_text_metric_inputs(predictions, references):
    clean_predictions = []
    clean_references = []
    skipped = 0

    for pred, refs in zip(predictions, references):
        pred = "" if pred is None else pred.strip()
        if nlg_default_tokenizer is not None:
            pred_tokens = nlg_default_tokenizer.tokenize(pred)
        else:
            pred_norm = pred if nlg_normalize_text is None else nlg_normalize_text(pred)
            pred_tokens = pred_norm.split()

        refs = [] if refs is None else list(refs)
        clean_refs = []
        for ref in refs:
            if ref is None:
                continue
            ref = ref.strip()
            if not ref:
                continue
            if nlg_default_tokenizer is not None:
                ref_tokens = nlg_default_tokenizer.tokenize(ref)
            else:
                ref_norm = ref if nlg_normalize_text is None else nlg_normalize_text(ref)
                ref_tokens = ref_norm.split()
            if not ref_tokens:
                continue
            clean_refs.append(ref)

        # Filter using the same tokenizer nlgmetricverse BLEU uses internally.
        # This removes strings that look non-empty but become empty token lists
        # after punctuation normalization, e.g. "." or "!!!".
        if not pred_tokens or len(clean_refs) == 0:
            skipped += 1
            continue

        clean_predictions.append(pred)
        clean_references.append(clean_refs)

    return clean_predictions, clean_references, skipped

def inference_m2t(model, lens_t: torch.Tensor, token_ids_m, seq_mask_m, seq_mask_t, seq_mask_no_end_t,
             special_ids_t, max_length, shape, rand_pos=True, token_cond=None, max_steps=10):
    # init sampling score
    scores = torch.ones(shape, dtype=torch.float32, device=lens_t.device)

    # init text token ids
    if token_cond is not None:  # has partial condition
        token_ids_t = token_cond.clone()
        token_ids_t[~seq_mask_no_end_t] = special_ids_t['pad_id']
        num_token_cond = (token_ids_t == special_ids_t['mask_id']).sum(-1)
    else:  # start from full mask
        token_ids_t = torch.full(shape, special_ids_t['mask_id'], dtype=torch.long, device=lens_t.device)
        token_ids_t[:, 0] = special_ids_t['cls_id']  # add [CLS] token for text

    sample_max_steps = torch.round(max_steps / max_length * lens_t) + 1e-8
    for step in range(max_steps):
        timestep = torch.clip(step / sample_max_steps, max=1)
        if len(lens_t) == 1 and step > 0 and torch.clip((step - 1) / sample_max_steps, max=1).cpu().item() == timestep:
            break
        rand_mask_prob = cosine_schedule(timestep)
        num_token_masked = (rand_mask_prob * lens_t).long().clip(min=1)

        if token_cond is not None:
            num_token_masked = (rand_mask_prob * num_token_cond).long().clip(min=1)
            scores[token_cond != special_ids_t['mask_id']] = 0

        # Set sampling score to 0 for [PAD] and [CLS]
        scores[~seq_mask_no_end_t] = 0
        scores[:, 0] = 0
        scores = scores / scores.sum(-1)[:, None]  # normalize only unmasked token

        _, sorted_score_indices = scores.sort(descending=True)  # deterministic

        token_ids_t[~seq_mask_t] = special_ids_t['pad_id']  # replace with pad id
        token_ids_t.scatter_(-1, lens_t[..., None].long(), special_ids_t['eos_id'])  # replace with end id

        # replace "mask_id" to "ids" that have highest "num_token_masked" "scores"
        select_masked_indices = generate_src_mask(sorted_score_indices.shape[1], num_token_masked)
        # repeat last_id to make it scatter_ the existing last ids
        last_index = sorted_score_indices.gather(-1, num_token_masked.unsqueeze(-1) - 1)
        sorted_score_indices = sorted_score_indices * select_masked_indices + (last_index * ~select_masked_indices)
        token_ids_t.scatter_(-1, sorted_score_indices, special_ids_t['mask_id'])

        logits = model(token_ids_t, token_ids_m, seq_mask_t, seq_mask_m)

        if rand_pos:
            temperature = 1  # starting_temperature * (steps_until_x0 / timesteps)  # temperature is annealed
        else:
            temperature = 0  # starting_temperature * (steps_until_x0 / timesteps)  # temperature is annealed

        # if temperature == 0, it is equal to argmax (pred_ids = pred_t.argmax(dim=-1))
        pred_ids_t = gumbel_sample(logits['logits_t'], temperature=temperature, dim=-1)
        is_mask = token_ids_t == special_ids_t['mask_id']

        token_ids_t = torch.where(is_mask, pred_ids_t, token_ids_t)

        # Update score
        probs_without_temperature = logits['logits_t'].softmax(dim=-1)
        scores = 1 - probs_without_temperature.gather(-1, pred_ids_t[..., None])
        scores = rearrange(scores, '... 1 -> ...')
        scores = scores.masked_fill(~is_mask, 0)

    return token_ids_t


def inference_m2t_ar(model, token_ids_m, seq_mask_m, special_ids_t, max_t, rand_pos=True):
    batch_size = token_ids_m.shape[0]
    device = token_ids_m.device
    bitm = get_model(model)
    token_ids_t = torch.full(
        (batch_size, max_t),
        special_ids_t['pad_id'],
        dtype=torch.long,
        device=device
    )
    seq_mask_t = torch.zeros((batch_size, max_t), dtype=torch.bool, device=device)
    token_ids_t[:, 0] = special_ids_t['cls_id']
    seq_mask_t[:, 0] = True
    finished = torch.zeros(batch_size, dtype=torch.bool, device=device)

    temperature = 1 if rand_pos else 0
    use_ar_cache = (
        getattr(bitm, 'supports_ar_cache', False)
        and callable(getattr(bitm, 'init_text_ar_cache', None))
        and callable(getattr(bitm, 'forward_text_ar_cached_step', None))
    )
    past_key_values = bitm.init_text_ar_cache(token_ids_m, seq_mask_m, text_len=max_t) if use_ar_cache else None
    for step in range(max_t - 1):
        if use_ar_cache:
            cached_outputs = bitm.forward_text_ar_cached_step(
                token_ids_t[:, step],
                text_position=step,
                motion_mask=seq_mask_m,
                text_key_mask=seq_mask_t[:, :step + 1],
                past_key_values=past_key_values
            )
            past_key_values = cached_outputs['past_key_values']
            step_logits = cached_outputs['logits_t']
        else:
            logits = _forward_bitm(
                model,
                token_ids_t,
                token_ids_m,
                seq_mask_t,
                seq_mask_m,
                mode='text'
            )
            step_logits = logits['logits_t'][:, step, :]

        next_token = gumbel_sample(step_logits, temperature=temperature, dim=-1)
        next_token = torch.where(finished, torch.full_like(next_token, special_ids_t['pad_id']), next_token)

        next_pos = step + 1
        token_ids_t[:, next_pos] = next_token
        seq_mask_t[:, next_pos] = ~finished
        finished = finished | (next_token == special_ids_t['eos_id'])
        if finished.all():
            break

    return token_ids_t


@torch.no_grad()
def eval_bitm_m2t(out_dir, val_loader, bitm, logger, writer, nb_iter, tokenizer, special_ids_t, invalid_ids, max_m, max_t,
                  best_iter=0., best_bleu1=0., best_bleu2=0., best_bleu3=0., best_bleu4=0., best_rouge_l=0.,
                  best_cider=0., best_bert_f1=0.,
                  draw=True, save=True, num_repeat=1, rand_pos=False, autoregressive=False):
    if num_repeat < 0:  # evaluate all generations
        is_avg_all = True
        num_repeat = -num_repeat
    else:  # evaluate last generation
        is_avg_all = False

    if NLGMetricverse is None or load_metric is None:
        raise ImportError("BiTM m2t eval now requires nlgmetricverse to match MotionGPT-style NLP metrics.")
    if bert_score is None:
        raise ImportError("BiTM m2t eval now requires bert_score to match MotionGPT-style BERT-F1.")
    if autoregressive and not getattr(get_model(bitm), 'supports_strict_ar', False):
        raise ValueError("autoregressive=True requires a strict-AR BiTM model.")

    nlg_evaluator = NLGMetricverse([
        load_metric("bleu", resulting_name="bleu_1", compute_kwargs={"max_order": 1}),
        load_metric("bleu", resulting_name="bleu_2", compute_kwargs={"max_order": 2}),
        load_metric("bleu", resulting_name="bleu_3", compute_kwargs={"max_order": 3}),
        load_metric("bleu", resulting_name="bleu_4", compute_kwargs={"max_order": 4}),
        load_metric("rouge"),
        load_metric("cider"),
    ])

    bitm.eval()
    all_pred_text = []
    all_reference_texts = []

    for batch in tqdm(val_loader, position=2, leave=True):
        word_embeddings, pos_one_hots, sent_len, token_ids_m, pose, m_length, token_ids_t, seq_mask_t, captions, all_captions = batch
        bs, seq = pose.shape[:2]
        lens_m = torch.ceil(m_length / 4).long()

        # Get motion mask
        seq_mask_m = generate_src_mask(max_m, lens_m + 1)
        if not autoregressive:
            # Restore the previous oracle-length evaluation so we can isolate the
            # metric-protocol change from the generation-length change.
            t_valid_mask = ~torch.isin(token_ids_t.cuda(), torch.tensor(invalid_ids).cuda())
            lens_t = t_valid_mask.sum(dim=1)
            seq_mask_eval_t = generate_src_mask(max_t, lens_t + 1)
            seq_mask_no_end_t = generate_src_mask(max_t, lens_t)

        for i in range(num_repeat):
            if autoregressive:
                index_text = inference_m2t_ar(bitm,
                                              token_ids_m=token_ids_m.cuda(),
                                              seq_mask_m=seq_mask_m.cuda(),
                                              special_ids_t=special_ids_t,
                                              max_t=max_t,
                                              rand_pos=rand_pos)  # (bs, max_t)
            else:
                index_text = inference_m2t(bitm,
                                           lens_t=lens_t.cuda(),
                                           token_ids_m=token_ids_m.cuda(),
                                           seq_mask_m=seq_mask_m.cuda(),
                                           seq_mask_t=seq_mask_eval_t.cuda(),
                                           seq_mask_no_end_t=seq_mask_no_end_t.cuda(),
                                           special_ids_t=special_ids_t,
                                           max_length=max_t - 1,
                                           shape=(bs, max_t),
                                           rand_pos=rand_pos)  # (bs, max_t)
            pred_text = decode_token_ids(index_text, tokenizer, eos_id=special_ids_t['eos_id'])

            if i == 0 or is_avg_all:
                all_pred_text.extend(pred_text)
                all_reference_texts.extend(all_captions)

    metric_pred_text, metric_reference_texts, skipped_empty = prepare_text_metric_inputs(all_pred_text, all_reference_texts)

    if skipped_empty > 0:
        logger.info(f"--> \t Skipped {skipped_empty} empty text-eval samples before metric computation.")

    if len(metric_pred_text) == 0:
        logger.info("--> \t No valid text-eval samples remained after filtering empty predictions/references.")
        bleu1 = bleu2 = bleu3 = bleu4 = 0.
        rouge_l = 0.
        cider_score = 0.
        bert_f1 = 0.
    else:
        scores = nlg_evaluator(predictions=metric_pred_text, references=metric_reference_texts)
        bleu1 = scores["bleu_1"]["score"]
        bleu2 = scores["bleu_2"]["score"]
        bleu3 = scores["bleu_3"]["score"]
        bleu4 = scores["bleu_4"]["score"]
        rouge_l = scores["rouge"]["rougeL"]
        cider_score = scores["cider"]["score"]

        _, _, bert_f1_tensor = bert_score(
            metric_pred_text,
            metric_reference_texts,
            lang="en",
            rescale_with_baseline=True,
            idf=True,
            verbose=False
        )
        bert_f1 = bert_f1_tensor.mean().item()

    msg = f"--> \t Eva. Iter {nb_iter} :, \n\
                bleu1. {bleu1}, \n\
                bleu2. {bleu2}, \n\
                bleu3. {bleu3}, \n\
                bleu4. {bleu4}, \n\
                rouge_l. {rouge_l:.4f}, \n\
                cidEr. {cider_score:.4f}, \n\
                bert_f1. {bert_f1:.4f}"

    logger.info(msg)

    if draw:
        writer.add_scalar('./Test/bleu1', bleu1, nb_iter)
        writer.add_scalar('./Test/bleu2', bleu2, nb_iter)
        writer.add_scalar('./Test/bleu3', bleu3, nb_iter)
        writer.add_scalar('./Test/bleu4', bleu4, nb_iter)
        writer.add_scalar('./Test/rouge_l', rouge_l, nb_iter)
        writer.add_scalar('./Test/cider', cider_score, nb_iter)
        writer.add_scalar('./Test/bert_f1', bert_f1, nb_iter)

    if bleu1 > best_bleu1:
        msg = f"--> --> \t BLEU1 Improved from {best_bleu1:.4f} to {bleu1:.4f} !!!"
        logger.info(msg)
        best_bleu1 = bleu1

    if bleu2 > best_bleu2:
        msg = f"--> --> \t BLEU2 Improved from {best_bleu2:.4f} to {bleu2:.4f} !!!"
        logger.info(msg)
        best_bleu2 = bleu2

    if bleu3 > best_bleu3:
        msg = f"--> --> \t BLEU3 Improved from {best_bleu3:.4f} to {bleu3:.4f} !!!"
        logger.info(msg)
        best_bleu3 = bleu3

    if bleu4 > best_bleu4:
        msg = f"--> --> \t BLEU4 Improved from {best_bleu4:.4f} to {bleu4:.4f} !!!"
        logger.info(msg)
        best_bleu4, best_iter = bleu4, nb_iter

    if rouge_l > best_rouge_l:
        msg = f"--> --> \t ROUGE-L Improved from {best_rouge_l:.4f} to {rouge_l:.4f} !!!"
        logger.info(msg)
        best_rouge_l = rouge_l

    if cider_score > best_cider:
        msg = f"--> -->\t CIDEr Improved from {best_cider:.4f} to {cider_score:.4f} !!!"
        logger.info(msg)
        best_cider = cider_score

    if bert_f1 > best_bert_f1:
        msg = f"--> -->\t BERT-F1 Improved from {best_bert_f1:.4f} to {bert_f1:.4f} !!!"
        logger.info(msg)
        best_bert_f1 = bert_f1

    if save:
        torch.save({'bitm': get_model(bitm).state_dict()}, os.path.join(out_dir, 'net_last_t.pth'))

    bitm.train()
    return best_iter, best_bleu1, best_bleu2, best_bleu3, best_bleu4, best_rouge_l, best_cider, best_bert_f1
