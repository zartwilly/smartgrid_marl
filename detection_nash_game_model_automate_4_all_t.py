# -*- coding: utf-8 -*-
"""
Created on Mon Mar  8 11:55:58 2021

@author: jwehounou
"""
import os
import time

import numpy as np
import pandas as pd
import smartgrids_players as players
import fonctions_auxiliaires as fct_aux
import itertools as it

import force_brute_game_model_automate_4_all_t as autoBfGameModel4T

from pathlib import Path

###############################################################################
#                   definition  des fonctions annexes
#
###############################################################################
# ____________          turn dico in2 df  --> debut             ______________
def turn_dico_stats_res_into_df_NASH(dico_stats_res_algo, path_to_save, 
                                     t_periods=2, 
                                     manual_debug=True, 
                                     algo_name="BEST-NASH"):
    """
    transform the dico in the row dico_nash_profils into a DataFrame

    Parameters
    ----------
    path_to_variable : TYPE
        DESCRIPTION.
        

    Returns
    -------
    None.

    """
    df = None
    for t in range(0,t_periods):
        dico_nash = dico_stats_res_algo[t]["dico_nash_profils"]
        df_t = pd.DataFrame.from_dict(dico_nash, orient='columns')
        if df is None:
            df = df_t.copy()
        else:
            df = pd.concat([df, df_t], axis=0)
            
    # save df to xlsx
    df.to_excel(os.path.join(*[path_to_save,
                               "{}_dico_NASH.xlsx".format(algo_name)]), 
                index=True)

# ____________          turn dico in2 df  --> fin               ______________

# ____________        checkout NASH equilibrium --> debut        ______________
# def checkout_nash_4_profils_by_periods(arr_pl_M_T_vars_modif,
#                                         arr_pl_M_T_vars,
#                                         pi_hp_plus, pi_hp_minus, 
#                                         pi_0_minus_t, pi_0_plus_t, 
#                                         ben_csts_M_t,
#                                         t,
#                                         manual_debug):
#     """
#     verify if the profil at time t and k_stop_learning is a Nash equilibrium.
#     """
#     # create a result dataframe of checking players' stability and nash equilibrium
#     cols = ["players", "nash_modes_t{}".format(t), 'states_t{}'.format(t), 
#             'Vis_t{}'.format(t), 'Vis_bar_t{}'.format(t), 
#                'res_t{}'.format(t)] 
    
#     m_players = arr_pl_M_T_vars_modif.shape[0]
#     id_players = list(range(0, m_players))
#     df_nash_t = pd.DataFrame(index=id_players, columns=cols)
    
#     # revert Si to the initial value ie at t and k=0
#     Sis = arr_pl_M_T_vars[:, t,
#                           fct_aux.AUTOMATE_INDEX_ATTRS["Si"]]
#     arr_pl_M_T_vars_modif[:, t,
#                             fct_aux.AUTOMATE_INDEX_ATTRS["Si"]] = Sis
    
#     # stability of each player
#     modes_profil = list(arr_pl_M_T_vars_modif[
#                             :, t,
#                             fct_aux.AUTOMATE_INDEX_ATTRS["mode_i"]] )
#     for num_pl_i in range(0, m_players):
#         state_i = arr_pl_M_T_vars_modif[
#                         num_pl_i, t,
#                         fct_aux.AUTOMATE_INDEX_ATTRS["state_i"]] 
#         mode_i = modes_profil[num_pl_i]
#         mode_i_bar = fct_aux.find_out_opposite_mode(state_i, mode_i)
        
#         opposite_modes_profil = modes_profil.copy()
#         opposite_modes_profil[num_pl_i] = mode_i_bar
#         opposite_modes_profil = tuple(opposite_modes_profil)
        
#         df_nash_t.loc[num_pl_i, "players"] = fct_aux.RACINE_PLAYER+"_"+str(num_pl_i)
#         df_nash_t.loc[num_pl_i, "nash_modes_t{}".format(t)] = mode_i
#         df_nash_t.loc[num_pl_i, "states_t{}".format(t)] = state_i
        
#         random_mode = False
#         arr_pl_M_T_K_vars_modif_mode_prof_BAR, \
#         b0_t_k_bar, c0_t_k_bar, \
#         bens_t_k_bar, csts_t_k_bar, \
#         dico_gamma_players_t_k \
#             = fct_aux.balanced_player_game_t_4_mode_profil_prices_SG(
#                     arr_pl_M_T_vars_modif.copy(), 
#                     opposite_modes_profil,
#                     t, 
#                     pi_hp_plus, pi_hp_minus, 
#                     pi_0_plus_t, pi_0_minus_t,
#                     random_mode,
#                     manual_debug, dbg=False)
        
#         Vi = ben_csts_M_t[num_pl_i]
#         bens_csts_t_k_bar = bens_t_k_bar - csts_t_k_bar
#         Vi_bar = bens_csts_t_k_bar[num_pl_i]
    
#         df_nash_t.loc[num_pl_i, 'Vis_t{}'.format(t)] = Vi
#         df_nash_t.loc[num_pl_i, 'Vis_bar_t{}'.format(t)] = Vi_bar
#         res = None
#         if Vi >= Vi_bar:
#             res = "STABLE"
#             df_nash_t.loc[num_pl_i, 'res_t{}'.format(t)] = res
#         else:
#             res = "INSTABLE"
#             df_nash_t.loc[num_pl_i, 'res_t{}'.format(t)] = res   
            
#     return df_nash_t
# # ____________        checkout NASH equilibrium --> fin         ______________

# __________         detection of NASH EQUILIBRIUM   ---> debut        ________
def detect_nash_balancing_profil(dico_profs_Vis_Perf_t, 
                                 arr_pl_M_T_vars_modif, t):
    """
    detect the profil driving to nash equilibrium
    
    dico_profs_Vis_Perf_t[tuple_prof] = dico_Vis_Pref_t with
        * tuple_prof = (S1, ...., Sm), Si is the strategie of player i
        * dico_Vis_Pref_t has keys "Pref_t" and RACINE_PLAYER+"_"+i
            * the value of "Pref_t" is \sum\limits_{1\leq i \leq N}ben_i-cst_i
            * the value of RACINE_PLAYER+"_"+i is Vi = ben_i - cst_i
            * NB : 0 <= i < m_players or  i \in [0, m_player[
    """
    nash_profils = list()
    dico_nash_profils = dict()
    cpt_nash = 0
    for key_modes_prof, dico_Vi_Pref_t in dico_profs_Vis_Perf_t.items():
        cpt_players_stables = 0
        dico_profils = dict()
        for num_pl_i, mode_i in enumerate(key_modes_prof):                      # 0 <= num_pl_i < m_player            
            Vi, ben_i, cst_i = dico_Vi_Pref_t[fct_aux.RACINE_PLAYER\
                                              +"_"+str(num_pl_i)]
            state_i = arr_pl_M_T_vars_modif[num_pl_i, t, 
                                      fct_aux.AUTOMATE_INDEX_ATTRS["state_i"]]
            gamma_i = arr_pl_M_T_vars_modif[num_pl_i, t, 
                                    fct_aux.AUTOMATE_INDEX_ATTRS["gamma_i"]]
            setx = arr_pl_M_T_vars_modif[num_pl_i, t, 
                                    fct_aux.AUTOMATE_INDEX_ATTRS["set"]]
            prod_i = arr_pl_M_T_vars_modif[num_pl_i, t, 
                                    fct_aux.AUTOMATE_INDEX_ATTRS["prod_i"]]
            cons_i = arr_pl_M_T_vars_modif[num_pl_i, t, 
                                    fct_aux.AUTOMATE_INDEX_ATTRS["cons_i"]]
            r_i = arr_pl_M_T_vars_modif[num_pl_i, t, 
                                    fct_aux.AUTOMATE_INDEX_ATTRS["r_i"]]
            mode_i_bar = None
            mode_i_bar = fct_aux.find_out_opposite_mode(state_i, mode_i)
            new_key_modes_prof = list(key_modes_prof)
            new_key_modes_prof[num_pl_i] = mode_i_bar
            new_key_modes_prof = tuple(new_key_modes_prof)
            
            Vi_bar = None
            Vi_bar, ben_i_bar, cst_i_bar \
                = dico_profs_Vis_Perf_t[new_key_modes_prof]\
                                          [fct_aux.RACINE_PLAYER+"_"+str(num_pl_i)]
            if Vi >= Vi_bar:
                cpt_players_stables += 1
            dico_profils[fct_aux.RACINE_PLAYER+"_"+str(num_pl_i)+"_t_"+str(t)] \
                = {"set":setx, "state":state_i, "mode_i":mode_i, "Vi":Vi, 
                   "gamma_i":gamma_i, "prod":prod_i, "cons":cons_i, "r_i":r_i,
                   "ben":ben_i, "cst":cst_i}
            
        if cpt_players_stables == len(key_modes_prof):
            nash_profils.append(key_modes_prof)
            Perf_t = dico_profs_Vis_Perf_t[key_modes_prof]["Perf_t"]
            dico_profils["Perf_t"] = Perf_t
            dico_nash_profils["NASH_"+str(cpt_nash)] = (dico_profils)
            cpt_nash += 1
                
    return nash_profils, dico_nash_profils
# __________         detection of NASH EQUILIBRIUM   ---> fin          ________



# __________       main function of NASH EQUILIBRIUM   ---> debut      ________
def nash_balanced_player_game_perf_t_USE_DICT_MODE_PROFIL(
                                arr_pl_M_T_vars_init,
                                pi_hp_plus=0.2, 
                                pi_hp_minus=0.33,
                                path_to_save="tests", 
                                manual_debug=False, 
                                dbg=False):
    
    print("\n \n game: {}, pi_hp_minus ={} ---> debut \n"\
          .format(pi_hp_plus, pi_hp_minus))
        
    m_players = arr_pl_M_T_vars_init.shape[0]
    t_periods = arr_pl_M_T_vars_init.shape[1]
    
    # _______ variables' initialization --> debut ________________
    pi_sg_plus_t, pi_sg_minus_t = 0, 0
    pi_sg_plus_T = np.empty(shape=(t_periods,))                                 # shape (T_PERIODS,)
    pi_sg_plus_T.fill(np.nan)
    pi_sg_minus_T = np.empty(shape=(t_periods,))                                # shape (T_PERIODS,)
    pi_sg_plus_T.fill(np.nan)
    pi_0_plus_t, pi_0_minus_t = 0, 0
    pi_0_plus_T = np.empty(shape=(t_periods,))                                  # shape (T_PERIODS,)
    pi_0_plus_T.fill(np.nan)
    pi_0_minus_T = np.empty(shape=(t_periods,))                                 # shape (T_PERIODS,)
    pi_0_minus_T.fill(np.nan)
    B_is_M = np.empty(shape=(m_players,))                                       # shape (M_PLAYERS, )
    B_is_M.fill(np.nan)
    C_is_M = np.empty(shape=(m_players,))                                       # shape (M_PLAYERS, )
    C_is_M.fill(np.nan)
    b0_ts_T = np.empty(shape=(t_periods,))                                      # shape (T_PERIODS,)
    b0_ts_T.fill(np.nan)
    c0_ts_T = np.empty(shape=(t_periods,))
    c0_ts_T.fill(np.nan)
    BENs_M_T = np.empty(shape=(m_players, t_periods))                           # shape (M_PLAYERS, T_PERIODS)
    CSTs_M_T = np.empty(shape=(m_players, t_periods))
    CC_is_M = np.empty(shape=(m_players,))                                      # shape (M_PLAYERS, )
    CC_is_M.fill(np.nan)
    BB_is_M = np.empty(shape=(m_players,))                                      # shape (M_PLAYERS, )
    BB_is_M.fill(np.nan)
    RU_is_M = np.empty(shape=(m_players,))                                      # shape (M_PLAYERS, )
    RU_is_M.fill(np.nan)    
    
    arr_pl_M_T_vars_modif = arr_pl_M_T_vars_init.copy()
    arr_pl_M_T_vars_modif[:,:,fct_aux.AUTOMATE_INDEX_ATTRS["Si_minus"]] = np.nan
    arr_pl_M_T_vars_modif[:,:,fct_aux.AUTOMATE_INDEX_ATTRS["Si_plus"]] = np.nan
    arr_pl_M_T_vars_modif[:,:,fct_aux.AUTOMATE_INDEX_ATTRS["bg_i"]] = 0
    arr_pl_M_T_vars_modif[:,:,fct_aux.AUTOMATE_INDEX_ATTRS["u_i"]] = 0
    arr_pl_M_T_vars_modif[:,:,fct_aux.AUTOMATE_INDEX_ATTRS["S1_p_i_j_k"]] = 0.5
    arr_pl_M_T_vars_modif[:,:,fct_aux.AUTOMATE_INDEX_ATTRS["S2_p_i_j_k"]] = 0.5
    arr_pl_M_T_vars_modif[:,:,fct_aux.AUTOMATE_INDEX_ATTRS["non_playing_players"]] \
        = fct_aux.NON_PLAYING_PLAYERS["PLAY"]
        
    dico_id_players = {"players":[fct_aux.RACINE_PLAYER+"_"+str(num_pl_i) 
                                  for num_pl_i in range(0, m_players)]}
    df_nash = pd.DataFrame.from_dict(dico_id_players)
    
    # _________  creation des arrays pour chaque algo  _______________________
    arr_pl_M_T_vars_modif_BADN = None
    arr_pl_M_T_vars_modif_BESTN = None
    arr_pl_M_T_vars_modif_MIDN = None
    
    pi_sg_plus_T_BESTN = pi_sg_plus_T.copy()
    pi_sg_minus_T_BESTN = pi_sg_minus_T.copy()
    pi_0_plus_T_BESTN = pi_0_plus_T.copy()
    pi_0_minus_T_BESTN = pi_0_minus_T.copy()
    B_is_M_BESTN = B_is_M.copy()
    C_is_M_BESTN = C_is_M.copy()
    b0_ts_T_BESTN = b0_ts_T.copy()
    c0_ts_T_BESTN = c0_ts_T.copy()
    BENs_M_T_BESTN = BENs_M_T.copy()
    CSTs_M_T_BESTN = CSTs_M_T.copy()
    CC_is_M_BESTN = CC_is_M.copy()
    BB_is_M_BESTN = BB_is_M.copy()
    RU_is_M_BESTN = RU_is_M.copy()
    C_is_M_BESTN = CC_is_M.copy()
    B_is_M_BESTN = BB_is_M.copy()
    dico_stats_res_BESTN = dict()
    df_nash_BESTN = df_nash.copy()
    
    pi_sg_plus_T_BADN = pi_sg_plus_T.copy()
    pi_sg_minus_T_BADN = pi_sg_minus_T.copy()
    pi_0_plus_T_BADN = pi_0_plus_T.copy()
    pi_0_minus_T_BADN = pi_0_minus_T.copy()
    B_is_M_BADN = B_is_M.copy()
    C_is_M_BADN = C_is_M.copy()
    b0_ts_T_BADN = b0_ts_T.copy()
    c0_ts_T_BADN = c0_ts_T.copy()
    BENs_M_T_BADN = BENs_M_T.copy()
    CSTs_M_T_BADN = CSTs_M_T.copy()
    CC_is_M_BADN = CC_is_M.copy()
    BB_is_M_BADN = BB_is_M.copy()
    RU_is_M_BADN = RU_is_M.copy()
    C_is_M_BADN = CC_is_M.copy()
    B_is_M_BADN = BB_is_M.copy()
    dico_stats_res_BADN = dict()
    df_nash_BADN = df_nash.copy()
    
    pi_sg_plus_T_MIDN = pi_sg_plus_T.copy()
    pi_sg_minus_T_MIDN = pi_sg_minus_T.copy()
    pi_0_plus_T_MIDN = pi_0_plus_T.copy()
    pi_0_minus_T_MIDN = pi_0_minus_T.copy()
    B_is_M_MIDN = B_is_M.copy()
    C_is_M_MIDN = C_is_M.copy()
    b0_ts_T_MIDN = b0_ts_T.copy()
    c0_ts_T_MIDN = c0_ts_T.copy()
    BENs_M_T_MIDN = BENs_M_T.copy()
    CSTs_M_T_MIDN = CSTs_M_T.copy()
    CC_is_M_MIDN = CC_is_M.copy()
    BB_is_M_MIDN = BB_is_M.copy()
    RU_is_M_MIDN = RU_is_M.copy()
    C_is_M_MIDN = CC_is_M.copy()
    B_is_M_MIDN = BB_is_M.copy()
    dico_stats_res_MIDN = dict()
    df_nash_MIDN = df_nash.copy()
    
    arr_pl_M_T_vars_modif_BADN = arr_pl_M_T_vars_modif.copy()
    arr_pl_M_T_vars_modif_BESTN = arr_pl_M_T_vars_modif.copy()
    arr_pl_M_T_vars_modif_MIDN = arr_pl_M_T_vars_modif.copy()
    
    # ____      game beginning for all t_period ---> debut      _____
    dico_stats_res = dict()
    dico_mode_prof_by_players_T = dict()
    
    pi_sg_plus_t0_minus_1 = pi_hp_plus-1
    pi_sg_minus_t0_minus_1 = pi_hp_minus-1
    pi_sg_plus_t_minus_1, pi_sg_minus_t_minus_1 = 0, 0
    pi_sg_plus_t, pi_sg_minus_t = None, None
    pi_hp_plus_s = np.array([pi_hp_plus] * t_periods, dtype=object)
    pi_hp_minus_s = np.array([pi_hp_minus] * t_periods, dtype=object)
    
    
    for t in range(0, t_periods):
        print("----- t = {} ------ ".format(t))
        if manual_debug:
            pi_sg_plus_t = fct_aux.MANUEL_DBG_PI_SG_PLUS_T_K #8
            pi_sg_minus_t = fct_aux.MANUEL_DBG_PI_SG_MINUS_T_K #10
            pi_0_plus_t = fct_aux.MANUEL_DBG_PI_0_PLUS_T_K #2 
            pi_0_minus_t = fct_aux.MANUEL_DBG_PI_0_MINUS_T_K #3
        else:
            pi_sg_plus_t_minus_1 = pi_sg_plus_t0_minus_1 if t == 0 \
                                                         else pi_sg_plus_t
            pi_sg_minus_t_minus_1 = pi_sg_minus_t0_minus_1 if t == 0 \
                                                            else pi_sg_minus_t
            pi_0_plus_t = round(pi_sg_plus_t_minus_1*pi_hp_plus/pi_hp_minus, 
                                fct_aux.N_DECIMALS)
            pi_0_minus_t = pi_sg_minus_t_minus_1
            if t == 0:
               pi_0_plus_t = 4
               pi_0_minus_t = 3
               
        
        arr_pl_M_T_vars_modif = fct_aux.compute_gamma_state_4_period_t(
                                arr_pl_M_T_K_vars=arr_pl_M_T_vars_modif.copy(), 
                                t=t, 
                                pi_0_plus=pi_0_plus_t, pi_0_minus=pi_0_minus_t,
                                pi_hp_plus=pi_hp_plus, pi_hp_minus=pi_hp_minus,
                                manual_debug=manual_debug,
                                dbg=dbg)
        
        possibles_modes = fct_aux.possibles_modes_players_automate(
                                        arr_pl_M_T_vars_modif.copy(), t=t, k=0)
        print("possibles_modes={}".format(len(possibles_modes)))
        
        arr_pl_M_T_vars_modif_BADN[:,t,:] = arr_pl_M_T_vars_modif[:,t,:]
        arr_pl_M_T_vars_modif_BESTN[:,t,:] = arr_pl_M_T_vars_modif[:,t,:]
        arr_pl_M_T_vars_modif_MIDN[:,t,:] = arr_pl_M_T_vars_modif[:,t,:]
            
        pi_0_plus_T[t] = pi_0_plus_t
        pi_0_minus_T[t] = pi_0_minus_t
        
        # balanced player game at instant t    
        dico_profs_Vis_Perf_t = dict()
        cpt_profs = 0
        
        mode_profiles = it.product(*possibles_modes)
        for mode_profile in mode_profiles:
            dico_gamme_t = dict()
            arr_pl_M_T_vars_mode_prof, \
            b0_t, c0_t, \
            bens_t, csts_t, \
            pi_sg_plus_t, pi_sg_minus_t, \
            dico_gamme_t \
                = autoBfGameModel4T.balanced_player_game_4_mode_profil_prices_SG(
                    arr_pl_M_T_vars_modif.copy(),
                    mode_profile, t,
                    pi_hp_plus, pi_hp_minus,
                    pi_0_plus_t, pi_0_minus_t,
                    manual_debug, dbg)
                
            In_sg, Out_sg = fct_aux.compute_prod_cons_SG(
                                arr_pl_M_T_vars_mode_prof, 
                                t)
            
            bens_csts_t = bens_t - csts_t
            Perf_t = np.sum(bens_csts_t, axis=0)
            dico_Vis_Pref_t = dict()
            for num_pl_i in range(bens_csts_t.shape[0]):            # bens_csts_t.shape[0] = m_players
                dico_Vis_Pref_t[fct_aux.RACINE_PLAYER+"_"+str(num_pl_i)] \
                    = (bens_csts_t[num_pl_i], 
                       bens_t[num_pl_i], 
                       csts_t[num_pl_i])
                    
                dico_vars = dict()
                dico_vars["Vi"] = round(bens_csts_t[num_pl_i], 2)
                dico_vars["ben_i"] = round(bens_t[num_pl_i], 2)
                dico_vars["cst_i"] = round(csts_t[num_pl_i], 2)
                variables = ["state_i", "mode_i", "prod_i", "cons_i", "r_i", 
                             "gamma_i", "Pi", "Ci", "Si", "Si_old", 
                             "Si_minus", "Si_plus"]
                for variable in variables:
                    dico_vars[variable] = arr_pl_M_T_vars_mode_prof[
                                            num_pl_i, t, 
                                            fct_aux.AUTOMATE_INDEX_ATTRS[variable]]
                    
                dico_mode_prof_by_players_T["PLAYER_"
                                            +str(num_pl_i)
                                            +"_t_"+str(t)
                                            +"_"+str(cpt_profs)] \
                    = dico_vars
                    
            dico_mode_prof_by_players_T["Perf_t_"+str(t)+"_"+str(cpt_profs)] = round(Perf_t, 2)
            dico_mode_prof_by_players_T["b0_t_"+str(t)+"_"+str(cpt_profs)] = round(b0_t,2)
            dico_mode_prof_by_players_T["c0_t_"+str(t)+"_"+str(cpt_profs)] = round(c0_t,2)
            dico_mode_prof_by_players_T["Out_sg_"+str(t)+"_"+str(cpt_profs)] = round(Out_sg,2)
            dico_mode_prof_by_players_T["In_sg_"+str(t)+"_"+str(cpt_profs)] = round(In_sg,2)
            dico_mode_prof_by_players_T["pi_sg_plus_t_"+str(t)+"_"+str(cpt_profs)] = round(pi_sg_plus_t,2)
            dico_mode_prof_by_players_T["pi_sg_minus_t_"+str(t)+"_"+str(cpt_profs)] = round(pi_sg_minus_t,2)
            dico_mode_prof_by_players_T["pi_0_plus_t_"+str(t)+"_"+str(cpt_profs)] = round(pi_0_plus_t,2)
            dico_mode_prof_by_players_T["pi_0_minus_t_"+str(t)+"_"+str(cpt_profs)] = round(pi_0_minus_t,2)
            
                    
            dico_Vis_Pref_t["Perf_t"] = Perf_t
            dico_Vis_Pref_t["b0"] = b0_t
            dico_Vis_Pref_t["c0"] = c0_t
            
            dico_profs_Vis_Perf_t[mode_profile] = dico_Vis_Pref_t
            cpt_profs += 1
            
            if cpt_profs%5000 == 0:
                print("cpt_prof={}".format(cpt_profs))
                
        # detection of NASH profils
        nash_profils = list();
        dico_nash_profils = list()
        nash_profils, dico_nash_profils = detect_nash_balancing_profil(
                        dico_profs_Vis_Perf_t,
                        arr_pl_M_T_vars_modif, 
                        t)
        
        # delete all occurences of the profiles 
        print("----> avant supp doublons nash_profils={}".format(len(nash_profils)))
        nash_profils = set(nash_profils)
        print("----> apres supp doublons nash_profils={}".format(len(nash_profils)))
        
        # create dico of nash profils with key is Pref_t and value is profil
        dico_Perft_nashProfil = dict()
        for nash_mode_profil in nash_profils:
            Perf_t = dico_profs_Vis_Perf_t[nash_mode_profil]["Perf_t"]
            if Perf_t in dico_Perft_nashProfil:
                dico_Perft_nashProfil[Perf_t].append(nash_mode_profil)
            else:
                dico_Perft_nashProfil[Perf_t] = [nash_mode_profil]
                
        if len(dico_Perft_nashProfil.keys()) != 0:        
            arr_pl_M_T_vars_modif_algo = None
            b0_ts_T_algo, c0_ts_T_algo = None, None
            BENs_M_T_algo, CSTs_M_T_algo = None, None
            pi_0_plus_T_algo, pi_0_minus_T_algo = None, None
            df_nash_algo = None
            for algo_name in fct_aux.ALGO_NAMES_NASH:
                
                if algo_name == fct_aux.ALGO_NAMES_NASH[0]:              # BEST-NASH
                    arr_pl_M_T_vars_modif_algo = arr_pl_M_T_vars_modif_BESTN.copy()
                    pi_sg_plus_T_algo = pi_sg_plus_T_BESTN.copy()
                    pi_sg_minus_T_algo = pi_sg_minus_T_BESTN.copy()
                    b0_ts_T_algo = b0_ts_T_BESTN.copy()
                    c0_ts_T_algo = c0_ts_T_BESTN.copy()
                    BENs_M_T_algo = BENs_M_T_BESTN.copy()
                    CSTs_M_T_algo = CSTs_M_T_BESTN.copy()
                    pi_0_plus_T_algo = pi_0_plus_T_BESTN.copy() 
                    pi_0_minus_T_algo = pi_0_minus_T_BESTN.copy()
                    dico_stats_res_algo = dico_stats_res_BESTN.copy()
                    df_nash_algo = df_nash_BESTN.copy()
                                   
                elif algo_name == fct_aux.ALGO_NAMES_NASH[1]:            # BAD-NASH
                    arr_pl_M_T_vars_modif_algo = arr_pl_M_T_vars_modif_BADN.copy()
                    pi_sg_plus_T_algo = pi_sg_plus_T_BADN.copy()
                    pi_sg_minus_T_algo = pi_sg_minus_T_BADN.copy()
                    b0_ts_T_algo = b0_ts_T_BADN.copy()
                    c0_ts_T_algo = c0_ts_T_BADN.copy()
                    BENs_M_T_algo = BENs_M_T_BADN.copy()
                    CSTs_M_T_algo = CSTs_M_T_BADN.copy()
                    pi_0_plus_T_algo = pi_0_plus_T_BADN.copy()
                    pi_0_minus_T_algo = pi_0_minus_T_BADN.copy()
                    dico_stats_res_algo = dico_stats_res_BADN.copy()
                    df_nash_algo = df_nash_BADN.copy()
                    
                elif algo_name == fct_aux.ALGO_NAMES_NASH[2]:            # MIDDLE-NASH
                    arr_pl_M_T_vars_modif_algo = arr_pl_M_T_vars_modif_MIDN.copy()
                    pi_sg_plus_T_algo = pi_sg_plus_T_MIDN.copy()
                    pi_sg_minus_T_algo = pi_sg_minus_T_MIDN.copy()
                    b0_ts_T_algo = b0_ts_T_MIDN.copy()
                    c0_ts_T_algo = c0_ts_T_MIDN.copy()
                    BENs_M_T_algo = BENs_M_T_MIDN.copy()
                    CSTs_M_T_algo = CSTs_M_T_MIDN.copy()
                    pi_0_plus_T_algo = pi_0_plus_T_MIDN.copy()
                    pi_0_minus_T_algo = pi_0_minus_T_MIDN.copy()
                    dico_stats_res_algo = dico_stats_res_MIDN.copy()
                    df_nash_algo = df_nash_MIDN.copy()
                
                # ____      game beginning for one algo for t ---> debut      _____
                # min, max, mean of Perf_t
                print("algo_name = {}".format(algo_name))
                best_key_Perf_t = None
                if algo_name == fct_aux.ALGO_NAMES_NASH[0]:              # BEST-NASH
                    best_key_Perf_t = max(dico_Perft_nashProfil.keys())
                elif algo_name == fct_aux.ALGO_NAMES_NASH[1]:            # BAD-NASH
                    best_key_Perf_t = min(dico_Perft_nashProfil.keys())
                elif algo_name == fct_aux.ALGO_NAMES_NASH[2]:            # MIDDLE-NASH
                    mean_key_Perf_t  = np.mean(list(dico_Perft_nashProfil.keys()))
                    if mean_key_Perf_t in dico_Perft_nashProfil.keys():
                        best_key_Perf_t = mean_key_Perf_t
                    else:
                        sorted_keys = sorted(dico_Perft_nashProfil.keys())
                        boolean = True; i_key = 1
                        while boolean:
                            if sorted_keys[i_key] <= mean_key_Perf_t:
                                i_key += 1
                            else:
                                boolean = False; i_key -= 1
                        best_key_Perf_t = sorted_keys[i_key]
                        
                
                # find the best, bad, middle key in dico_Perft_nashProfil and 
                # the best, bad, middle nash_mode_profile
                best_nash_mode_profiles = dico_Perft_nashProfil[best_key_Perf_t]
                best_nash_mode_profile = None
                if len(best_nash_mode_profiles) == 1:
                    best_nash_mode_profile = best_nash_mode_profiles[0]
                else:
                    rd = np.random.randint(0, len(best_nash_mode_profiles))
                    best_nash_mode_profile = best_nash_mode_profiles[rd]
                
                print("** Running at t={}: numbers of -> cpt_profils={}, nash_profils={}, {}_nash_mode_profiles={}, nbre_cle_dico_Perft_nashProf={}"\
                      .format(t, cpt_profs, 
                        len(nash_profils),
                        algo_name.split("-")[0], len(best_nash_mode_profiles),
                        list(dico_Perft_nashProfil.keys())      
                              ))
                print("{}_key_Perf_t={}, {}_nash_mode_profile={}".format(
                        algo_name.split("-")[0], best_key_Perf_t, 
                        algo_name.split("-")[0], 
                        best_nash_mode_profile))
                
                arr_pl_M_T_vars_nash_mode_prof_algo, \
                b0_t, c0_t, \
                bens_t, csts_t, \
                pi_sg_plus_t, pi_sg_minus_t, \
                dico_gamme_t_nash_mode_prof \
                    = autoBfGameModel4T.balanced_player_game_4_mode_profil_prices_SG(
                        arr_pl_M_T_vars_modif_algo.copy(),
                        best_nash_mode_profile, t,
                        pi_hp_plus, pi_hp_minus,
                        pi_0_plus_t, pi_0_minus_t,
                        manual_debug, dbg)
                suff = algo_name.split("-")[0]
                dico_stats_res_algo[t] = {"gamma_i": dico_gamme_t_nash_mode_prof,
                                "nash_profils": nash_profils,
                                "nb_nash_profils": len(nash_profils),
                                suff+"_nash_profil": best_nash_mode_profile,
                                suff+"_Perf_t": best_key_Perf_t,
                                "nb_nash_profil_byPerf_t": 
                                    len(dico_Perft_nashProfil[best_key_Perf_t]),
                                "dico_nash_profils": dico_nash_profils,
                                suff+"_b0_t": b0_t,
                                suff+"_c0_t": c0_t
                                }
                    
                # pi_sg_{plus,minus} of shape (T_PERIODS,)
                if np.isnan(pi_sg_plus_t):
                    pi_sg_plus_t = 0
                if np.isnan(pi_sg_minus_t):
                    pi_sg_minus_t = 0
                pi_sg_plus_T_algo[t] = pi_sg_plus_t
                pi_sg_minus_T_algo[t] = pi_sg_minus_t
                pi_0_plus_T_algo[t] = pi_0_plus_t
                pi_0_minus_T_algo[t] = pi_0_minus_t
                
                # b0_ts, c0_ts of shape (T_PERIODS,)
                b0_ts_T_algo[t] = b0_t
                c0_ts_T_algo[t] = c0_t
                
                # BENs, CSTs of shape (M_PLAYERS, T_PERIODS)
                BENs_M_T_algo[:,t] = bens_t
                CSTs_M_T_algo[:,t] = csts_t
                
                # checkout NASH equilibrium
                bens_csts_M_t = bens_t - csts_t
                df_nash_t = None
                df_nash_t = autoBfGameModel4T.checkout_nash_4_profils_by_periods(
                                arr_pl_M_T_vars_nash_mode_prof_algo,
                                arr_pl_M_T_vars_init,
                                pi_hp_plus, pi_hp_minus, 
                                pi_0_minus_t, pi_0_plus_t, 
                                bens_csts_M_t,
                                t,
                                manual_debug)
                df_nash_algo = pd.merge(df_nash_algo, df_nash_t, 
                                        on='players', 
                                        how='outer')
                # ____      game beginning for one algo for t ---> FIN        _____
                
                # __________        compute prices variables         ____________________
                # B_is, C_is of shape (M_PLAYERS, )
                prod_i_M_T_algo = arr_pl_M_T_vars_nash_mode_prof_algo[
                                        :,:t_periods, 
                                        fct_aux.AUTOMATE_INDEX_ATTRS["prod_i"]]
                cons_i_M_T_algo = arr_pl_M_T_vars_nash_mode_prof_algo[
                                        :,:t_periods, 
                                        fct_aux.AUTOMATE_INDEX_ATTRS["cons_i"]]
                B_is_M_algo = np.sum(b0_ts_T_algo * prod_i_M_T_algo, axis=1)
                C_is_M_algo = np.sum(c0_ts_T_algo * cons_i_M_T_algo, axis=1)
                
                # BB_is, CC_is, RU_is of shape (M_PLAYERS, )
                CONS_is_M_algo = np.sum(cons_i_M_T_algo, axis=1)
                PROD_is_M_algo = np.sum(prod_i_M_T_algo, axis=1)
                BB_is_M_algo = pi_sg_plus_T_algo[t] * PROD_is_M_algo #np.sum(PROD_is)
                for num_pl, bb_i in enumerate(BB_is_M_algo):
                    if bb_i != 0:
                        print("player {}, BB_i={}".format(num_pl, bb_i))
                    if np.isnan(bb_i):
                        print("player {},PROD_is={}, pi_sg={}".format(num_pl, 
                              PROD_is_M_algo[num_pl], pi_sg_plus_T_algo[t]))
                CC_is_M_algo = pi_sg_minus_T_algo[t] * CONS_is_M_algo #np.sum(CONS_is)
                RU_is_M_algo = BB_is_M_algo - CC_is_M_algo
                print("{}: t={}, pi_sg_plus_T={}, pi_sg_minus_T={} \n".format(
                    algo_name, t, pi_sg_plus_T_algo[t], pi_sg_minus_T_algo[t] ))
                
                pi_hp_plus_s = np.array([pi_hp_plus] * t_periods, dtype=object)
                pi_hp_minus_s = np.array([pi_hp_minus] * t_periods, dtype=object) 
                # __________        compute prices variables         ____________________
                
                # __________        maj arrays for all algos: debut    ____________
                if algo_name == fct_aux.ALGO_NAMES_NASH[0]:                           # BEST-BRUTE-FORCE
                    arr_pl_M_T_vars_modif_BESTN = arr_pl_M_T_vars_nash_mode_prof_algo.copy()
                    pi_sg_plus_T_BESTN[t] = pi_sg_plus_T_algo[t]
                    pi_sg_minus_T_BESTN[t] = pi_sg_minus_T_algo[t]
                    pi_0_plus_T_BESTN[t] = pi_0_plus_T_algo[t]
                    pi_0_minus_T_BESTN[t] = pi_0_minus_T_algo[t]
                    B_is_M_BESTN = B_is_M_algo.copy()
                    C_is_M_BESTN = C_is_M_algo.copy()
                    b0_ts_T_BESTN = b0_ts_T_algo.copy()
                    c0_ts_T_BESTN = c0_ts_T_algo.copy()
                    BENs_M_T_BESTN = BENs_M_T_algo.copy()
                    CSTs_M_T_BESTN = CSTs_M_T_algo.copy()
                    CC_is_M_BESTN = CC_is_M_algo.copy()
                    BB_is_M_BESTN = BB_is_M_algo.copy()
                    RU_is_M_BESTN = RU_is_M_algo.copy()
                    dico_stats_res_BESTN = dico_stats_res_algo.copy()
                    df_nash_BESTN = df_nash_algo.copy()
                    
                elif algo_name == fct_aux.ALGO_NAMES_NASH[1]:                         # BAD-BRUTE-FORCE
                    arr_pl_M_T_vars_modif_BADN = arr_pl_M_T_vars_nash_mode_prof_algo.copy()
                    pi_sg_plus_T_BADN[t] = pi_sg_plus_T_algo[t]
                    pi_sg_minus_T_BADN[t] = pi_sg_minus_T_algo[t]
                    pi_0_plus_T_BADN[t] = pi_0_plus_T_algo[t]
                    pi_0_minus_T_BADN[t] = pi_0_minus_T_algo[t]
                    B_is_M_BADN = B_is_M_algo.copy()
                    C_is_M_BADN = C_is_M_algo.copy()
                    b0_ts_T_BADN = b0_ts_T_algo.copy()
                    c0_ts_T_BADN = c0_ts_T_algo.copy()
                    BENs_M_T_BADN = BENs_M_T_algo.copy()
                    CSTs_M_T_BADN = CSTs_M_T_algo.copy()
                    CC_is_M_BADN = CC_is_M_algo.copy()
                    BB_is_M_BADN = BB_is_M_algo.copy()
                    RU_is_M_BADN = RU_is_M_algo.copy()
                    dico_stats_res_BADN = dico_stats_res_algo.copy()
                    df_nash_BADN = df_nash_algo.copy()
                    
                elif algo_name == fct_aux.ALGO_NAMES_NASH[2]:                         # MIDDLE-BRUTE-FORCE
                    arr_pl_M_T_vars_modif_MIDN = arr_pl_M_T_vars_nash_mode_prof_algo.copy()
                    pi_sg_plus_T_MIDN[t] = pi_sg_plus_T_algo[t]
                    pi_sg_minus_T_MIDN[t] = pi_sg_minus_T_algo[t]
                    pi_0_plus_T_MIDN[t] = pi_0_plus_T_algo[t]
                    pi_0_minus_T_MIDN[t] = pi_0_minus_T_algo[t]
                    B_is_M_MIDN = B_is_M_algo.copy()
                    C_is_M_MIDN = C_is_M_algo.copy()
                    b0_ts_T_MIDN = b0_ts_T_algo.copy()
                    c0_ts_T_MIDN = c0_ts_T_algo.copy()
                    BENs_M_T_MIDN = BENs_M_T_algo.copy()
                    CSTs_M_T_MIDN = CSTs_M_T_algo.copy()
                    CC_is_M_MIDN = CC_is_M_algo.copy()
                    BB_is_M_MIDN = BB_is_M_algo.copy()
                    RU_is_M_MIDN = RU_is_M_algo.copy()
                    dico_stats_res_MIDN = dico_stats_res_algo.copy()
                    df_nash_MIDN = df_nash_algo.copy()
                
                # __________        maj arrays for all algos: fin      ____________
        else:
            if algo_name == fct_aux.ALGO_NAMES_NASH[0]:                           # BEST-BRUTE-FORCE
                # arr_pl_M_T_vars_modif_BESTN = arr_pl_M_T_vars_nash_mode_prof_algo.copy()
                pi_sg_plus_T_BESTN[t] = 0
                pi_sg_minus_T_BESTN[t] = 0
                pi_0_plus_T_BESTN[t] = 0
                pi_0_minus_T_BESTN[t] = 0
                B_is_M_BESTN[:] = 0
                C_is_M_BESTN[:] = 0
                b0_ts_T_BESTN[t] = 0
                c0_ts_T_BESTN[t] = 0
                BENs_M_T_BESTN[:,t] = 0
                CSTs_M_T_BESTN[:,t] = 0
                CC_is_M_BESTN[:] = 0
                BB_is_M_BESTN[:] = 0
                RU_is_M_BESTN[:] = 0
                dico_stats_res_BESTN[t] = {"gamma_i": dict(),
                                        "nash_profils": list(),
                                        "nb_nash_profils": 0,
                                        suff+"_nash_profil": (),
                                        suff+"_Perf_t": 0,
                                        "nb_nash_profil_byPerf_t": 0,
                                        "dico_nash_profils": dict(),
                                        suff+"_b0_t": 0,
                                        suff+"_c0_t": 0
                                        }
                
            elif algo_name == fct_aux.ALGO_NAMES_NASH[1]:                         # BAD-BRUTE-FORCE
                # arr_pl_M_T_vars_modif_BADN = arr_pl_M_T_vars_nash_mode_prof_algo.copy()
                pi_sg_plus_T_BADN[t] = 0
                pi_sg_minus_T_BADN[t] = 0
                pi_0_plus_T_BADN[t] = 0
                pi_0_minus_T_BADN[t] = 0
                B_is_M_BADN[:] = 0
                C_is_M_BADN[:] = 0
                b0_ts_T_BADN[t] = 0
                c0_ts_T_BADN[t] = 0
                BENs_M_T_BADN[:,t] = 0
                CSTs_M_T_BADN[:,t] = 0
                CC_is_M_BADN[:] = 0
                BB_is_M_BADN[:] = 0
                RU_is_M_BADN[:] = 0
                dico_stats_res_BADN[t] = {"gamma_i": dict(),
                                        "nash_profils": list(),
                                        "nb_nash_profils": 0,
                                        suff+"_nash_profil": (),
                                        suff+"_Perf_t": 0,
                                        "nb_nash_profil_byPerf_t": 0,
                                        "dico_nash_profils": dict(),
                                        suff+"_b0_t": 0,
                                        suff+"_c0_t": 0
                                        }
                
            elif algo_name == fct_aux.ALGO_NAMES_NASH[2]:                         # MIDDLE-BRUTE-FORCE
                # arr_pl_M_T_vars_modif_MIDN = arr_pl_M_T_vars_nash_mode_prof_algo.copy()
                pi_sg_plus_T_MIDN[t] = 0
                pi_sg_minus_T_MIDN[t] = 0
                pi_0_plus_T_MIDN[t] = 0
                pi_0_minus_T_MIDN[t] = 0
                B_is_M_MIDN[:] = 0
                C_is_M_MIDN[:] = 0
                b0_ts_T_MIDN[t] = 0
                c0_ts_T_MIDN[t] = 0
                BENs_M_T_MIDN[:,t] = 0
                CSTs_M_T_MIDN[:,t] = 0
                CC_is_M_MIDN[:] = 0
                BB_is_M_MIDN[:] = 0
                RU_is_M_MIDN[:] = 0
                dico_stats_res_MIDN[t] = {"gamma_i": dict(),
                                        "nash_profils": list(),
                                        "nb_nash_profils": 0,
                                        suff+"_nash_profil": (),
                                        suff+"_Perf_t": 0,
                                        "nb_nash_profil_byPerf_t": 0,
                                        "dico_nash_profils": dict(),
                                        suff+"_b0_t": 0,
                                        suff+"_c0_t": 0
                                        }
                    
    # ____      game beginning for all t_period ---> fin      _____
    
    #_______      save computed variables locally from algo_name     __________
    msg = "pi_hp_plus_"+str(pi_hp_plus)+"_pi_hp_minus_"+str(pi_hp_minus)
    name_dir = "tests"; date_hhmm = "DDMM_HHMM"
    
    print("path_to_save={}".format(path_to_save))
    algo_name = fct_aux.ALGO_NAMES_NASH[0]
    if "simu_DDMM_HHMM" in path_to_save:
        path_to_save = os.path.join(name_dir, "simu_"+date_hhmm,
                                    msg, algo_name
                                    )
    Path(path_to_save).mkdir(parents=True, exist_ok=True)
    df_nash_BESTN.to_excel(os.path.join(
                *[path_to_save,
                  "resume_verify_Nash_equilibrium_{}.xlsx".format(algo_name)]), 
                index=False)
    if arr_pl_M_T_vars_modif_BESTN.shape[0] < 11:
        fct_aux.save_variables(path_to_save, arr_pl_M_T_vars_modif_BESTN, 
                   b0_ts_T_BESTN, c0_ts_T_BESTN, B_is_M_BESTN, C_is_M_BESTN, 
                   BENs_M_T_BESTN, CSTs_M_T_BESTN, 
                   BB_is_M_BESTN, CC_is_M_BESTN, RU_is_M_BESTN, 
                   pi_sg_minus_T_BESTN, pi_sg_plus_T_BESTN, 
                   pi_0_minus_T_BESTN, pi_0_plus_T_BESTN,
                   pi_hp_plus_s, pi_hp_minus_s, dico_stats_res_BESTN, 
                   algo=algo_name, 
                   dico_best_steps=dict())
    else:
        fct_aux.save_variables(path_to_save, arr_pl_M_T_vars_modif_BESTN, 
                    b0_ts_T_BESTN, c0_ts_T_BESTN, B_is_M_BESTN, C_is_M_BESTN, 
                    BENs_M_T_BESTN, CSTs_M_T_BESTN, 
                    BB_is_M_BESTN, CC_is_M_BESTN, RU_is_M_BESTN, 
                    pi_sg_minus_T_BESTN, pi_sg_plus_T_BESTN, 
                    pi_0_minus_T_BESTN, pi_0_plus_T_BESTN,
                    pi_hp_plus_s, pi_hp_minus_s, dico_stats_res_BESTN, 
                    algo=algo_name, 
                    dico_best_steps=dict())
    turn_dico_stats_res_into_df_NASH(dico_stats_res_algo=dico_stats_res_BESTN, 
                                path_to_save=path_to_save, 
                                t_periods=t_periods, 
                                manual_debug=manual_debug, 
                                algo_name=algo_name) \
        if len(dico_Perft_nashProfil.keys()) != 0 \
        else None
    
    algo_name = fct_aux.ALGO_NAMES_NASH[1]
    if "simu_DDMM_HHMM" in path_to_save:
        path_to_save = os.path.join(name_dir, "simu_"+date_hhmm,
                                    msg, algo_name
                                    )
    df_nash_BADN.to_excel(os.path.join(
                *[path_to_save,
                  "resume_verify_Nash_equilibrium_{}.xlsx".format(algo_name)]), 
                index=False)
    if arr_pl_M_T_vars_modif_BADN.shape[0] < 11:
        fct_aux.save_variables(path_to_save, arr_pl_M_T_vars_modif_BADN, 
                   b0_ts_T_BADN, c0_ts_T_BADN, B_is_M_BADN, C_is_M_BADN, 
                   BENs_M_T_BADN, CSTs_M_T_BADN, 
                   BB_is_M_BADN, CC_is_M_BADN, RU_is_M_BADN, 
                   pi_sg_minus_T_BADN, pi_sg_plus_T_BADN, 
                   pi_0_minus_T_BADN, pi_0_plus_T_BADN,
                   pi_hp_plus_s, pi_hp_minus_s, dico_stats_res_BADN, 
                   algo=algo_name,
                   dico_best_steps=dict())
    else:
        fct_aux.save_variables(path_to_save, arr_pl_M_T_vars_modif_BADN, 
                    b0_ts_T_BADN, c0_ts_T_BADN, B_is_M_BADN, C_is_M_BADN, 
                    BENs_M_T_BADN, CSTs_M_T_BADN, 
                    BB_is_M_BADN, CC_is_M_BADN, RU_is_M_BADN, 
                    pi_sg_minus_T_BADN, pi_sg_plus_T_BADN, 
                    pi_0_minus_T_BADN, pi_0_plus_T_BADN,
                    pi_hp_plus_s, pi_hp_minus_s, dico_stats_res_BADN, 
                    algo=algo_name,
                    dico_best_steps=dict())  
    turn_dico_stats_res_into_df_NASH(dico_stats_res_algo=dico_stats_res_BADN, 
                                path_to_save=path_to_save, 
                                t_periods=t_periods, 
                                manual_debug=manual_debug, 
                                algo_name=algo_name) \
        if len(dico_Perft_nashProfil.keys()) != 0 \
        else None
    
    algo_name = fct_aux.ALGO_NAMES_NASH[2]
    if "simu_DDMM_HHMM" in path_to_save:
        path_to_save = os.path.join(name_dir, "simu_"+date_hhmm,
                                    msg, algo_name
                                    )
    df_nash_MIDN.to_excel(os.path.join(
                *[path_to_save,
                  "resume_verify_Nash_equilibrium_{}.xlsx".format(algo_name)]), 
                index=False)
    if arr_pl_M_T_vars_modif_MIDN.shape[0] < 11: 
        fct_aux.save_variables(path_to_save, arr_pl_M_T_vars_modif_MIDN, 
                   b0_ts_T_MIDN, c0_ts_T_MIDN, B_is_M_MIDN, C_is_M_MIDN, 
                   BENs_M_T_MIDN, CSTs_M_T_MIDN, 
                   BB_is_M_MIDN, CC_is_M_MIDN, RU_is_M_MIDN, 
                   pi_sg_minus_T_MIDN, pi_sg_plus_T_MIDN, 
                   pi_0_minus_T_MIDN, pi_0_plus_T_MIDN,
                   pi_hp_plus_s, pi_hp_minus_s, dico_stats_res_MIDN, 
                   algo=algo_name,
                   dico_best_steps=dict())
    else:
        fct_aux.save_variables(path_to_save, arr_pl_M_T_vars_modif_MIDN, 
                    b0_ts_T_MIDN, c0_ts_T_MIDN, B_is_M_MIDN, C_is_M_MIDN, 
                    BENs_M_T_MIDN, CSTs_M_T_MIDN, 
                    BB_is_M_MIDN, CC_is_M_MIDN, RU_is_M_MIDN, 
                    pi_sg_minus_T_MIDN, pi_sg_plus_T_MIDN, 
                    pi_0_minus_T_MIDN, pi_0_plus_T_MIDN,
                    pi_hp_plus_s, pi_hp_minus_s, dico_stats_res_MIDN, 
                    algo=algo_name,
                    dico_best_steps=dict())
    turn_dico_stats_res_into_df_NASH(dico_stats_res_algo=dico_stats_res_MIDN, 
                                path_to_save=path_to_save, 
                                t_periods=t_periods, 
                                manual_debug=manual_debug, 
                                algo_name=algo_name) \
        if len(dico_Perft_nashProfil.keys()) != 0 \
        else None
        
    return arr_pl_M_T_vars_modif
        
# __________       main function of NASH EQUILIBRIUM   ---> fin        ________

###############################################################################
#                   definition  des unittests
#
###############################################################################
def test_NASH_balanced_player_game_perf_t_USE_DICT_MODE_PROFIL():
    fct_aux.N_DECIMALS = 8
    
    pi_hp_plus = 10 #0.2*pow(10,-3) #[5, 15]
    pi_hp_minus = 20 #0.33 #[15, 5]
    
    manual_debug=True
    debug = False
    criteria_bf = "Perf_t"
    
    prob_A_A = 0.8; prob_A_B = 0.2; prob_A_C = 0.0;
    prob_B_A = 0.3; prob_B_B = 0.4; prob_B_C = 0.3;
    prob_C_A = 0.1; prob_C_B = 0.2; prob_C_C = 0.7;
    scenario1 = [(prob_A_A, prob_A_B, prob_A_C), 
                 (prob_B_A, prob_B_B, prob_B_C),
                 (prob_C_A, prob_C_B, prob_C_C)]
    
    t_periods = 2
    setA_m_players, setB_m_players, setC_m_players = 10, 6, 5
    setA_m_players, setB_m_players, setC_m_players = 8, 3, 3
    setA_m_players, setB_m_players, setC_m_players = 6, 2, 2
    path_to_arr_pl_M_T = os.path.join(*["tests", "AUTOMATE_INSTANCES_GAMES"])
    used_instances = True #False #True
    
    arr_pl_M_T_vars_init = fct_aux.get_or_create_instance_Pi_Ci_etat_AUTOMATE(
                            setA_m_players, setB_m_players, setC_m_players, 
                            t_periods, 
                            scenario1,
                            path_to_arr_pl_M_T, used_instances)
    fct_aux.checkout_values_Pi_Ci_arr_pl(arr_pl_M_T_vars_init)
    
    arr_pl_M_T_vars = nash_balanced_player_game_perf_t_USE_DICT_MODE_PROFIL(
                                arr_pl_M_T_vars_init.copy(),
                                pi_hp_plus=pi_hp_plus, 
                                pi_hp_minus=pi_hp_minus,
                                path_to_save="tests", 
                                manual_debug=manual_debug, 
                                dbg=debug)
    
    return arr_pl_M_T_vars

def test_NASH_balanced_player_game_Pi_Ci_one_period():
    
    fct_aux.N_DECIMALS = 8
    
    pi_hp_plus = 10 #0.2*pow(10,-3) #[5, 15]
    pi_hp_minus = 20 #0.33 #[15, 5]
    
    manual_debug=True
    debug = False
    criteria_bf = "Perf_t"
    
    setA_m_players = 15; setB_m_players = 10; setC_m_players = 10
    setA_m_players, setB_m_players, setC_m_players = 8, 3, 3
    setA_m_players, setB_m_players, setC_m_players = 6, 2, 2
    t_periods = 1 
    path_to_arr_pl_M_T = os.path.join(*["tests", "AUTOMATE_INSTANCES_GAMES"])
    used_instances = True #False#True
    
    prob_A_A = 0.7; prob_A_B = 0.3; prob_A_C = 0.0;
    prob_B_A = 0.3; prob_B_B = 0.4; prob_B_C = 0.3;
    prob_C_A = 0.1; prob_C_B = 0.2; prob_C_C = 0.7;
    scenario = [(prob_A_A, prob_A_B, prob_A_C), (prob_B_A, prob_B_B, prob_B_C),
                (prob_C_A, prob_C_B, prob_C_C)]
    
    arr_pl_M_T_vars_init = fct_aux.get_or_create_instance_Pi_Ci_one_period(
                        setA_m_players, setB_m_players, setC_m_players, 
                        t_periods, 
                        scenario,
                        path_to_arr_pl_M_T, used_instances)
    fct_aux.checkout_values_Pi_Ci_arr_pl_one_period(arr_pl_M_T_vars_init)
    
    arr_pl_M_T_vars = nash_balanced_player_game_perf_t_USE_DICT_MODE_PROFIL(
                                arr_pl_M_T_vars_init.copy(),
                                pi_hp_plus=pi_hp_plus, 
                                pi_hp_minus=pi_hp_minus,
                                path_to_save="tests", 
                                manual_debug=manual_debug, 
                                dbg=debug)
    
    return arr_pl_M_T_vars
    
###############################################################################
#                   Execution
#
###############################################################################
if __name__ == "__main__":
    ti = time.time()
    
    arr_pl_M_T_vars = test_NASH_balanced_player_game_perf_t_USE_DICT_MODE_PROFIL()
    # arr_pl_M_T_vars = test_NASH_balanced_player_game_Pi_Ci_one_period()
    
    print("runtime = {}".format(time.time() - ti))